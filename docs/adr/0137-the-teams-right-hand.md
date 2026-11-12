# 0137. The team's right hand

- Status: Accepted; §6 and §7 amended 2026-11-06 by ADR 0079 §7 (built: engine, server, the shared client, the web and the phone app); amended 2026-11-03 (§5, a person alone with the team; §4 and §6 written as decided); amended 2026-11-04 (§8, agents act on agentes.chat through their tools, never by signing in to it); amended 2026-11-04 (§4, it starts everything a person does in the app, as cards); amended 2026-11-04 (§1, §4 and §7: it thinks with a person's plan through Claude Code or OpenCode, locked down and checked before each turn; then through Codex and Cursor too, the owner accepting their residual risk); amended 2026-11-04 (§4: through Grok Build too, checked on its `init` like Claude Code, ADR 0142); amended 2026-11-04 (§4: through the Antigravity CLI too, as an agent with no tool of its own, checked on its `init` and every step, ADR 0143); amended 2026-11-04 (§9, "Semana da equipe": a weekly card in each admin's DM, from stored data); amended 2026-11-04 (§10: the team set up from three questions, one team card, team templates); amended 2026-11-04 (§4: the team map's drag posts its settings card, ADR 0148); amended 2026-11-05 (§11, each person's own AI); amended 2026-11-06 (§12, it reads the Drive and the wiki for the person); amended 2026-11-06 (§13, the one you talk to: it sees the team and hands work on); amended 2026-11-11 (§4: a teammate's skills on its settings card); amended 2026-11-12 (§4: every agent asks for its own settings on the same card, always a click); amended 2026-11-12 (§4, §12, §13: it has a normal agent's tools)
- Date: 2026-11-03
- Supersedes: ADR 0093 (the team's coordinator)
- Amends: ADR 0081 (one-click Criar and Criar e testar on the right hand's cards), ADR 0092 §5 (a teammate's settings, on the right hand's card)
- Extends: ADR 0053 (who is behind a run), ADR 0061 and 0129 (action cards applied as whoever clicks), ADR 0085 (an agent's audience by roles), ADR 0074 (the router)
- Code: db `packages/db/src/schema/agents.ts` (`agents.builtin`, index `agents_one_right_hand`, migration `right_hand`), `schema/context.ts` (`proposal_target` `agent_settings`, `context_proposals.settings`, `requested_by_user_id`, `asked_at`, migration `right_hand_settings`); engine `right-hand.ts` (`ensureRightHand`, `ensureRightHands`, `followOwner`, `RIGHT_HAND_GRANTS`, `RIGHT_HAND_EDITABLE`, `refuseRightHand`, `rightHandReaches`), `right-hand-prompt.ts` (`rightHandPrompt`), `settings-proposals.ts` (`SETTING_GROUP`, `settingLines`, `applySettings`, `revertSettings`), `context/proposals.ts` (`askProposal`), `agent-proposals.ts` (`askAgentProposal`, `first_task`, superseded cards), `setup-tools.ts` (`propose_settings_change`, `request_settings_change`, `offer_approvals`, `propose_member_changes`, `offer_open_page`, `APP_PAGES`, the card cap), `card-via.ts` (`cardVia`), `skills.ts` (`importSkillFromUrl`, `importPickedSkills` with `forAgentId`), `agents.ts` (`unarchiveAgent`), `router.ts`, `organizations.ts`, `exports.ts`; on a plan (2026-11-04): db `agents.plan_for_others` (migration `right_hand_plans`), engine `right-hand.ts` (`thinkingAgent`, `scrubRightHandReply`, `rightHandPlanRefusal`, `rightHandNoAiReason`, `RIGHT_HAND_TURN`), `brains/select.ts` (`resolveBrain`, `mayFallBack`), `brains/claude-code.ts`, `brain-settings.ts` (`settingsAgent`), `ai-status.ts`, `no-ai.ts`, `executor.ts` (`brainUnavailable`), `machines.ts` (`machineAgents`), adapters `LOCKED_BRAIN_PROTOCOL`, runner `brain.ts` (`brainProfileLaunch("chat")`, `ClaudeProcess.lock`), `mcp.ts` (`CHAT_DENIED_TOOLS`, `chatToolsBreach`), `brain-opencode.ts` (`OPENCODE_CHAT_PERMISSION`, `opencodeToolsBreach`), `brain-codex.ts` (`CODEX_CHAT_OFF`, `CODEX_CHAT_CONFIG`, `codexChatBreach`, `chatFolder`), `brain-cursor.ts` (`CURSOR_CHAT_PERMISSIONS`, `cursorChatBreach`), `handlers.ts`, engine `tool-detail.ts` (`scrubSignIns`), `right-hand-prompt.ts` ("# Your tools"), engine `brains/codex.ts` (the chat gate), `email.ts` (`queuePlanOpenedEmail`), client `lib/no-ai.ts` (`planLine`); each person's own AI (2026-11-05): db `right_hand_brains` (migration `right_hand_brains`), engine `right-hand.ts` (`personalBrain`, `withPersonalBrain`, `rightHandPerson`), `brain-settings.ts` (`BrainScope`, `personalView`, `setPersonalBrain`), `machines.ts` (`machineAgents`, `accounts`), runner `keepAccount`, client `lib/right-hand.ts` (`rightHandFallback`); server `routes/app/agents.ts`, `routes/app/memory.ts` (`POST …/proposals/{id}/ask`, `POST …/agent-proposals/{messageId}/ask`); client `api/context.ts` (`CardVia`), `lib/app-pages.ts`, `lib/action-cards.ts` (`memberRowDone`), `lib/right-hand.ts` (`isRightHand`, `rightHandOf`, `RIGHT_HAND_DEFAULT`, `finishOnboarding`, `createWorkspace`, `introCards`), `lib/proposals.ts` (`settingLineText`, `decidersOf`, `onlyKey`, `sentToText`); web `components/RightHandCards.tsx`, `RightHandIntro.tsx`, `RightHandSettings.tsx`, `Sidebar.tsx`, `pages/OnboardingPage.tsx`; phone `features/right-hand/*`, `features/chats/logic.ts` (`rightHandPin`), `features/onboarding/OnboardingFlow.tsx`

## Context

People asked for a way to build and run the team by talking: "I need someone to answer customers by email", "put this agent on a better model", "what isn't set up yet?". Everything that does it already existed as screens and as cards agents may post (ADR 0061, 0081, 0092, 0129), but no agent was there to start them, and every agent's cards went through a review screen first.

ADR 0093 tried a narrower fix: a switch that made one agent take the messages the router gave to nobody. It answered one complaint (a person alone with a new team got no answer to "bom dia!") with hidden routing nobody could see on a screen.

## Decision

### 1. One built-in agent per workspace

- It is an ordinary `agents` row marked `builtin = 'right_hand'`, with a unique partial index on `org_id`. DMs, runs, budget, the Model Gateway's accounting, cards, the profile and the phone work as for any agent. Jev stays the router and judge behind the scenes; Ada stays a ready-made agent.
- It is made with the workspace (`ensureRightHand` in `createOrganization`) and, for workspaces made before, by a backfill that runs off the boot path (`ensureRightHands`), so every workspace has it on the next load. No announcement is posted.
- Its name is **Lodi**, the same in every language, with the teal look, happy eyes and the headset. Admins may rename it and change its look. Its label stays fixed: "seu braço direito" (en "your right hand", localized as each language says it).
- It can't be archived or deleted (403 `agent.right_hand_permanent`). Only its name, handle, AI and model, budget, look and audience change (`RIGHT_HAND_EDITABLE`), and it is on no computer (`agents.machine_id` stays null: no computer tools, no desktop, no terminal as it). It is left out of exports, so imports never make one, and out of the team counts and the invitation page.
- Amended 2026-11-04: its AI settings are any agent's: an API key of any provider (the model brain, as before) or a person's plan through any CLI the runner locks down for it: Claude's plan or a coding plan's key through Claude Code, OpenCode's, ChatGPT's through Codex and Cursor's (§4). On a plan it stores that brain and that plan's account (`brain_account_id`, never a computer's own sign-in), and its turns run as that CLI on the computer where the account is signed in (`thinkingAgent`: the Cloud workspace's always-on computer, or on a self-hosted server a computer someone connected). That computer lists it in its `agents` frame while it thinks there, so a computer where each agent is its own OS user lends it the sign-in; nothing else puts it on that computer, and every save of its AI sends the frames again, so the computer of a plan it left stops lending it even when the person saving never connected that computer. Only the account's owner gives their plan to it (`account.not_owner` otherwise); anyone who sets its AI may take it back to a key.
- **Codex and Cursor, an accepted risk** (the owner's decision, 2026-11-04). They were refused first (403 `brain.right_hand_plan`, now gone) for reasons checked on their CLIs, and those reasons still hold: neither says which tools a turn gets before it can use one (Codex 0.165's `exec --json` and app-server list none, and `codex debug prompt-input` with every feature that can be off still shows `exec` (a JavaScript sandbox with `apply_patch` and MCP resources in it), `wait`, `request_user_input` and the collaboration tools; Cursor's stream-json `init` documents no tool list), and both read their own sign-in from the account's folder, so a command of theirs could read that sign-in and print it. The owner accepted that: the people who could try it are the workspace's own, and with no malicious insider it doesn't happen. What is done instead is every mitigation the CLIs allow (§4): their tools switched off or denied as far as each documents, an instruction in its prompt, a kill at the first tool call that isn't our bridge's, and a scrub of every reply for sign-ins and keys. **The residual risk, plainly:** a determined insider could still get one command run (or one file read) before the runner sees its event and kills the process, and what that command does (send the sign-in out over the network, for one) is done by then; the scrub only keeps it out of the reply.
- "Atende outras pessoas" on a plan is its own switch (`agents.plan_for_others`, off when it moves onto a plan), never its audience: off, only the plan's owner's DM thinks with the plan and anyone else's run stops at once with one line (`plan_not_shared`); on, every DM within its audience does. It follows any agent's rule (ADR 0059 §5): the plan's owner chooses, an admin may override, and when someone else turns it on the plan's owner gets the same email (`planOpened`, `agent.plan_opened`, sent to the plan's owner through `thinkingAgent`). Each turn still acts as the person in that DM (§2), and each DM is its own CLI session, so it still keeps no memory across people.
- Its owner is the workspace's longest-standing owner who can still sign in, followed through role changes, people leaving and deleted accounts (`followOwner`).

### 2. One agent, a private DM per person, acting as that person

- Each person talks to it in their own DM. Every tool acts with the permissions of the person in that DM (`personBehindCall`, ADR 0053): a member's Lodi and an admin's Lodi are the same agent with different rights.
- Its prompt is read live on every run (`rightHandPrompt`): what the person behind it may and can't do, the team as they may see it (agents, models, apps, channels, routines, budgets), the setup checklist (no AI, an agent without one, no agent besides it, nobody invited, no app, no workspace context, no computer ready, an agent in no channel, a budget running out) and the card rules.
- It keeps no memory across people in v1: its memory tools are denied and its conversations are never reflected or learned from.
- It is in no channel. An @mention in any channel reaches it all the same (`rightHandReaches`, read by the mention lookups and `eligibleChannelAgents`), never in a DM between people, so the router never picks it and it posts nothing unless someone writes to it.

### 3. Who sees it and what admins set

- Everyone sees it by default. Admins narrow it through its audience by roles (ADR 0085). Outside its audience there is no row for the person. There is no off switch and no per-person hide in v1.
- Settings › Lodi (by its name and face, for `manage_agents`): name and look, AI and model (Automático, which starts it on the cheap tier), its own monthly budget (empty is the workspace's default), who may use it, the line that it can't be archived or deleted, and its audit log. Its agent page is the same short form; its instructions are the product's.

### 4. What it may do

Anything a person can do in the app, started as a card applied as whoever clicks (ADR 0129), checked against that person's permissions at the click, never when the card was written. The audit log records the person, `via` the right hand.

- **A new agent:** its `propose_agent` card reads **Criar** in one click, or **Criar e testar** when it carries a first task and the clicker is the person it is for (their DM with the new agent opens with the task in the composer, never sent for them: it would run with their permissions unread), plus Editar antes (Criar agente filled in) and Descartar. A newer card for the same agent puts the older one away (`superseded`). This amends ADR 0081 for the right hand's cards only: the card already shows everything the review screen would, and the click is still the person's. Other agents keep the review.
- **A teammate's settings:** `propose_settings_change` posts one card with a row per agent and decider: model, AI account, budget, owner, who talks to it, channels joined or left, reply mode, archive. Each row is decided by whoever may make that change on the agent's page (`manage_agents`; its owner too for its audience and channels; an AI account only by the account's owner, who must own the agent), applied through the page's own editors as them. A row made against a value that moved since is out of date ("Desatualizado", with Refazer). An applied row is a receipt with Undo (`agent.settings_changed`), which stops once someone changed it again; archive's Undo is `unarchiveAgent`. This amends ADR 0092 §5 for the right hand's card only.
- **Asking whoever may:** a person who can't decide a row (or create the agent) sends it with **Pedir a um admin** (`POST …/proposals/{id}/ask`, `POST …/agent-proposals/{messageId}/ask`). Each person who may decide it gets a waiting inbox entry (`change_request`), decided there; the asker's card reads whom it went to, then "Aplicado por …" or "Recusado por …" live (`proposal.decided`). Nothing is sent before they press it.
- **The rest exists already:** instructions, role and apps (`propose_instruction_change`, ADR 0092), creating a channel (direct, with Undo), routines, Connect AI, connecting an app and inviting people (ADR 0129 cards), archiving and deleting agents (§8). It may post up to 10 cards a turn, of every kind together; every other agent keeps 3, and none has the approvals, people or Abrir cards.
- **Approvals waiting for the person** (`offer_approvals`): one card listing what they may decide now, each approval drawn as the conversation draws it (its hold for high risk, Aprovar sempre where offered, Agora não asking why) and decided through the approvals path as whoever clicks. It never decides one itself.
- **People** (`propose_member_changes`): a row per person and change, making someone an owner or not (owners only, `manage_owners`), giving or taking roles (`manage_members`, only below the clicker's own) or removing them (`manage_members`, an owner only by an owner), applied with the members screen's own calls; removal opens the members screen's confirmation (what goes with them, then Remover). Inviting stays `offer_invites`.
- **Any other screen** (`offer_open_page`, a fixed list `APP_PAGES`): billing (the plan, Stripe's checkout and portal open there, for `manage_billing`; no money moves from the chat), deleting the workspace (owners: the email code, the typed name and the grace period) or one's account, one's password and sign-in, API keys and AI accounts, roles, the audit log, usage, computers, connectors, skills, storage, notifications, its own settings, import and export, approvals, routines, Drive, wiki, issues, calendar, an agent's page (memory, access, its own delete) and a channel. Its button opens that screen, which asks what it always asks and checks who may; a person who can't use it reads so. The phone opens its own screen where it has one, else the page on the website.
- **Keys, passwords and tokens** are still never typed in the chat: it posts the card whose button opens our dialog (`offer_connect_ai`, `offer_connect_app`, `offer_open_page` at the keys or the account).
- **Audited via it:** approvals decided and people changed from its cards carry the card's message (`via`, ignored unless that card names them), so the audit log reads them as the person, via the right hand, like every other card here.
- **Channels only through its cards:** it never puts an agent in a channel or takes one out by itself (`add_agent_to_channel` is denied to it): the channels rows of its settings card do it, decided like any other row. It can't be put in a channel or on a computer itself.
- **Its tools are fixed in code** (`RIGHT_HAND_GRANTS`): setup cards, reading context, reading the Drive and the wiki as the person behind the run (§12), routines and instruction proposals, without the memory tools, the web, apps, a computer, databases, writing files, mail, posting elsewhere or long work.
- **On a plan, the CLI gets those tools and nothing else** (amended 2026-11-04): the same `RIGHT_HAND_GRANTS` through our MCP bridge (the Tool Gateway lists and checks them per call, as for any computer brain), sent as the turn's `permissions.mode: "chat"` (`RIGHT_HAND_TURN`), which only a runner of `LOCKED_BRAIN_PROTOCOL` (41) gets: an older one reads any mode but `plan` as `work`, so its turn is `runner_outdated` (its DM says the computer's program needs an update) and nothing is sent. Every chat turn runs in the agent's own folder (Codex and Cursor: an empty folder of its own, `chatFolder`) whatever the request names, with no extra folders, no checkout prepared, none of the checkout's instructions and none of the agent's secrets in its environment.
  - **Claude Code** (flags checked against 2.1.318): `--tools ""` (none of its own tools), `--disallowedTools` every one of them too (`CHAT_DENIED_TOOLS`, ToolSearch, Workflow, ListAgents and ReportFindings included), `--strict-mcp-config` with only our bridge, `--allowedTools mcp__agentes`, `--permission-mode dontAsk` with no permission prompt tool, `--setting-sources ""`, `--disable-slash-commands`, `--no-chrome`, `CLAUDE_CODE_DISABLE_AUTO_MEMORY=1` and `ENABLE_CLAUDEAI_MCP_SERVERS=false`. The guard reads its `system` `init` line, which lists every tool the model gets and the MCP servers before the turn's first request comes back: anything but `mcp__agentes__…` and server `agentes`, or an `init` without the lists, or an answer before any `init`, kills the process at once and ends the turn with `tools_not_locked` (`chatToolsBreach`). On 2.1.318 the locked `init` lists `tools: []` plus our bridge's.
  - **OpenCode** (read in its source at 1.19.5): `OPENCODE_CONFIG_CONTENT` with only our MCP server and `permission` `{"*": "deny", "agenteschat_agentes_*": "allow"}` (OpenCode leaves out of the model's request every tool whose last matching rule is a `*` deny, `session/llm/request.ts`, so a tool a new version adds is left out too), the turn's model as its default model, `run --agent build --pure` (no plugins but its own), no project config, the global config folder emptied before each turn, `~/.opencode` with settings refusing the turn, no autoupdate, no LSP downloads. The guard runs `opencode debug agent build --pure` first with the same environment and folder: it lists every built-in, plugin and custom tool with whether that agent gets it, through the same rules; any tool on but ours, a failed probe or no list ends the turn with `tools_not_locked` before `run` starts. That list leaves out MCP servers' tools, so the guard also reads the agent's `permission` rules in the same answer: after the last `*` deny only `*` denies, ours and `external_directory` may follow (an allow that a config read after ours adds, such as an MDM or OpenCode console org config, stops the turn). A `chat` turn sets `OPENCODE_DISABLE_CLAUDE_CODE` (no `~/.claude/CLAUDE.md` of the computer in its context), and a tool of OpenCode's own that runs anyway kills the process at once, before what it read can be said.
  - **Codex** (flags checked against the installed 0.165.0: `codex exec --help`, `codex features list`, and `codex debug prompt-input` with the same switches): always `codex exec`, never the app-server; `--ignore-user-config` (no `config.toml`: no MCP servers, profiles or features of the account's), `--ignore-rules`, `-c approval_policy="never"`, `-c web_search="disabled"`, `-c project_doc_max_bytes=0` (no `AGENTS.md`), `-c features.code_mode.direct_only_tool_namespaces=["mcp__agenteschat_agentes"]` (Codex's catalog makes gpt-5.6 and gpt-6 `code_mode_only`, which puts every MCP tool inside `exec`; this offers our bridge's tools to the model directly, checked on 0.164.0 against a mock of the Responses API), `-c agents.enabled=false` (the catalog turns on the `collaboration` tools for gpt-6 although `multi_agent_v2` is off, and a `spawn_agent` emits no item while the sub-agent it starts can call our bridge unseen; this removes them), `--disable` for every feature of 0.165.0 that adds a tool or reads the computer (`CODEX_CHAT_OFF`: the route's `shell_tool`, `sleep_tool`, `skill_search`, `tool_suggest`, `plugins`, `apps`, `multi_agent`, `browser_use`, `computer_use`, `image_generation`, then `unified_exec`, `unified_exec_tty`, `shell_snapshot`, `skill_mcp_dependency_install`, `remote_plugin`, `plugin_sharing`, `multi_agent_v2`, `browser_use_external`, `browser_use_full_cdp_access`, `browser_annotation_api`, `in_app_browser`, `in_app_local_automation`, `view_image`, `hooks`, `memories`, `goals`, `code_mode_host` (so `exec` fails closed: an `exec` cell and an `apply_patch` it calls emit no item for the kill to see), `workspace_dependencies`; Codex refuses an unknown name, so a renamed one fails the turn instead of staying on), `--sandbox read-only`, our bridge as its only MCP server, no writable roots, an empty folder, and an environment without any sign-in variable or the agent's secrets. The kill (`codexChatBreach`) reads every `item.started`, `item.updated` and `item.completed`: anything but `agent_message`, `reasoning` or an `mcp_tool_call` to our server (a `command_execution`, a `file_change`, a web search, a collaboration call, a new kind) kills the process at once (`item.started` comes before a command runs) and ends the turn with `tools_not_locked`, passing nothing after it on.
  - **Cursor** (flags and rules checked against cursor.com/docs/cli/reference/parameters, …/permissions and …/configuration, read 2026-11-04; no Cursor CLI on the machine that wrote this): `agent -p --output-format stream-json --stream-partial-output --workspace <empty folder> --trust --disable-auto-update --approve-mcps --mode ask --sandbox enabled`, never `--force`; that folder holds only our `.cursor/mcp.json` and a `.cursor/cli.json` denying every built-in tool the docs list (`Shell(*)`, `Shell(*:*)`, `Read(**)`, `Read(/**)`, `Read(~/**)`, the same for `Write`, `WebFetch(*)`: `CURSOR_CHAT_PERMISSIONS`; a deny wins over any allow; its one allow is `Mcp(agenteschat_agentes:*)`, so a call to our bridge never waits on an approval), so no project rules, `AGENTS.md` or hooks. MCP tools can't be denied but for ours (a deny would win over our allow), and the account's own `mcp.json` or user rules have no switch: the kill (`cursorChatBreach`) ends the turn at any `tool_call`, started or completed, that isn't an `mcpToolCall` named `agenteschat_agentes-…` (or from that `providerIdentifier`). A turn killed after it already called our bridge posts nothing of what it wrote either, only its DM's line (`executor.ts`).
  - **Grok Build** (flags read in Grok Build 1.0.34's own docs and `--help`, ADR 0142; not yet run against a signed-in plan): `grok -p --output-format streaming-messages-json --tools search_tool,use_tool` (the MCP meta-tools stay whatever `--tools` says), `--disallowed-tools` every built-in its docs name (`GROK_CHAT_DENIED`, `Agent` blocking subagents), `--no-subagents --disable-web-search --no-plan --permission-mode dontAsk --allow MCPTool(agenteschat_agentes__*) --sandbox workspace`, in an empty folder of its own, `GROK_HOME` the account's folder with our MCP server alone in its `config.toml`, and Claude Code's and Cursor's MCP servers, rules, skills, agents and hooks, managed MCP and gateway tools, telemetry and self-update all off by env. The guard (`grokChatBreach`) reads every line: an `init` without the lists or with a tool but the meta-tools, a server but ours, anything before `init`, a tool block that isn't a meta-tool (a backend web search included, as its block starts) or a `use_tool` naming a tool that isn't ours kills the process and ends the turn with `tools_not_locked`. Its own sign-in sits in `GROK_HOME`, out of reach with no shell or read tool on the list, as with Claude Code.
  - **The Antigravity CLI** (flags and files read in antigravity.google's docs and changelog up to CLI 1.4.12, ADR 0143; not yet run against a signed-in plan): `agy -p --output-format stream-json --sandbox --disable-slash-commands --agent agenteschat-chat`, never `--dangerously-skip-permissions`; that agent, written in the account's home before each turn, has `tools: []`, `commandExecutionPolicy: off` and `subagent: false`; the home's `mcp_config.json` holds our server alone and its settings allow only `mcp(agenteschat_agentes/*)`; global agents, rules, skills, hooks and plugins are removed before every turn, and the empty folder's `.agents/` and `.gemini/` too. The guard (`antigravityChatBreach`) reads every line: an `init` without a tool list or with any tool but our server's, anything before `init`, a tool step that isn't ours or a subagent kills the process and ends the turn with `tools_not_locked`. Google's tokens, keys and client secrets join the scrub.
  - **Its prompt says so too** ("# Your tools", `RIGHT_HAND_TOOLS`, for every brain and every run, one with no person behind it too): it uses only its agentes tools, never runs commands, touches a computer's files, opens the web or writes out tokens, keys, passwords or sign-in data, and refuses and says so when asked. A model may not follow it, so it is no barrier: the kill and the scrub are.
  - **Every reply is scrubbed** before it is posted, whatever the brain (`scrubRightHandReply`, `scrubSignIns`): OpenAI and Anthropic keys and OAuth tokens (`sk-…`, `sk-ant-…`), JWTs (Codex's `id_token` and `access_token`), Cursor keys (`key_…`, `crsr_…`), OpenAI refresh tokens (`rt.…` as Codex 0.165's `auth.json` holds them, and `rt_…`), Google's OAuth tokens, API keys and client secrets (`ya29.…`, `1//…`, `AIza…`, `GOCSPX-…`), private keys, and the value of any sign-in file's field (`access_token`, `refresh_token`, `id_token`, `accessToken`, `refreshToken`, `apiKey`, `*_API_KEY`, `CLAUDE_CODE_OAUTH_TOKEN`) become a note in the language of the person behind the run, a key the person pasted included (the text of a reply cut by "Parar" too), and the audit log gets `right_hand.reply_redacted` with how many (never what). Its streamed text holds back its last word until it is whole and shows the same shapes masked, so nothing of one shows live either.

### 5. The coordinator goes

ADR 0093 is superseded. The switch, its chips and lines, the delete warning, `setCoordinator`, the first-agent claim, the `rule:coordinator` tier, its prompt line, the `agent.coordinator` event and their strings in all 14 languages are gone from the engine, the web and the phone. In its place, one router change (R2 in the design): in R5, a person alone in a channel with two or more agents gets the top-scored candidate when the message needs an agent (the existing need gate). When no step can read a message, the rules are reply, only agent, follow-up, else nobody.

Amended 2026-11-03: the first version let a greeting or small talk under the need gate ("bom dia!") wake nobody when the person was alone with two or more agents, which brought back the silence ADR 0093 had fixed. Now, when the router would wake nobody for a person's message and no other person is a member of the channel, the best placed agent answers it (the step's tie-break, else the top score, then whoever spoke here last), in a run it may pass on. It is stored as its own rule (`rule:alone`, reason `alone; best; …`); the receipt shows no line for it (a reason line adds nothing for a person alone with the team, so `alone` stays internal data). It counts in the default rule's cap (`DEFAULT_PICKS_PER_HOUR` a channel), so it can't loop. Never for an agent's message, a message already answered, a message for a person, a reply in another person's thread, a thanks, an ok or affection the step heard as social (an agent's reaction answers it), or a few words right after an agent answered this person's own message ("valeu" closes that exchange). It uses only the step's scores and social choice, with no word list, so it holds in every language. When no step can read the message, nothing changes.

### 6. Onboarding

The onboarding asks only the workspace's name (its logo and time zone), in Lodi's face, finishes the workspace at once and opens Lodi's DM (`finishOnboarding`), on the web and the phone. Making it is one round trip (`createWorkspace`): `POST /organizations` takes the workspace's zone, the owner's own (`memberTimezone`) and `finished`, and answers where it opens (`rightHandId`) with `GET /me` as it is now, so the app opens the DM without asking again; with a logo picked, the workspace is made, the logo sent, then `PATCH …/onboarding` finishes it with the same answer. `POST …/dms` answers the DM as the list has it (`dm`), which the app puts in its cached list instead of reading the lists again. A workspace left at any step of the older onboarding is finished and opened there. The top of Lodi's DM is drawn by the app, never stored, so it costs nothing and works before any AI is connected: its greeting, then its cards (`introCards`): Connect AI while there is none. With one, the start card (the ready-made agents, describing the need, an import or the form), for whoever may create agents: with no agent yet, or, while the person is the workspace's only member, the team is only ready-made agents and some are left, each tile its own Criar. With a team and nobody else yet, the next card under it (inviting people and the first task). Neither waits for the person, and none shows after. The workspace context and the computer, which the old onboarding asked for, are lines of the setup checklist.

Amended 2026-11-06: on a billing hold (ADR 0079 §7) the cards are the start card and what's next alone, with no Connect AI and no style card. The greeting's lead says the agents start with the plan, a tap on the start card posts that business's template with no model call, "Outra coisa" opens the gallery, and the top card offers the plan instead of inviting. Lodi can't answer there: anything written gets the wall.

Amended 2026-11-07 (ADR 0155 §6): for the workspace's owners the start card, the next card and Connect AI give way to one first-run checklist inside the greeting (what the workspace does, the team, an AI, apps, people), each row a dialog in place and read done from the data. Anyone else keeps Connect AI while there is none; how agents talk to them waits until the checklist is complete. Início's first steps give way to one line back to it.

On a person's first visit to Lodi's DM (they never read it, on any device: no `channel_reads` row of theirs, `everRead` in the DM list), Lodi's waving sticker shows under the greeting: the agents' sticker drawn from its look (`wave`, since 2026-11-04 also a mood people and agents send, ADR 0091), playing once, still with reduced motion, decorative, never stored and with no model call. That visit marks the DM read, so the next one, after a message or not, has no wave.

### 7. Cost

It runs on the workspace's AI through the Model Gateway like any agent: budget checked before each call, usage and cost recorded with `org_id` and its `agent_id`, and stopped by its own budget with the usual card. It never runs on Jev's or the platform's key; a message typed before any AI exists gets the standard no-AI card. Amended 2026-11-06: before a Cloud workspace pays, no turn runs on any AI, an API key included, and a message gets the wall (ADR 0079 §7), which replaces the "payment or an API key" of the plans decision.

Amended 2026-11-04: on a plan, the plan's owner pays, as for any agent on a plan: each turn's usage is recorded with `org_id`, its `agent_id`, the computer and the account, at no cost (`billed_to = plan`). It never stands in on an API key (`mayFallBack` is false for it) and never waits for its computer with a spinner: when the computer is asleep or paused, missing, signed out, the plan at its limit or the DM not its owner's while the switch is off, the run fails at once and its DM shows one line saying why (`rightHandNoAiReason`: `computer_away`, `plan_limit`, `plan_not_shared`, `runner_outdated` for a computer whose program needs an update, `plan_tools` when the guard stopped the turn, or the usual no-AI reasons) with "Usar uma chave de API", which moves it to the model brain on the key picked or saved there, and, while the workspace waits for its plan on the Cloud (no computer before payment), the way to pay. Only waiting its turn for room on a busy computer stays a wait. Connect AI for it offers every plan (Claude's and the coding plans, ChatGPT's, Cursor's, OpenCode's, Grok's, Gemini's) and every API key, as for any agent. Settings › Lodi, on the web and the phone, shows the plan's account with Change, or "Usar um plano", and "Atende outras pessoas" under a plan.

## Consequences

- Every workspace gets one more agent row. Lists that count "the team" leave it out; its row is its entry: the first row of Agentes, where the agents' DMs live (the web sidebar and Conversas on the phone), on a soft tint of the agent blue with "seu braço direito", outside the section's sorting and pins, never dragged or hidden, and still shown while Agentes is closed (alone on top of Conversas while there is no Agentes section); never under Mensagens diretas. Amended 2026-11-09 (ADR 0162): the workspace's agent count under its name ("1 membro · 4 agentes") counts it, as it lists it right under that count; "seu braço direito" is its one role name everywhere (its panel, its card and the phone's screens too, never the stored "Workspace assistant"); and it is never away (ADR 0084 §15).
- `agents.coordinator` and its index stay in the database, read and written by nothing, until no running version selects them (`check:migrations`); a later migration drops them. Workspaces that had a coordinator get an ordinary agent back, and nothing is posted.
- Stored decisions keep their strategy `rule:coordinator`, read as the default rule's line, and still count toward the per-channel cap for their hour.
- `PATCH …/agents/{agentId}` ignores an incoming `coordinator` and answers 200, because phones without an over-the-air update still send it.
- Every proposal made in conversation now keeps who asked for it (`requested_by_user_id`).
- On a Codex or Cursor plan (2026-11-04) the risk the owner accepted stays: one command or file read can happen before the kill (§1).
- On a plan (2026-11-04), the CLI keeps each DM's session in the account's folder on the plan's computer, as for any agent on a plan: with "Atende outras pessoas" on, whoever controls that computer could read other people's conversations with it there.

## Alternatives considered

- **Jev as the right hand:** Jev has no agent row and runs on the installation's key; making it a chat partner mixes "the model that routes" with "an agent on your AI" and puts its cost on our key.
- **Promote Ada:** she is the Dev preset, renamed, reassigned and deleted like any agent; one face would do two jobs.
- **One right hand per person (N rows):** private memory, but N budgets and a roster that grows with the people. One row acting as the person in their own DM gives the same privacy.
- **Keep the coordinator, hide its switch:** an agent answering what nobody took with no screen saying why.
- **Move the coordinator's routing to the right hand:** it would answer unasked in channels and run on every unclaimed message.
- **Make it a hidden member of every channel** so mentions reach it: it would show in rosters and need a membership row per channel; reading it in the two mention lookups was smaller.

## Amendment (2026-11-04): agents act on agentes.chat through their tools, never by signing in to it (§8)

### Context

A person asked an agent "Quero apagar todos os outros agentes e vamos reconstruir tudo novamente." The agent had no tool to archive teammates (only the right hand's settings card had an archive row), so, following the rule that a step needing a person is handed over, it opened its browser and asked the person to sign in to agentes.chat there with the admin account. That would put a person's session, with every permission they hold, on the agent's computer, outside the audit, the cards and the permission checks. In other products the agent acts on the other agents directly; here it should too, as a card.

### Decision

1. **A removal card for any agent** (`propose_remove_agents`, under `setup:write`, so every agent with the setup tools and the right hand): one card listing the agents to archive, or to delete for good when the person asked for that (`delete: true`). One `agent_settings` row per agent with a single `archive` or `delete` line, decided by whoever manages agents (`SETTING_GROUP`), applied as whoever clicks, one row at a time. It never names the agent that proposes it, nor the right hand. On the web it reads "Arquivar 5 agentes?" with the agents listed, each with its switch, and "Arquivar todos" (or "Arquivar 3" with some switched off) and Descartar; a person who can't archive reads "Só admins arquivam um agente" and sends every row with "Pedir a um admin"; archived, "Aplicado por você: …" and one Desfazer for the whole card (`undoMessage`). On the phone the rows show as the settings card's rows, each applied on its own.
2. **Deleting from a card** follows ADR 0082 as it is: `manage_agents`, never the right hand, no Undo (no receipt), and nothing goes before the name is typed: on the web "Apagar todos" opens a dialog with the names, what goes and what stays, and the name typed to confirm (with several, how many); on the phone a delete row opens the agent's delete screen, which accepts that row. An archived agent can be on a delete card (and a delete row still applies once its agent is archived). The row is marked accepted, then `deleteAgent` runs as the clicker outside the decision's transaction (its missions, routines and work on its computer stop there); if that fails the row is open again. A deleted agent's decided settings rows stay (its other proposals go), and only the row that deleted it is shown, so the card still reads how it ended without its earlier settings. This replaces §4's "never delete an agent" for the right hand: it still never deletes, a person does from its card.
3. **Never sign in to agentes.chat itself.** The browser guidance says it: sign in to the account the person names, but never to agentes.chat, the app the agent works in, nor ask a person to; change the workspace with its tools and cards, and where none does it, link the person to the page. `browser_ask_person` and `desktop_ask_person` refuse a hand-off whose instructions name our own app (this server's `PUBLIC_URL` unless it is loopback, where it is another app on the agent's computer, or agentes.chat and its subdomains; an email address there aside, a URL's `user@` and width forms or an ideographic full stop not), and `browser_ask_person` also when the agent's browser shows one of its pages. The refusal names the cards to use and the links to the team and settings pages (`appPageLink`).
4. **Rebuilding:** a "start over" turn is one removal card, then the new team. Amended 2026-11-04 (§10): the right hand proposes the new team with one team card (`propose_team`); other agents keep a `propose_agent` card per new agent, within the cards a run may post (3; 10 for the right hand).

### Consequences

- The tool group label names archiving and deleting, so `find_tools` reaches the card from "apaga os outros agentes" (the eval's `start-over` turn).
- An agent can no longer hand its browser to a person on agentes.chat, even for work a person wants there (testing the product itself on its own Cloud workspace, say); browsing it on its own still works.
- A self-host's server reached by its IP address, rather than its `PUBLIC_URL` host, is not recognized as our app.
- `ProposedSettingLine.field` gains `delete` (no migration: the lines are JSON).


## Amendment (2026-11-04): it starts everything a person does in the app (§4)

### Context

§4 listed what the right hand never did, even when asked: deciding approvals, people's roles and removal, billing, deleting a workspace or an account. Those are things people ask it for. The decision: most, if not all, of what a person does in the app should be possible through it, with the confirmation the app already asks for.

### Decision

1. Each of those became a card applied as whoever clicks and checked at the click (§4 as written above): the approvals card, the people card and the Abrir card. Its tools stay fixed in code (`RIGHT_HAND_GRANTS`: no new scope, the three cards are setup tools for it alone), within its 10 cards a turn.
2. What it starts with a card now: a new agent; a teammate's model, AI account, budget, owner, audience, channels, reply mode and archiving; instructions, role and apps; archiving or deleting agents; a channel (direct, with Undo); routines; Connect AI; an app or an MCP server; invitations; approvals; people's ownership, roles and removal; and, through Abrir, every screen in `APP_PAGES`.
3. Left as a screen it opens, not a card of its own: creating issues, wiki pages, Drive files and calendar events (it has no tools that write them); a channel's settings, archiving and permissions (Abrir opens the channel); roles' permissions; computers (pairing and control need the person at the device); join requests; mailboxes and databases. Never from it: anything written in the person's name (messages, reactions, posts elsewhere: `post_message` and `send_dm` stay denied), and moving money.
4. The phone draws the approvals and people cards as a line whose button opens the matching screen (the approval, Membros), and Abrir opens its own screen or the page on the website.

### Consequences

- The setup group's label names the right hand's cards, so the judge loads them for "aprova o deploy" or "quero cancelar o plano" (a DM "oi" grows to 44,789 characters, under its ceiling).
- `PATCH …/members/{userId}`, `DELETE …/members/{userId}` and `PUT …/members/{userId}/roles` take `?via=`, and an approval's approve, refuse and `decide` take `via`: the card's message, recorded in the audit's details only when that card names the approval or the person.

## Amendment (2026-11-04): "Semana da equipe", a weekly card for each admin (§9)

### Context

A beginner asked for a lead agent that, after the team exists, points out what isn't working and suggests improvements. Another customer's lead split work into five steps and finished only the first: the reviewer rejected step 1 four times and steps 2 to 4 waited on it for hours, with nothing saying so. Lodi never spoke first (§2: it posts nothing unless someone writes to it), so neither reached anyone. The owner approved the "Semana da equipe" concept: one card a week in place of several notes and cards.

### Decision

1. **Who and when.** Each person who holds `administrator` (owners included) and may talk to Lodi gets one card a week in their DM with it, on Friday at 17h in the workspace's time zone by default. It is the one exception to "posts nothing unless someone writes to it". Each person moves or stops their own (`organization_members.team_week`, `{ off?, day?, hour? }`, migration 0218, read through `teamWeekPrefsOf`): from the card's footer ("Toda sexta às 17:00 · Mudar"), from Settings › Lodi ("Semana da equipe", on the web and the phone), or by telling Lodi (`set_team_week`, a setup tool for it alone, acting for the person behind the run).
2. **The job.** A worker tick every 10 minutes (`enqueueTeamWeeks`) queues `team_week.post` in the outbox (ADR 0005) for every admin whose slot passed in the last 6 hours, in open workspaces with Lodi and at least one other agent; its dedupe key is the person and the Monday of the slot's local week, so moving the day never sends a second card that week. The handler (`postTeamWeek`) checks again who may get it, builds the card and posts it as Lodi with no run, enqueuing `notifications.message` like any agent's message in a DM. A week with nothing to say (no work done, none stuck and no row) posts nothing; no team, no card.
3. **What it says, from stored data, with no model call** (`buildTeamWeek`): the week's work done and runs that failed, the approvals waiting for this person, the money spent this month against the team's monthly budgets added up, the busiest agent per channel this person can read and the tasks agents closed ("Funcionou"), then up to 6 rows ("Para melhorar"):
   - approvals of one agent waiting for them ("Ver e aprovar" opens them on the card as the conversation draws them, decided one by one);
   - an agent that stopped at its budget (`budget_exceeded`): a settings proposal to raise it by half, in whole dollars;
   - an agent in no channel for a day or more: a settings proposal to put it in #general (else the oldest public channel);
   - people's questions in a channel this person reads that nobody answered within a day (three or more): "Propor um agente" sends Lodi, as the person, a message asking for one, in that DM;
   - the same request typed by this person to one agent on three days or more (words compared without accents, mentions or punctuation), with no routine of that agent doing it: "Criar rotina" makes a daily routine at the hour it was usually asked, reporting where it was asked;
   - a task whose steps (`parent_issue_id`) wait for 4 hours or more while another step is in progress, in review or blocked: "Liberar em paralelo" posts, as the person, in the task's conversation (ADR 0144), mentioning its agent, that those steps don't need to wait.
4. **Applied as whoever clicks.** Settings rows are the settings card's own proposals (`proposeSettings`, decided through `decideProposal`, an open one reused the next week), so their receipt and Undo live on the week's message (`cardOf` reads a card's `proposalIds` whatever its kind, and a receipt carries no run). Approvals go through the approvals path. The routine, the message to Lodi and the task's message go through `POST …/team-week/{messageId}` (`actOnTeamWeek`), only for the person the card is for, with their words in their language, and are kept on the card (`done`). "Aplicar as N" runs every open row but approvals. "Agora não" puts the card away (`dismissedAt`).
5. **Privacy and cost.** Only counts, names, channels this person can read and their own requests; the card lives in their private DM. No model call builds it, so it costs nothing; asking Lodi for an agent is an ordinary turn on its budget through the Model Gateway.
6. **Phone.** The same card, its rows stacked with their buttons under the words; approvals open the phone's approval screen and "Mudar" opens Settings › Lodi, where the day and the hour are pills. The push reads "Lodi: Sua semana da equipe está pronta" (the message's text, written in the person's language).

### Consequences

- Lodi's DM gets one more message a week for admins; people stop it in one tap or one sentence.
- A settings proposal made for a week's card stays open until someone decides it; the next week reuses it rather than stacking a new one.
- A Monday 9h card is a setting, not the default the earlier concept drew (design R2 tab 6): the Friday card closes the week the team just had.

## Amendment (2026-11-04): the team set up from three questions, one team card (§10)

### Context

A beginner found the app clear but got stuck deciding how many agents to make, what each does and how they work together, and worked it out with another AI outside the app. The start card offered four ready-made agents and four ways in, each asking the person to already know what they need, and a team of three came as three separate cards that never showed the team as a whole (§8 said no card proposes several agents).

### Decision

1. **The start card asks first.** With an AI and no agent yet, it reads "O que a Acme faz? Com isso eu monto um time pronto, e você só confere." with the business types to tap (agência, loja online, clínica ou consultório, software e apps, atendimento ao cliente, escritório de serviços, outra coisa) or a sentence typed. Each tap is the person's own message in the DM ("outra coisa" puts the cursor in the composer); answered, the card reads "respondida" with the pick checked. The ready-made agents, an import, the form and the team templates move to its footer ("Já sabe o que quer?"). It is still drawn by the app, costs nothing and stores nothing.
2. **Two more questions, as answers to tap** (`offer_answers`, the right hand's only): its message with the question, then chips (`meta.replyChips`: the answers, one or several with "Enviar N", "Pergunta N de 3"). Each tap is a normal message of the person's, typing works all along, and once a message of theirs comes after it the chips show what was picked and take no tap. One a turn. Its prompt runs the interview while the team is empty, in its DM (`TEAM_INTERVIEW`): what takes the most time (several), who else works there, then the team.
3. **One team card** (`propose_team`, the right hand's only, `meta.actionCard.kind = team_proposal`): up to 6 agents, each with its face, name, role, one line, the channel it lives in (an existing one by name, or a new one, marked "novo"), up to 3 routines (schedules read when proposed, as `propose_agent`'s), a first task; up to 4 skills for the team's own agents; a line on what waits for approval; the people named in question 3; and the right hand's weekly check (Fridays at 17h in the person's time zone, in their DM with it, concept C's routine). A newer team card in the conversation puts the open one away (`superseded`).
4. **"Criar o time"** (`POST …/team-proposals/{id}/create`, `create_agents`) makes it all as whoever clicks, through the app's own calls (`createChannel`, `createAgent` with the card as `via`, `addChannelMember`, `createRoutine`, a skill as Settings › Skills writes one), in one transaction: a step that fails creates nothing, and the card stays open with that step and its reason ("Tentar de novo"; the reason keeps the error's status and code so the app says it in its language, and a server error keeps no driver text). An existing public channel the clicker isn't in is joined first, since an agent joins only channels its owner is in; a private channel they aren't in, or one archived by someone else, can't be named (a template takes `financeiro-2` there). Skills are an admin's (`manage_agents`) and the weekly check is for who may manage the right hand's routines: without that right they are left out and the receipt names them, the rest is made. Each agent's AI comes after, as for one proposal (an account of the clicker's that thinks for no agent, else the workspace's model; an agent with nothing to think with opens Connect AI). "Ajustar" edits one agent's draft on the card (name, role, line, channel, instructions, first task) before the click (`PATCH …/agents/{handle}`), in a dialog on the web and a sheet on the phone, so the team still comes in one click. "Ver como mapa" shows the same team read only: the people, a column per channel with its agents and routines, the right hand as the weekly reviewer. Descartar closes it (whoever it was for, or who creates agents).
5. **After the click** the card is a one-line receipt with Desfazer (a day, by whoever created it or an admin: its routines and skills go, its agents and the channels it created are archived), then a "Primeira tarefa" card for whoever created it: a row per agent whose "Abrir com a tarefa" opens its DM with the task typed and not sent, and "Convidar …" for the people named (the invite dialog, with any address given). The right hand hears what was made in a notice and says it in one line.
6. **Team templates** ("Ver modelos de time", on the start card's footer): six business types (agência de marketing, loja online, clínica ou consultório, software e apps, atendimento e suporte, escritório de serviços), each a team of the same few agents, kept in code (`team-templates.ts`) with their words in `@agenteschat/i18n` (`teamTemplates.*`, every language; a channel name that isn't a valid name in a language takes its English one). The gallery previews each as its card would propose it (`GET …/team-templates`); "Usar este modelo" (`POST …/team-templates/{id}/use`) posts it as the right hand's team card in the person's DM with it, with no model call, then its first question to fit it (1 of 2), whose answer starts its turn: it asks the second and proposes the team again.
7. **The phone** draws the same: the start card's chips, the chips under a question, the team card as stacked rows with the same buttons (Ajustar opens a sheet), the receipt and first tasks, and the templates and the map as sheets.

Amended 2026-11-07 (ADR 0155 §6): §1's start card is gone. Its question is the first run's row 1 ("O que a Acme faz?", the business types and one sentence, saved as the workspace's context), and §6's "Usar este modelo" is "Criar o time": the template's team is made at once, its card posted already created with Desfazer, with no question after and no model call. The interview of §2 and §3 stays for whoever types, its first question skipped once the context says it. Ajustar leaves the first run, since the card is never open there.

### Consequences

- The card's state lives in its message (`meta.actionCard`), like the other cards: no migration. `team.proposal.updated` carries the whole card to the conversation.
- A template's card is posted with no run behind it, so nobody is told when it is created; the right hand reads it in the conversation.
- The questions and the team cost tokens on the workspace's AI, as every turn of the right hand does; the templates cost none.
- A member who creates agents but doesn't manage them gets the team without its skills, which wait for an admin.

## Amendment (2026-11-04): the team map's drag is its settings card (§4)

Equipe › Mapa (ADR 0148) lets a person drop an agent on another channel. The map never moves it: `proposeChannelMove` (`team-map.ts`, `POST …/team/channel-move`) posts the right hand's settings card in that person's DM with it, with a `channel_add` row (answering there as it did where it was) and a `channel_remove` row when it came from a channel, through `proposeSettings`. The card's reason is the map's line ("Levar Ada de #eng para #vendas, pelo mapa da equipe."). It is decided, applied, audited and undone like any of its cards. It isn't one of its turns: no run, no tokens, and the right hand's delegated approvals (ADR 0139) don't take it, since the person asked for a card to apply themselves.

## Amendment (2026-11-05): each person's own AI (§11)

### Context

One AI for the whole workspace didn't fit a private DM per person. Lodi's plan was one person's, so everyone else's DM either stopped ("só atende o próprio dono") or spent that person's plan. An admin who gave it a colleague's plan lost their own Lodi, and the colleague's plan left the dialog.

### Decision

### 11. Each person's DM thinks with that person's AI

- **Each person's own.** A row in `right_hand_brains` (one per member, it goes with the membership and with the account) names the plan their DM thinks with: the brain, its model and effort, and the account. A table, not columns on `organization_members`: the account's foreign key cascades, and `organization_members` stays about the person.
- **Whose plans.** Their own, on any computer of the workspace. Someone else's only with `use_others_plans`, by the same rule as giving one to any agent (ADR 0059 §3): its owner gets the same `agent.plan_lent` note, the row keeps who gave it, and `takeBackPlan` deletes it. Nobody's plan serves someone else otherwise. A login made for one agent still thinks for one: an account that isn't `shared` and already thinks for another agent is `account.in_use`.
- **The workspace's AI.** The right hand's own `agents` row is now the fallback for people with no row. Admins set it: an API key, or a plan under "Atende outras pessoas" (§1). Off, that plan answers only its owner; a person with no plan of their own reads `plan_not_shared`, with "Conectar meu plano". An API key is always the workspace's, never a person's.
- **It goes with the sign-in.** `releaseAgents` deletes the rows of an account that goes (removed, its owner leaving), so a DM doesn't wait on a runner to say so. `orgHasAi` counts these rows: a person's plan may be the workspace's only AI. AI accounts lists the right hand under any plan it thinks with, `usedBy` as for any agent. A login that isn't `shared` moves like any agent's: to a person's right hand with `moveAccount`, and to an agent out of everyone's right hand.
- **Resolved per run.** `rightHandPerson` reads who is behind the run (`personBehindCall`, ADR 0053), and `resolveBrain`, `agentAiState` and the executor put that person's row over the agent's brain fields (`withPersonalBrain`). Everything else is §1 and §4 unchanged: a locked-down `chat` turn on the plan's computer, the plan's owner paying, no fallback to a key. A run with no person behind it thinks with the workspace's. On a plan that answers only its owner it can't, and no one's own plan would answer it either, so its line never says to connect one: `plan_unattended` ("o pedido não veio de uma pessoa"), with "Usar uma chave de API" for whoever sets its AI (anyone else reads who does). Work that comes back to a run (a decision on its card, an answer) carries that run (`refs.runId`), so it keeps the person it was for.
- **`GET` and `PUT …/agents/{id}/brain` take a `scope`.** The route's default for the right hand is `mine`, any member's own, so the Connect dialog on the web and the phone works for it as for any agent. `workspace` is the fallback, for admins. The engine's default stays `workspace`: cards and setup change the workspace's. Every other agent ignores `scope`.
- **`GET …/ai-status` is per viewer**, so its "Sem IA" chip and Connect cards say what the viewer's DM can do.
- **On the computer.** The `agents` frame lists the right hand where any of these accounts is signed in, the extra ones in `accounts`, so in system mode its user keeps them all while it thinks. A runner that doesn't read `accounts` keeps only `account`, and lends the others turn by turn. The frame's field is additive: no protocol bump.
- **The screens.** Settings › Lodi and its panel show "Sua IA", then "IA do workspace" with its key or plan and "Atende outras pessoas". Everyone else gets "Sua IA" on its page. Connect for it shows no "Atende outras pessoas": a person's own serves them alone.

### Consequences

- An admin's own Lodi no longer depends on the workspace's plan, and an admin is never told only an admin can connect one.
- A person's turns can run on a different account than a colleague's on the same computer at once, as the same agent's OS user in system mode. They are separate CLI sessions (each DM is its own, §1), and the accepted risk in §1 stands: that user holds more than one person's sign-in while it thinks.
- A person's plan on a computer that is away says so (§7); it doesn't fall to the workspace's, which is for people with none.

## Amendment (2026-11-05): the team can be built with it at any time (§10)

The start card reads the conversation's first message as its answer and leaves once the team grows, so someone who wrote before connecting an AI, or came back later with agents already here, had no way in. For whoever may create agents, once an AI is there and the start card has stopped asking with no interview under way, the greeting ends with a line and a text action ("Montar o time") that sends their message. The interview is in its prompt in every DM, not only with no team: asked in words or by that line it runs, asks question 1 when it wasn't answered, and proposes around the agents already here.

## Amendment (2026-11-06): one thing at a time (§10)

A first conversation piled up: the start card and "how should I talk to you?" asked at once, the prompt's "not set up yet" list had it offer invites, apps and the computer on top of the interview, and a greeting read as the start card's answer, which left it "respondida" with live buttons and a second "build the team" line under it. So:

- **The greeting's cards are one question at a time** (`introCards`): Connect AI, the start card, then how agents talk, then what next. The ready-made tiles keep what next beside them, as neither waits on an answer. The "build the team" line shows only with a team and no card left.
- **The start card's answer is the first of its choices the person sent, or, once the interview or a team card followed, what they wrote** (`startCardAnswer`). Anything else leaves it asking. Answered, it keeps only the pick: no other chips, no footer. Answered chips are the same under a question.
- **One question or offer a turn.** `offer_answers`, `propose_team`, `offer_connect_ai`, `offer_connect_app` and `offer_invites` go through `cardsLeft(ctx, true)`: for the right hand a second one in a turn isn't posted and the tool tells it to end the turn, as no error, since nothing failed. Other cards (several `propose_agent`, settings changes) stay as they were: the person asked for those.
- **One Connect.** With no AI, once a person typed, the no-AI card under their message offers it, and the greeting's card goes.
- **Nothing waits on a card.** It is only ever a limit on what the right hand posts: the composer stays free, and whatever the person types comes first.
- **With no team, "Not set up yet" holds only the AI and the team**; with one, it raises the first that fits, once what they asked is done, one per turn.
- `propose_team`'s routines ask for cron: words need the workspace's small model through the gateway, which a workspace on a plan alone doesn't have, so the first card failed with a schedule error.

## Amendment (2026-11-06): it reads the Drive and the wiki for the person (§12)

### Context

A person gave Lodi an HTML file in its DM, in the Drive and in the wiki. Every `read_artifact` and `search_wiki` of its turns came back "lacks the scope". Its tools were fixed in code without those scopes on purpose (§4: "so it can't be used to reach data"), and the refusal told it to use `request_permission`, whose card could not work: `loadScopeKeys` ignores grant rows for it. It then asked the agents it had created, which had no way into its DM.

### Decision

### 12. It reads what the person behind the run may read

- **`drive:read` and `wiki:read` join `RIGHT_HAND_GRANTS`.** A person who hands their right hand a file expects it read. No migration: its grants live in code, so every workspace has them at once, on every brain. The bridge lists the same tools to a plan's locked-down turn, so those turns and the model gateway read alike; nothing is added to the CLI, and §4's switches and kills stand.
- **Bound by that person.** Reads go through the rule for any agent (ADR 0111): its run's conversation and what the person behind it may see, so one person's DM with it stays closed to another's. A wiki page limited to people follows `wikiActorOfCall`. With nobody behind a run it reaches the org-wide Drive and nothing private.
- **Reading only.** `share_artifact` is denied: copying a file into a conversation would be posting. No `drive:write` or `wiki:write`: writing stays a screen `offer_open_page` opens. The prompt's "# Your tools" says it reads with these tools and never touches a computer's files.
- **What is outside stays honest.** `request_permission` is denied and `missingPermissions` offers it nothing, since nothing can turn on a tool for it; a refused tool answers `RIGHT_HAND_REFUSAL` (hand the work to the agent whose job it is, or propose one) instead of an admin's screen that does nothing for it.

### Consequences

- What a file says now reaches a turn that can write cards. A card still needs a person's click, it has no way to send anything out, and its replies keep the scrub of §4, so injected text can at most propose. The file's text comes marked as data, like any agent's.
- It can read a file and then hand the work over: `ask_agent` passes the id, and the agent asked reads it for the same person (ADR 0111).

## Amendment (2026-11-06): the one you talk to (§13)

### Context

After onboarding the right hand couldn't see the team: `search_context` and `read_conversation` reached only channels it is in, and it is in none, `issues:read` wasn't among its grants, and its prompt named no way to hand work on. A customer called it useless past setup, and asked to talk to one agent about all of it.

### Decision

### 13. It sees what the person sees, and hands work on

- **It reads as the person, in their DM (`rightHandReader`, `personReach`).** With a person behind the run, in a DM where they are the one person, `search_context`, `read_conversation`, `get_summary` and `expand` read what `readableChannelIds` lets them read, plus public channels, through `searchForUser`'s own filters. Never a routine's room. Called by name in a channel it keeps its reach, because others read that reply.
- **`issues:read`, and `create_issue` as itself, only in the person's DM.** `update_issue` and `comment_issue` are denied. Called in a channel, both refuse (`rightHandAway`), since others read that reply. `list_issues` lists what the person sees. A task it makes is written as the agent, never in the person's name, stays with that person and administrators (`visible_to: everyone` refused: the person opens it on the task), is never assigned to itself, and is refused to who may not post. Real work is `create_issue`, then `tell_agent`, whose report comes back through `reportHandOffs`.
- **`team_status` (`team-status.ts`).** One tool, no model call, from stored data: what each agent does now, open and stuck tasks, what finished and failed today, what waits for this person. Only agents they see, the rest a count. Work in a place they can't read says "busy with something this person can't see", with no subject, unless it runs for them (a hand-off in the agents' DM, `readerOfRun`). Questions count only those whose run works for them. Hidden characters are stripped from titles. Titles are plain text with angle brackets taken out, not in `<external_data>`, so asking doesn't mark the run as outside. In the core group, so it is listed on the first turn, and only in the person's own DM.
- **The prompt.** Its first paragraph names `team_status`, `ask_agent`, `tell_agent`, `create_issue` and `follow_up`. What it handed on and hasn't heard back was already there (`# Work you handed off here`). Its size is paid for by trims in the same block: an "oi" costs less than before. `RIGHT_HAND_AUTO` keeps a status cheap and gives handing work on and reporting the medium tier.
- **§4's "every change is a card" is amended** by ADR 0092's amendment of the same date.
- **What stays.** It acts as the person, never more. No computer, shell, web or file writing. No `post_message` or `send_dm`. No long work of its own. It never decides an approval in chat. No memory across people. In no channel, and the router never picks it.

### Consequences

- What a person may read now reaches a turn that can write cards, marked as data. `read_conversation` and `search_context` mark the run as outside, so a change right after them stays a card.
- On an API key it has one budget for the whole workspace, sized for setup chat. One heavy person could stop it for everyone. ADR 0141's limits cover this but are off by default.

## Amendment (2026-11-07): one thread per piece of work (§14)

### Context

§13 let the right hand hand work on with `tell_agent`, which runs in the two agents' DM that nobody reads. For real work the person wanted to follow it, talk to the agent about it, and keep their DM with the right hand a short log. A task already is that (ADR 0145): its own conversation, receipts, stop, and everyone who sees the task follows it.

### Decision

### 14. A task it hands on starts there, and comes back here

- **`create_issue` assigned to an agent starts that agent in one step** (`askAgentToImplement` with `by`). The start message in the task's conversation is written as the right hand, from its run, never in the person's name. The checks come before the task is made: an agent the person may talk to directly (its audience, not `viaAgent`, since they read the conversation), one the right hand may call, never itself. A task with no agent, or a person, starts nothing.
- **It is a `note` row of the right hand's run** (`agent_consultations`, its channel the task's conversation). The consulted run's end settles it as in an agents' DM (`answersHandOffs`), so what came of it reaches the person's DM by itself (`reportHandOffs`), and its cards go there (`consultationOrigin`). A stop in the task's conversation is heard the same way.
- **The chip.** The tool returns `data.handedTask`, and the reply carries `meta.tasks`: one chip per task, "#42 Campanha de Natal · Ada · Em andamento", live, that opens the task's conversation beside the chat (web) or as a thread (phone). The `issue.created` receipt of that task is left out under it: the chip is the task.
- **The audience** stays the person and administrators (§13), which they widen on the task (ADR 0151).
- **Resumo do dia.** The weekly card (§9) can come every day at an hour instead (`team_week.daily`), over the last day, from the same builder with no model call, on days with something to say. Anyone may turn it on, telling the right hand (`set_team_week` `daily`) or in Settings › Lodi. Anyone but an administrator gets runs counted only where they read, no money and no budget row; a fix the card can't offer them leaves no proposal behind. The weekly card stays the default, for administrators.
- **The prompt** names `create_issue` assigned to an agent for real work and `tell_agent` for a small thing, and that either reports back by itself.

### Consequences

- The work and any talk about it live in the task's conversation. The DM with the right hand reads as chips and reports.
- A task's agent asking something lands its card in the person's DM, where they asked, not in the task's conversation.

## Amendment (2026-11-07): out of the reporting line (§15)

The right hand is nobody's supervisor and reports to nobody (ADR 0148's addendum refuses it at either end). It reaches what each person reaches already, so an agent with no supervisor needs nothing written. The Organograma draws it as a slim chip beside the workspace, "acompanha tudo com você", opening its DM, not above the people.

## Amendment (2026-11-07): it does what the app lets the person do (§4)

### Context

Asked to create a role for a marketing person who may not merge or deploy, the right hand said it could only assign one afterwards and opened Papéis e permissões for the owner to do it by hand. It was following the amendment of 2026-11-04 (§3 there), which kept roles' permissions, a channel's settings and more as screens it only opens. The standing decision says otherwise: it does almost everything the person can do in the app, as them, with the app's own confirmations.

### Decision

1. **One catalog tool, `workspace_action`** (the setup group, the right hand only). `find` returns the best actions with their input and whether this person may; `action` does one. Each entry is the engine call its screen makes with the person as the actor, so every rule of that screen holds (a role below theirs, only keys they hold, a channel they manage, their own status). One tool for all of them keeps its prompt the size of one, and the prompt names it in one line.
2. **At once with Undo** when the person may decide it, asked in their own words (`ownWords`): a `workspace.changed` receipt on the reply, `params.action` saying which. Desfazer runs the entry's own inverse as whoever clicks, refused when the target moved since (a new role someone or something holds since, a channel exception, an invitation). What can't be undone (cancelling or resending an invitation, stopping or continuing work) still applies at once, and the right hand says it can't be undone. At most 10 such changes a turn.
3. **A card otherwise** (`meta.actionCard.kind = "workspace_action"`): after outside content was read, when the screen's check refuses the person, or for what can't be undone or is a safety switch (deleting a role or a channel, the action check). Aplicar runs it as the clicker and puts the receipt, with Desfazer when it has one, on the card. The person it was for and can't sends it to whoever may (`change_request` with `source.action`), who opens and applies it from their inbox without reading that DM (nobody else: a card no key opens goes to the owners). Refused at Aplicar by the screen's own rule (a role above theirs), the card of the person it was for turns to sending it on. A card of the person's own status, notifications or time zone is theirs alone to apply. The card shows everything it changes (permissions, a new name, privacy, a budget), so whoever applies it from their inbox sees all of it. The people card's roles given at once count toward the same 10.
4. **The catalog today**: create, change, move and delete roles; give and take a person's roles; a channel's exception for a role or a person; their own status, notifications and time zone; a channel's name, topic and privacy, archiving and bringing it back, its people, deleting it; cancelling or resending an invitation and changing the roles it gives; deciding a request to join (a card); stopping and continuing an agent's work; the workspace's name, time zone and default budget; the action check. Beside it: the people card's role rows apply at once with Undo (ownership and removal stay on the card), `propose_settings_change` names people too in who may talk to an agent, `update_issue` is no longer denied (a task the person sees, in their DM), `delete_routine` and `run_routine_now` take any agent's routine the person may manage, it writes wiki pages its person may edit (`wiki:write`, written as itself), and Abrir reaches the Vault, AI apps, approval settings, GIFs and voice.
5. This replaces §3 of the 2026-11-04 amendment for roles' permissions and a channel's settings, archiving and permissions. Still screens it opens: billing, deleting the workspace or an account, passwords, keys, mailboxes and databases (our own dialogs), pairing a computer and live control (the person at the device), uploads. Still never: messages in the person's name.

### Consequences

- Lodi's own prompt grew by about 50 characters. The tool's schema loads only with the setup group and only for it, so a DM "oi" with any other agent is unchanged.
- The phone draws the card and its inbox entry as the web does. Its Abrir for roles now opens the phone's own roles screen (Configurações › Papéis), which `APP_PAGES` had left out.
- The catalog's invitations and requests to join send email through the server's address and secret, passed to the setup tools and the card's route.
- Left for later, in the audit's order: a task's or a page's audience, approval covers, deleting tasks and board columns, the language and the rest of their own settings, pins and channel categories, invitation links, the task manager's paused runs, routines' stop, duplicate and take over, models and per-person limits, the Drive, the calendar, skills, agents' extras, proposals waiting on them, apps, AI keys and computers housekeeping, knowledge and memories by hand, dashboards' extras and missions. Also not in the catalog yet: undoing another agent's change from its receipt, correcting an agent's reply (a lesson), Responder agora, an agent's request to show a board to more people, a new agent's setup checklist, and one agent's Quem pensa and Autonomia for others. Posting as the right hand elsewhere waits on the owner's call.
- Desfazer of taking a role away gives the role back, not the seats in the channels the person left with it (they may join again through it), nor the notifications those channels cleared. Leaving a private channel through `channel_people` is undone only by someone who manages it.

## Amendment (2026-11-08): the onboarding has four steps before the DM (§6)

ADR 0162: the workspace's name, what it does, its team from a template and, where the workspace waits for its first
plan, the plan come before the workspace opens, on the blue rail with the right hand on its horizon. Paid or done, it
opens in #general, where the team says hi; the plan left for later opens the right hand's DM.

## Amendment (2026-11-10): its settings are its own page (§11)

The right hand has no entry in Settings. Its page (`/agents/{id}`, where `/settings/right_hand` now leads) holds its
settings in two groups. "Só para você", for every member: "Sua IA", when its weekly card comes, and what it creates and
adjusts for them without asking (ADR 0139 §2). "Para todo o workspace", only with `manage_agents`: its name and look,
"IA de quem não tem plano próprio" (the fallback of §11, before "IA do workspace"), the switch "Emprestar este plano a
quem não tem um" (before "Atende outras pessoas"), its monthly budget where something bills per use, and who may use
it. A value that changes is one row that opens its choice in a dialog (a sheet on the phone). Alone in a personal
workspace, lending and the audience are not shown.

## Amendment (2026-11-11): a teammate's skills on its settings card (§4)

Asked to give an agent a skill or take one away, the right hand had no card for it: skills were left for later in the
amendment of 2026-11-07. They are now lines of `propose_settings_change` (`add_skills`, `remove_skills`, by the name
Settings › Skills lists, the exact name before one that differs only in punctuation), one `skill` line per skill with
its id in `skillId`, its name in `label.to` and whether the agent has it on as `from` and `to`. They are decided as on
the agent's page, where only who manages agents changes skills (`admin`; `setAgentSkills` also takes the agent's
owner, the page doesn't). They apply at once with Undo when the person who asked may, else wait on the card, sent on
with "Pedir a um admin". A name no installed skill has is refused with the names there are, and a skill removed
before the click leaves the row out of date. The notice to the proposer and a refusal's lesson say each skill on or
off by its name. An applied card refreshes every open agent page's skills (`agents.changed`), since that page saves
its whole list. The right hand's own skills can't be changed (it has no skill tools), and its delegated decisions (ADR
0139) never take a skill line. Nothing reaches its grants, the Vault or any secret: a skill is instructions an agent
opens, under the agent's own tools.

## Amendment (2026-11-12): every agent asks for its own settings, always with a click (§4)

### Context

An agent that needed a skill installed in the workspace but not on for it told the person to open its page and turn
it on by hand, and said it couldn't ask on a card. `propose_settings_change` is any setup agent's tool (ADR 0139), but
it reads as teammates' settings and loads only with the setup tools, and installing a skill from an agent's card left
it off for that agent. The owner decided that agents edit their own settings when a person approves.

### Decision

- **`request_settings_change`.** Every agent but the right hand has it in every run a person is behind: no scope, like
  `request_permission`, so a run in a channel's thread holds it without the setup tools. Like `request_permission` it
  speaks for the agent (`ELSEWHERE` in the run policy), so a routine's run, or one fed by what a routine read, never
  asks for it. Its definition waits with the
  conversation's rarer tools (ADR 0043: up front, the whole card's schema would add about 3,800 characters to every
  run) and what the agent can do names it, so the agent calls it by that name (`use_tool`). It takes any line of the
  settings card (skills, channels and how it answers there, model, AI account, budget, owner, who talks to it, name,
  look, who it reports to, archiving) and has no `agent` field: its only target is the agent that calls it. It posts
  the same card, read as the agent's own (`chat.body.settings_request`, "Pede uma mudança nas próprias configurações"),
  whose rows are decided as before (`SETTING_GROUP`, "Pedir a um admin" for whoever can't). A skill on and off at once
  is refused, and a refusal lists at most 20 names. The right hand keeps `propose_settings_change`, its wider reach and
  its fixed list of its own settings.
- **Always a click.** An agent's own row never applies at once, even when the person who asked could make the change
  and wrote it themselves: the agent may be acting on text from an email, an issue or a web page, so it never widens
  its own settings without a person's click. Its card gets no look from the right hand either (ADR 0139 §2 already keeps
  an agent's own settings the person's). A receipt that changed skills, from this card or the right hand's, is undone
  or redone only by who manages agents (`requireMayUndo`): never the agent's owner, as on its page. "Desfazer tudo"
  checks every receipt of the card before undoing any, so it never undoes part of one and then refuses.
- **What it says.** The capabilities and the tool tell an agent that lacks a skill, a channel, a model or another
  setting of its own to offer the card, never to list manual steps or say it can't ask. `load_skill` on a skill
  installed here but off for the agent, and `offer_install_skill` on a link already installed, point to the card.
- **An install from an agent's card can turn the skill on for it, in the open.** The install dialog opened from
  `offer_install_skill`'s card shows a box, on by default, "Fica ligada para {{agent}}" (web and phone), and sends that
  agent (`forAgentId`) only when it is checked and only on an install from the card's own link: a link typed over it, a
  repository picked under "Escolher do GitHub conectado", or a link to the screen that merely names an agent turns
  nothing on (`cardInstallAgent`: the card that opened it is kept in this tab's session on the web, through connecting
  GitHub, and in memory on the phone). The box shows only for a live agent other than the right hand, the ones the
  server would turn it on for. The server marks each pick that takes a name already used (`replaces`), and the dialog
  says so: "Substitui a skill X já instalada" (it becomes a new version for every agent that has it) or "Substitui a
  skill X removida". A removed skill installed again from a link comes back on for none of its old agents (their
  assignments turn off, `source: "url"`): the link may hold anything under that name. A restore, or a save by hand or
  from a .zip, still brings its agents back. The server turns it on for the card's agent when the installer may change
  its skills, never for an agent archived or gone nor the right hand, and announces `agents.changed`. Otherwise the
  install still stands and the agent asks for it on its own card.

### Consequences

- What the card still can't carry: connector apps (`propose_instruction_change` for teammates, `request_permission`
  for itself), mailboxes, databases, computer access, Vault items, routines and instructions, each on its own screen
  or tool.
- One more line in what every agent can do (about 150 characters); the tool's definition loads when a run needs it.

## Amended 2026-11-12: it has a normal agent's tools (§4, §12, §13)

### Context

Its tools were a short list fixed in code (§4), so the one agent everybody talks to could not read the Vault, use a
connected app, a mailbox, a database or a skill, search the web, remember anything or post outside its DM. Asked for
any of these it refused or handed the work on, and a grant made for it on the server did nothing: `loadScopeKeys`
threw its rows away. The owner decided it has every tool an agent can have, by default, the Vault included.

### Decision

- **Every built-in scope an agent can be given, in code** (`RIGHT_HAND_GRANTS`): context, memory, the Drive (reading
  and writing), tasks, the calendar, skills, the wiki, routines, the Vault (seeing and editing) and the setup cards,
  with what was denied by name gone (`request_permission`, `share_artifact`, the memory tools, `web_search`,
  `web_fetch`, `post_message`, `send_dm`, `add_agent_to_channel`, long work's tools, `comment_issue`). A test fails
  when a new built-in scope is left out of the list.
- **Its grant rows count on top** (`loadScopeKeys` adds them to the list instead of replacing them): the apps every
  new connection gives every agent (`grantToEveryAgent`), a server connected by address, a mailbox, a database, a tool
  turned off (`deny:`). `request_permission` works for it as for any agent, and the refusal that said its tools were
  fixed is gone.
- **Its page shows and changes them.** `/agents/{id}` has two tabs for it: its settings (as before) and the agent
  page's own "Ferramentas e acesso" (apps, mailboxes, databases, built-in areas, approvals, skills), saved with the
  same bar. Its built-in scopes are held in code, so an area an admin turns off there is kept as denials of its tools
  (`setAgentAccess`), lifted when the area is turned on again; that covers the tools with no row of their own on
  the page (`UNLISTED_TOOLS`). Its setup cards are its job and have no area to turn off. The older save of scopes
  as a list (`setAgentScopes`) is refused for it, since it can't carry those denials. A save made from its grants as a list
  (`replaceableGrants`, an access proposal) carries the scopes it holds in code, so it turns none of them off. On the
  phone its profile lists what it may use, and a mailbox's owner gives or takes it there. Changing an app's level for
  it from the phone is not there yet.
- **Skills.** It loads the skills turned on for it. Its own skill is a line of its settings card like any agent's own
  (always a click), and an install from its card may turn the skill on for it. A skill's script needs a computer, so
  it reads a skill's instructions and runs none.

### What stays

- **No archive, no delete**, its instructions the product's, its owner the workspace's (§1). It is still in no channel
  and answers an @mention anywhere (§2): the router still never picks it. It posts with `post_message` where the
  person behind the run may post, a private channel included, as it already answers there by name.
- **Its workspace powers behind cards** (§4): the team, people, approvals and `workspace_action` are its alone, applied
  as whoever clicks.
- **No computer yet.** `sandbox:run`, `browser:use` and `desktop:use` are not on its list, a row for one gives it
  nothing, its access tree leaves them out, `request_permission` never offers them and refuses a card that asks, and a
  call of one answers that it has no computer and to hand the work to an agent that has one. `agents.machine_id` stays
  null (`machines.ts`). A separate change gives it a computer of its own.
- **The locked turn on a plan** (`RIGHT_HAND_TURN`, §4) is unchanged: the CLI gets our bridge and nothing else. Every
  tool above is ours, served by the Tool Gateway on the server (the web tools fetch from the server, with no browser
  to fall back on), so the lock stops none of them. Long work is the same run going on in the background. Its turn on
  a plan is no longer told of a computer's own tools, which it never had there: not by the turn-end judge's means
  either, and its "What you can do" names no browser, no `git_clone` (left off its list) and no way to type a Vault
  login or pass a key (`describeCapabilities` with `noComputer`).
- **One person's things stay that person's.** One row answers everyone, each acting as the person behind the run, so
  what is one person's is used only in that person's own DM with it (`rightHandReader`, null anywhere else). That DM
  has one person and no agent but the right hand. A routine's own run there counts as its creator: only a routine's
  creator sets what it does, and only they read that DM. A run a routine's report or work woke counts as nobody.
  - **The Vault** (`vaultPersonOfRun`): a personal item for its owner, a team item for its audience, only in that DM.
    Called in a channel, or by a routine that reports anywhere else, it reaches only team items open to everyone and
    shared with it.
  - **A mailbox** (`mailboxUserCheck`): only for the person who connected it, in that DM. Being in its audience opens
    no one else's mailbox, since its audience is everyone. Its routine watches a mailbox only when the routine's
    creator connected it (`watchesFor`, checked when the routine is saved and again as mail arrives, so a routine
    taken over by someone else gets none), and `create_routine` names only that person's mailboxes. The mailbox's
    row for it tells its owner that it uses the mailbox only for them (`mail.agent.onlyYou`).
  - **Tasks** (§13): `comment_issue` joins `list_issues`, `create_issue` and `update_issue`: in that DM, on a task
    the person sees.
  - **Memory**: `remember`, `update_memory`, `forget` and `save_how_to` work only in that DM, and what they save is
    that person's alone with fields that already existed (`scope_type = 'person'`, `scope_id` the person, and that
    DM as its only channel, a rule's too): read back in that DM for that person, never in another person's DM or in
    a channel, and changed or forgotten only by them there. A rule it keeps holds in the runs of the person who gave
    it and nobody else's, whoever decides its approvals (`rulesForPerson`, which filters by person before its cut of
    30). The DM as a rule's channel keeps it out of the lists of who reviews memory. One person's items never merge
    into another's, when saved (`findCandidates`) or in the nightly pass (`consolidateOrg`). `for: "team"` still
    asks to share with every agent, as the person's own choice, and is the one save it makes in a channel.
    Reflection and learning still skip its conversations (§2), so nothing is written for the team from what people
    tell it. Its page has a Memory tab on the web and the same lists on the phone, which show each viewer only
    their own.
  - **The Drive, the wiki and context** already read as the person behind the run (§12, §13), and writing follows
    the same rule.
- **Shared by nature, as for any agent open to everyone:** a connected app or a database is the workspace's, with one
  sign-in, so whoever may talk to it reaches what an admin gave it there. An admin narrows it on its access tab.

### Consequences

- This replaces §2's "its memory tools are denied", §4's "its tools are fixed in code" and "`add_agent_to_channel` is
  denied to it" (it is any agent's tool, with the rights of the person who asked and Undo), §12's "reading only" and
  "`request_permission` is denied", and §13's "no web or file writing, no `post_message` or `send_dm`, no long work".
- It also replaces, in the amendments of 2026-11-11 and 2026-11-12, "the right hand's own skills can't be changed"
  and the install box and `turnOnFor` leaving it out.
- Its prompt's "# Your tools" says what it has, that it has no computer yet, and that what is one person's stays in
  their own conversation with it. Its first paragraph no longer says it does no hands-on work: small things it does
  itself, work that is a teammate's job or needs a computer it hands on.
- It may now read a web page or an email and then act. Outside content marks the run as before (ADR 0117), so a
  change after it waits on a card, a send still asks a person, and its replies keep the scrub of §4.
- Its one budget on an API key (§13) now also carries the turns that read the web, write files and do long work for
  everyone who talks to it.
