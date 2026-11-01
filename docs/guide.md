# Throughline guide

Everything the [README](../README.md) leaves out: how each feature works, what it stores and where its limits are.

- [Workspaces, accounts and switching](#workspaces-accounts-and-switching)
- [Models, runs, Git and usage](#models-runs-git-and-usage)
- [Keyboard shortcuts](#keyboard-shortcuts)
- [Cross-agent review](#cross-agent-review)
- [Local models](#local-models)
- [Files and attachments](#files-and-attachments)
- [Import Claude Code and Codex chats](#import-claude-code-and-codex-chats)
- [Export a conversation](#export-a-conversation)
- [Ask a Friend](#ask-a-friend)
- [Private-link service](#private-link-service)
- [Saved data and migration](#saved-data-and-migration)
- [Running from source](#running-from-source)
- [Limitations](#limitations)
- [References](#references)

## Workspaces, accounts and switching

Open the composer’s agent/model button to browse cloud agents and downloaded Ollama models in one searchable panel. Selecting a model prepares the next prompt; only Send starts inference. Local selections stay with their workspace, preserve cloud preferences, and support text/code attachments. Images require a cloud connection and are never silently discarded. The legacy model/agent controls remain available as a fallback if the picker script cannot load.

Click **New workspace** or **Add workspace**, name the project, and select its folders. For example, a Shop workspace can contain its admin panel, backend and website together. Its single chat opens automatically; there is no New chat button or conversation list. Use **Workspace settings › Add folder** to attach more folders, and the remove control next to a folder to detach one. Files remain on disk, and folder changes preserve the same chat and drafts. The final folder cannot be removed.

The sidebar switches between workspaces and displays their attached folders. Codex and Claude receive every current folder when you explicitly run them. The Antigravity connection currently supports one folder; the advanced Gemini CLI connection supports a primary folder plus up to five additional folders. Adding/removing folders reconstructs provider sessions with the current access scope while retaining application history. Folder changes are blocked during active runs or file mutations. Missing folders stay listed with the saved chat available; remove or restore them before starting another run.

Existing projects migrate without changing IDs or deleting journals. The most recently updated legacy chat becomes the permanent chat; additional old chats remain saved as read-only archives. The previous registry is backed up as `projects.json.v1-backup`. Existing independent projects are not automatically combined; attach the relevant folders to the workspace you want to use.

Open **Settings** to inspect authentication, billing and usage; choose the model and effort in the composer. Installed and authenticated are different states. Background checks keep the last result on screen; Settings shows when each connection was last checked, says when a newer check timed out or failed, and **Refresh status** checks again. Connect uses the provider's own supported authentication flow. Claude runs the official unmodified installed Claude Code binary; login happens through Claude Code. For personal Google accounts, choose **Install Google connection** in Settings or onboarding, then **Connect account**. Throughline downloads the official [Antigravity ACP server](https://github.com/agentclientprotocol/registry/tree/main/antigravity-acp), verifies its pinned SHA-256 checksum, and starts Google's personal OAuth flow. The runtime manages its own authentication in an isolated application profile; Throughline never extracts credentials. Models and thinking levels come from that account's native session metadata. Google's account eligibility and usage limits apply; no unlimited free usage is promised. Google [moved consumer Gemini CLI access to Antigravity on June 18, 2026](https://developers.google.com/gemini-code-assist/docs/deprecations/code-assist-individuals). Gemini CLI 0.66.0+ remains an advanced API-key/enterprise option via `AI_RELAY_GEMINI_BIN`. Plain `agy -p` headless mode is not used. Existing native login methods remain available. Throughline does not extract tokens or copy another application's credential store.

Subscription, API and unknown billing are shown separately. Unknown or separately billed modes require explicit acceptance before an explicit provider run. There is no automatic API fallback. Usage stays unknown when the provider cannot report it. A model can be selected from current provider metadata or entered explicitly; selected models persist separately for each provider. Effective models are recorded when reported.

Use any connected assistant in the project’s existing chat. Wait or press **Stop** before switching. Consecutive messages to the same Claude or Codex agent resume its current native session and supply unseen shared context. Switching agents, including returning from a local run, starts a fresh session rebuilt from the shared journal rather than resuming that agent's older thread; Gemini runs reconstruct a fresh ACP session from Throughline's saved conversation history on each turn. **Continue with…** explicitly reconstructs a fresh session from saved application history after an interruption or an unusable native session. Switching the selector alone makes no model request. Only **Send** or **Continue** starts inference.

The application history is canonical. Native Claude, Codex and Gemini sessions remain separate. Hidden reasoning, native tool execution state and unfinished OS processes are not transferred. Full history stays saved. Within each run’s byte budget, saved summary, goal, decisions and tasks stay intact; the original user request and eight latest substantive user instructions take priority over assistant progress and tool logs. Oversized historical messages become explicit excerpts, and command output has a separate small allocation. The run details show fresh versus resumed sessions, included and omitted message counts, and compacted logs. If essential context cannot fit, sending fails before starting the agent; shorten the current request, attachments or saved context. Summaries are not automatically generated with AI. Errors distinguish quota, authentication, installation, permission, interruption and protocol failures.

Codex normally uses its official app-server with GUI approval requests. Claude uses the official Agent SDK with its installed binary and GUI `canUseTool` approvals. The advanced Gemini CLI connection uses ACP (`--acp`) with an isolated per-run policy that disables extensions, hooks, MCP, skills, telemetry and auto-memory, restricts read-only runs to read/search tools, routes edits and shell commands through one-time approvals, proxies text files within attached folders, and refuses managed system configurations it cannot safely combine. Antigravity uses its official ACP runtime in the confirmed `default` approval mode, routing one-time permissions to Throughline. Interactive questions and workspace-trust requests are never automatically answered. Native workspace hooks and trust remain under Antigravity’s control. Its connection does not claim a read-only sandbox: choose Codex or Claude for read-only work and background reviews. No unrestricted execution flag is enabled. Read-only uses the provider's sandbox/restricted tools; Claude and Gemini restrictions are not an operating-system sandbox. User/project hooks are disabled for managed runs where supported; administrator provider policy can still apply. These controls do not isolate unrelated host processes.

### Permission controls and tool approvals

Throughline provides two distinct permission choices in the composer toolbar:
- **Ask before changes** (the default): Actions that only read your workspace folders go ahead without asking: reading and searching files, listing folders, and read-only commands such as `ls`, `cat`, `rg`, `git status`, `git diff` and `git log`. Everything else appears in the app for approval before it runs: editing, creating or deleting files, installing packages, running project scripts or tests, network access, and any read outside the workspace folders. Commands Throughline cannot fully judge, such as ones that chain commands, redirect output, substitute values or use variables, always ask.
  When an approval names one exact action, **Approve** has a menu for allowing that same action again without asking: **Allow for this run** lasts until the run ends, and **Always allow in this workspace** is remembered for the workspace. A remembered command covers only that agent, those exact words and that folder (single commands only, never chained, piped or redirected); a remembered edit covers only that file. Anything else can only be allowed once. The activity log names the rule that allowed an action. Review and revoke remembered approvals in **Workspace settings › Remembered approvals**; they never carry over to other workspaces or imported conversations.
- **Full auto-approval**: Pending tool permission requests are approved automatically for that workspace. Approved actions remain visible in conversation activity and run progress. The selected access mode and native sandbox remain in place.

Permission policies are strictly scoped to the workspace:
- New workspaces always start with **Ask before changes** (`approvalPolicy: 'ask'`).
- Importing a conversation (via native transcript discovery or shared file import) never imports or alters permission settings.
- Reopening a saved workspace remembers its configured policy.
- Changing the permission policy in the composer affects subsequent runs; in-flight runs and existing pending approvals retain their original policy.
- Incompatible configurations are strictly rejected: a run cannot be marked read-only if writes are permitted, and combining **Read only** with **Full auto-approval** is blocked with an explicit error explaining that read-only access blocks edits while auto-approval requires edit mode.

Automatic executable discovery checks absolute PATH entries, common install folders (including Homebrew, Volta, nvm, pnpm, Bun, mise, asdf and fnm), macOS app bundles and compatible Codex VS Code extensions. Overrides are explicit and do not silently fall back:

```sh
AI_RELAY_CODEX_BIN=/absolute/path/to/codex AI_RELAY_CLAUDE_BIN=/absolute/path/to/claude AI_RELAY_GEMINI_BIN=/absolute/path/to/agy_acp_server.par npm start
```

## Local models

**Local** in the workspace header, **Continue locally** after an interrupted run, or **Agent › Continue Locally…** opens a handoff to a downloaded Ollama model. Use it when a cloud allowance runs out or when you prefer local inference. Select the model, review the task and current access mode, then press **Continue locally**. Opening the panel only reads model metadata; it never downloads a model or starts inference.

Setup:

1. Install [Codex CLI](https://github.com/openai/codex) for workspace tools and native approvals, and [Ollama](https://ollama.com/download) for model inference. This connection does not require a ChatGPT or Claude subscription or sign-in.
2. Download a coding model that supports tools using Ollama. Model capability, speed and memory needs vary; choose one that fits your hardware. Follow [Ollama's Codex setup](https://docs.ollama.com/integrations/codex), including a context window of at least 64K for longer coding tasks. Throughline does not start or reconfigure the Ollama server for you.
3. Start Ollama, open a workspace in Throughline, choose **Local**, and refresh the model list. Only verified downloaded GGUF models with tool support appear. Cloud models and aliases reporting a remote backend are excluded.

The default address is `http://127.0.0.1:11434`. For another local port, set `AI_RELAY_OLLAMA_URL` before starting Throughline. Only HTTP loopback addresses are accepted; redirects and credentials in the address are rejected. No remote model endpoint can be selected from this panel.

The handoff includes the current folders, saved project brief, task and recent conversation within a 96 KB prompt budget. The first version is text-only: historical images are explicitly omitted, while their original snapshots and the full conversation stay saved. The model should inspect current files before repeating unfinished actions. Hidden reasoning, native tool state and running processes are not transferred.

Local inference uses Ollama through Codex's tool harness, with the workspace's current read/edit mode and existing approval controls. A model's identity is checked again before starting; changed or removed models require refreshing the selection. A provider mismatch stops before any task is sent. Local runs never switch to a cloud model or consume a connected cloud plan allowance. They use your computer's resources and depend on the configured model and Ollama context window.

Cloud selections and native sessions stay saved. Each local handoff starts a fresh ephemeral tool session, and its messages, results, activity and local-model attribution remain in Throughline's permanent project conversation. **Stop** cancels the run. Continue with a cloud agent later through the normal composer; it receives the shared local work as context. The original composer draft is preserved when you start a local task. Conversation exports retain local-model attribution.

## Models, runs, Git and usage

**Layout.** The sidebar holds your workspaces, their files and **▶ Run**. The conversation is in the middle, with a side panel on the right for **Agents** (the **Routing** and **Handoff** settings) or **Git**: the icon tabs at its top switch between them. Two layout buttons at the top right of the window show or hide the sidebar (⌘B) and the side panel; each is filled while its area shows. With the sidebar hidden, the top bar names the open workspace; click the name to show the sidebar again. The side panel opens on the tab you last used, **Agents** on first launch. The top bar is a search bar (⌘K) for workspaces, files in every workspace (private paths such as `.git`, `node_modules` and `.env`, and build output, are never listed) and actions, including tools that open a window: **Review changes**, **Ask a friend**, **Previous chats** and **Export conversation**. They are also in the desktop **File** menu, and Review and Ask a friend appear under a finished run when there are changes. Drag the edge of the sidebar or the side panel, the line between workspaces and files, or the top of the Run panel to resize them; the handles also move with the arrow keys, double-clicking one resets it, and sizes are remembered.

The sidebar lists workspaces with search. A workspace with several folders shows them under its name; the selected folder is the one the **Files** view and **Git activity** show. Add, remove and rename are in **Workspace settings** (the ··· that appears when you hover a workspace). Each workspace still has one permanent conversation. File previews and code blocks in replies are syntax colored.

**Routing.** Choose a mode under **Routing** in the **Agents** panel and Throughline picks the agent, model and reasoning effort for each message, in one of three modes: **Cost saving** (lighter models and the agent with the most allowance left), **Balanced** (the model matched to the task) or **Maximum quality** (the strongest model and deeper reasoning). Before you send, a line above the message box shows exactly what Auto will use and why, such as "Claude · Opus · High effort — A complex task (refactoring)"; choose **Manual** to pick the model yourself again. While routing is on, the model button in the message box shows the mode, and clicking it opens **Routing**. Auto reads your message with simple rules, never a model call, so choosing costs no allowance: small edits and quick questions are light, focused changes are standard, and refactoring, migrations, debugging, security, performance and large multi-part requests are complex. It keeps the agent from your last run so the conversation keeps its session, moves to another connected agent when that one is near its limit (80% in Balanced, 90% in Maximum quality; Cost saving goes wherever the most allowance is left), and never picks an agent at 95%. It only picks agents billed to a subscription unless you turn on **Include API-billed agents**; unknown billing is not treated as free. Effort follows the levels each model supports. Under each prompt, a note says what Auto chose; hover it for the reason. Queued prompts keep the choice shown when they were queued.

Choose the agent, model, reasoning effort and access mode directly in the composer. Model and effort choices come from the installed provider's catalogue; custom model IDs remain available through **Enter a model ID…** (Gemini verifies a requested custom model ID against the ACP session before sending the prompt, while Antigravity exposes its native thinking-level choices and the advanced Gemini CLI connection leaves effort to its native model). Effort is remembered separately for each provider/model pair. The provider default remains an explicit choice. Reply headers show the model/effort recorded for that response when available; older replies are not given guessed model labels.

The run card shows elapsed time, the last provider activity, tool steps and provider-reported token counts when available. It distinguishes startup, provider-reported reasoning, tool execution, response streaming, approval requests and app reconnection. After 30 seconds without provider events it says **Waiting for provider**, rather than claiming the model is thinking or stuck. Stop remains available. No private reasoning text or invented percentage is shown.

**Project commands** (**▶ Run** beside **Files** in the sidebar) opens a collapsible panel at the bottom of the conversation to configure, run and monitor persistent shell commands for the current workspace, with separate **Run** and **Test** actions. Choose any attached workspace folder or package subdirectory, or inspect non-executing script suggestions from `package.json`. Commands run under your own local shell permissions, independently of agent read-only modes, and can stay running in the background while assistants edit the project. The panel streams the latest bounded log output, highlights local loopback HTTP links, shows an active process count badge on the **Run** button, and lets you stop or restart commands cleanly.

**Git activity** opens the repository inspector. For each attached folder it shows the current branch, staged/unstaged/untracked changes and the latest 15 local commits. GitHub origin repositories also get repository/commit links. This is local history, not a remote fetch or a commit/push action. The panel refreshes while visible; configured hooks, fsmonitor and external clean/process filters are disabled for its Git reads. Select a changed file to review its diff against the last commit (staged and unstaged together; new files in full). External diff drivers and textconv are disabled for diffs too. On wide windows the panel stays open unless you close it, and it refreshes when a run finishes.

The status bar shows the plan usage left for Claude Code and Codex (5-hour and weekly windows, plus model-specific weekly limits when the provider reports them); the composer shows the tightest limit for the selected agent and model. Select a meter or the composer chip to see that agent's windows and reset times. Codex usage comes from its app-server. Claude usage comes from an experimental Claude Agent SDK call and is shown as unavailable if a future SDK removes it. The pinned Antigravity connection reads its built-in `/usage` account report without an LLM turn. Bucket names, remaining allowance and reset times come from Google; unavailable quota, absolute counts and disabled limits are never converted into estimated percentages. Per-run context tokens are separate from account allowance. The advanced Gemini CLI connection does not report account quota through this integration. Reading usage never starts inference.

**Continue when a limit resets.** When a run stops on a usage limit, choose **Continue when a limit resets** to let the task wait instead of you. Throughline reads each connected agent's plan usage, shows when each limit resets, and continues the unfinished task on whichever agent has room first, from the shared conversation, as it does when you switch by hand. An agent that reports no reset time is checked again every ten minutes; reading usage does not use your allowance. The continued run uses the access and permission setting shown on the wait and is never given more: with **Ask before changes** it pauses at the first change that needs approval, and if full auto-approval is on you choose whether it applies while you are away.

**Queue prompts.** While an agent is working or the task is waiting for a reset, **Queue** (or Enter) adds your message to **Up next** instead of sending it. Queued prompts run one after another, each with the agent, model, effort, access and permission setting shown on it when it was queued, never more. Reorder, edit or remove them until they start. If a queued run reaches a usage limit, the task waits for a reset and the queue carries on afterwards. Any other stop pauses the queue, as does restarting Throughline, and **Resume queue** continues it. A workspace can queue up to 20 prompts.

**Add to the run.** To add a point or correct something while the agent is working, type it and choose **Add to run** (⌘↵, or Ctrl+Enter on Windows and Linux) instead of **Queue**. The agent takes your note into the task it is already doing, without stopping the run or starting over: Codex and Claude read it at their next step, and Gemini continues the same session with it. The note appears inside that run, marked **Added while working**. If the run finishes before your note reaches the agent, it goes first in the queue and runs next with the same settings. Attachments go with queued messages only.

**The agent's plan.** When an agent breaks the task into steps, the plan appears as one line above the message box, showing how many steps are done and what the agent is doing now; open it for the full to-do list. The list is the agent's own plan, from Codex's plan and Claude's to-do list, and from Gemini when its connection reports one (Antigravity keeps its plan to itself for now). It updates as the agent works. Agents plan longer tasks on their own; short tasks may not have a plan.

**Handoff.** While a cloud agent works, Throughline checks its plan usage every few minutes. Once it passes 90% of a limit, an offer appears under the run: it names the agent it would hand off to, that agent's model and billing, the access and permission setting it would use (the same as the current run, never more) and the task it would continue. **Hand off** stops the run and the other agent continues the task from the shared conversation; **Not now** keeps the run going and is not asked again during that run. Only connected agents below the threshold are offered, subscription-billed ones first. An agent billed to an API account, or whose billing cannot be confirmed, needs its charges accepted separately before **Hand off** is available. An offer is checked again just before switching: if the task, the workspace folders, the saved project context or the other agent's model, access or billing changed, nothing is started on the other agent and an updated offer replaces it. Choose when offers appear, or turn them off, under **Handoff** in the **Agents** panel (or **Agent › Hand Off Near Usage Limits** in the desktop menu). **Hand off automatically** switches without asking, only to subscription-billed agents, and says so in the conversation and a notification. Queued prompts carry on after a handoff.

**When you are in another app,** the desktop app tells you when a run finishes or stops, when a task continues after a reset, and when an agent needs your approval. The Dock icon shows how many things happened since you last looked, and bounces until you open Throughline when an approval is waiting. System notifications are shown too where macOS allows them; macOS does not allow them for builds without a Developer ID signature, so until signed builds ship (#1) the Dock is how you are told. Clicking a notification opens its workspace, and an approval notification opens that exact request without answering it. Notifications name the workspace and agent but never show commands, chat text or file paths. Turn them off, or turn on a sound, in the **Agent** menu (**Notify When Runs Finish or Need Approval** and **Play Notification Sound**); the Dock badge stays either way. In the sidebar, a workspace with requests waiting shows how many, even while another workspace is open. A wait survives restarting the app, ends after a day, and is replaced by any message you send yourself. If the continued run reaches another limit, it waits again, up to three times. **Cancel** stops waiting.

**Keep awake** in the status bar (desktop app) stops your Mac and its display from sleeping while any workspace has an agent running or is waiting for a limit to reset, so a long run is not interrupted. It shows **Auto** while switched on and waiting, **On** while it is holding the Mac awake, and releases as soon as the last run finishes. The setting is remembered between launches.

The appearance buttons in the status bar choose **System**, **Dark** or **Light**, and **Settings › Appearance** and setup offer the same choice. **System**, the default, follows your computer's light or dark setting as it changes; **Dark** and **Light** stay as chosen. In the desktop app, native menus and dialogs use the same appearance.

Messages and code blocks have copy buttons.

## Keyboard shortcuts

Shortcuts use ⌘ on macOS and Ctrl elsewhere:

- ⌘K opens the search bar at the top, which finds workspaces, files in every workspace and actions; start with > to see actions only. It never filters the sidebar. The arrow keys move through the results, Enter runs the highlighted one (the first match at first), and Escape clears the search. A file in another workspace opens that workspace and previews the file.
- ⌘1–9 open the first nine workspaces the filter shows.
- ⌘L focuses the message box.
- ⌘F finds text in the conversation. Enter and Shift+Enter move between matches, and Escape closes the search.
- ⇧⌘G shows or hides Git activity.
- ⌘B hides or shows the sidebar.
- ⌘↵ adds your message to the run that is working, instead of queueing it.
- ⌘. stops the current run.

The desktop app's menu bar lists these shortcuts too, and adds ⌘, for **Settings…**, ⌘N for **New Workspace** and ⌘G for **Find Next**. Each menu item does what its shortcut or button does. Items are dimmed when they don't apply, such as **Stop Run** when nothing is running, and while a dialog is open, items for the controls behind it do nothing. **Agent** ticks the selected agent and **Keep Awake**, **Workspace** ticks the open workspace, and **View** ticks **Show Files**, **Show Git Activity** and the appearance. **Help** opens this guide, the roadmap, the release notes and the bug and design feedback forms on GitHub. The bug form starts with your Throughline and macOS versions filled in.

## Cross-agent review

After a completed task, **Review changes…** (shown under the run when there are changes, and always in the search bar and the **File** menu) suggests the eligible changed files and prepares their exact diff preview. The goal is filled from the current task. Adjust the selected files if needed, inspect the preview and choose **Start read-only review**. Unknown or API billing needs explicit confirmation before the review can consume usage. The toolbar's **Review** action also supports choosing files manually.

The reviewer runs in a separate worker against copies of the approved files and their diffs. Its results appear in a side panel while you send your next prompt in the main conversation. Only selected files are copied; unrelated project files and native agent sessions are not transferred into this snapshot. The review cannot edit the live workspace, and stopping it does not stop the main agent. Close the panel and reopen it from **View review** at any time.

Later edits to selected files, Git state or attached folders make the report outdated. Select findings to prepare a fix draft only after the review completes and freshness checks pass. Existing text or attachments are preserved; a fix draft never starts an agent automatically. Failed, interrupted and unstructured reviews show that status instead of claiming there were no issues. App shutdown stops background workers, and interrupted reviews can be restarted. Finish or stop a background review before changing folder membership or removing the workspace.

## Files and attachments

The sidebar’s **Files** section shows each workspace folder as a separate root. Expand directories, preview text/code with line numbers or images, then choose **Attach to message**. Previews are read only. The explorer hides private app data, credentials, provider sessions, dependency folders and symbolic links. Large directories load in pages.

Click **Attach** in the composer, drag files onto it, or paste an image from your clipboard. Click an attachment chip to preview it, or its × to remove it before sending. Supported inputs:

- PNG, JPEG, GIF and WebP images, up to 5 MiB each.
- UTF-8 text and code (including Markdown, JSON, CSV and source files), up to 64 KiB each.
- Up to six files and 20 MiB per message, with a combined text limit of 128 KiB. The prompt context budget still applies.

PDF, Office, audio, video and other binary attachments are not supported. SVG is treated as text, never rendered as active content. Images require the native Codex app-server, Claude SDK or an ACP-capable Gemini CLI reporting image prompt support; the optional plain CLI adapter rejects image input explicitly.

Files are saved as immutable snapshots in the workspace’s local application storage. Selecting or previewing a file starts no inference; **Send** transmits it to the selected agent. Draft attachments stay with their workspace and survive reloads and failed sends. Journals store attachment metadata, not image base64. Recent unseen text/image attachments are included on model handoff within context/image limits; the agent is told when older images are omitted.

The first launch opens a short setup: a welcome, then three steps (connect your agents, choose the theme and default access, and choose your project folders) and a summary before the app appears. **Finish** leads to the summary, and **Open Throughline** completes setup. Previous conversations are offered inside the workspace after setup. **Skip for now** leaves a **Getting started** shortcut in the sidebar, and **Settings › Setup guide** reopens the steps at any time. Setup never changes existing chats.

Updates and reinstalls open your saved workspaces directly. After an update, a dismissible **What’s New** panel shows release notes bundled with the installed app, including recent releases you skipped. Once dismissed, it does not reopen automatically for that version. **Help › What’s New** reopens it at any time, including offline. The first update from a version without version tracking shows the installed version's notes without guessing the previous version. Downgrades and reinstalling the same version do not announce another update.

When a newly installed copy of the desktop app finds saved workspaces, it asks whether to **continue where you left off** or **start fresh**. Starting fresh renames the saved data to `relay-data-backup-<date>` in the same folder instead of deleting it; rename it back while the app is closed to restore it.

## Import Claude Code and Codex chats

Create or open a workspace first. Throughline checks its project folders for previous Claude Code and Codex conversations and offers **Review conversations** when it finds chats that have not been merged. The suggestion never opens a dialog or merges messages by itself. **Not now** is remembered for that workspace across restarts; after a successful merge, the automatic suggestion is also dismissed.

Choose **Previous chats** from the search bar (⌘K) or the **File** menu. The list defaults to **This workspace**, matches folder paths, and groups chats by project folder. Select one or several conversations from either agent, review their messages together, and confirm **Merge conversations**. Nothing is selected automatically. Messages merge into the open workspace’s single conversation by their original times, with their source and timestamps preserved.

**Browse other projects** is a secondary option for explicitly choosing unrelated chats. Their existing folders are attached to the open workspace if needed, with those additions shown before merging. Folders that no longer exist are reported and not attached. **Open conversation file…** brings a shared conversation into the workspace you have already opened. The destination workspace is always shown in the review.

Importing copies visible user and assistant text, original timestamps and available model provenance. Claude Code slash-command records, native tool state and hidden reasoning are not imported. Import never resumes a native session, starts inference or modifies the provider's original conversation. When you next press **Send**, the selected agent starts with the imported history as shared context (most recent messages first, within the context budget) and runs on your own installed CLI and account. Throughline supplies no API keys of its own.

Discovery and preview use the installed Claude Agent SDK session readers and the Codex app-server history APIs; both read local history. Throughline's own runs are excluded from the list. Each import confirms that the reviewed content has not changed; a changed source must be previewed again. Repeated imports are deduplicated, and a reviewed import of a grown conversation updates its partial messages. Each conversation is limited to its most recent 1,000 text messages and 2 MiB, with clipping disclosed, and up to 20 conversations can be imported at once.

## Export a conversation

**Export conversation**, from the search bar (⌘K) or the **File** menu, saves the conversation as a `.throughline.json` file that another Throughline user can open with **Previous chats › Open conversation file…** after opening their own project workspace. They review the messages and continue with their own Claude, Codex or Gemini account. Nothing runs during export or import.

By default an export contains the user and assistant text of the whole conversation plus the saved goal, decisions and tasks. Secrets and local paths are removed, and workspace paths become folder names such as `[frontend]/src/app.js`. You can limit it to recent messages, include tool activity, or turn removal off; the dialog shows what the file contains before you save it. **Save as Markdown** writes a readable copy instead. A file holds up to 2 MB of conversation (the oldest messages are left out first). A file that was edited after export is rejected on import. On import, shared context fills only fields the receiving conversation has not set, and the other person's messages are shown as theirs. Import files only from people you trust, because their messages become context for your assistant. To ask someone for code changes and receive a reviewable patch instead, use **Ask a Friend**.

## Ask a Friend

The default view prepares a local preview from the current task and up to eight recent conversation messages. No form is required: edit the filled-in request if you wish, optionally include the suggested changed source files, then inspect the exact preview. **Export request file** approves and exports that preview. **Create private link** approves and publishes that preview only when a sharing service is configured. Opening the view never approves or publishes anything. Changes to the request require a refreshed preview. Source files are opt-in, and secret scanning can miss private information.

**Advanced request editor** retains exact message selection, source paths, decisions, tasks and editable package JSON. The complete workflow is:

1. In the original conversation click **Ask a Friend**. Enter the problem and expected outcome; select individual messages or tool logs.
2. Choose **Context only** or **Selected source**. Enter only approved workspace-relative text-file paths. Add specific permitted new-file paths if a returned patch may create files. The repository is never selected automatically.
3. In multi-folder workspaces use the displayed folder prefix, such as `frontend/src/app.js`, to distinguish files. Prepare the offline preview. Inspect and edit the actual outgoing JSON, inventory and warnings. Refresh an edited preview to recalculate its integrity. Confirm and approve that exact content.
4. Export the approved JSON offline, or configure a separate sharing service under **Solutions & links** and create a private link.
5. Your friend can view/download the approved material and submit a solution in a normal browser. They use their own tools and account; the website cannot access their local subscriptions. Throughline is optional for them.
6. If they use Throughline, **Help a friend** imports into a deliberately selected local workspace and its existing chat; map each shared folder to an attached local folder. Importing writes no source files and starts no assistant. They can prepare files locally, then build/export an exact solution against the approved baseline. Upload that solution through the friend webpage, or return the JSON offline.
7. Retrieve or import solutions under **Solutions & links**. Explanations and contributor verification appear in the original conversation. Review each diff before choosing **Apply reviewed patch**. Instructions-only solutions have no automatically applicable code.
8. Run an explicitly reviewed local syntax/whitespace check. Recovery restores affected baseline files when safe and preserves unrelated or newer edits.

A private link grants its holders view and submission access until expiry or revocation. The owner capability remains in local private storage. Default expiry is seven days; the service supports bounded expiry and revocation. Creation/delivery needs connectivity; preparation, approval, export/import, diff, application, recovery and supported verification do not need AI or internet. Lost upload responses retry with the same persisted upload identity. One rejected patch does not prevent receiving other valid solutions.

Source baselines retain exact approved content and SHA-256 hashes, including dirty and selected untracked files. Git commit identity alone is insufficient. Patches support explicit UTF-8 text-file create/replace/delete operations for approved paths, up to 128 files and 256 KiB per file, within the 2 MiB portable-package limit. Unsafe paths, private runtime paths, symlinks, binary content and unapproved baselines are rejected. Changed target files become conflicts and are not overwritten. The app never resets, stashes or commits a user's project. Request and solution IDs make delivery/application idempotent. Previews bind to a private workspace snapshot; changing workspace folders requires preparing a new preview. Approved requests and recovery checkpoints keep their original folder mapping and refuse writes to detached roots. Durable recovery checkpoints precede file writes.

Verification is intentionally limited to reviewed `node --check relative-file.js` and `git diff --check`. Imported commands and arbitrary package scripts never run automatically. Git external diffs, text converters, hooks and configured clean/process filters are disabled for this whitespace check. Broader tests can be run deliberately in your own terminal.

Default exclusions cover environment/credential files, provider session stores, runtime data and unnecessary absolute paths. Transcript redaction and secret scans assist review; they cannot guarantee that sensitive content has been removed. Review source and conversation text yourself before approving.

## Private-link service

For a same-computer test:

```sh
npm run sharing
```

Set the GUI service URL to `http://127.0.0.1:4319`. These are local test links; another computer cannot open them. Remote links require a separately deployed HTTPS service with persistent private storage. Each release publishes a container image, `ghcr.io/ahmednavaz/throughline-sharing`. Deployment, Docker, limits, capabilities and proxy configuration are in [sharing/README.md](../sharing/README.md). `AI_RELAY_SHARING_URL` can configure the client, and `AI_RELAY_SHARING_CREATE_KEY` can provide the service's optional creation key.

The sharing service stores only approved packages and solutions. It has no execution endpoints, provider credentials, repository mounts or account integration. Do not expose or tunnel the local coding server. Production hosting has **not** been deployed or verified by this implementation.

## Saved data and migration

Desktop data lives under Electron's OS application-data directory in `Throughline/relay-data` (on macOS, `~/Library/Application Support/Throughline/relay-data`). Projects, append-only journals, local collaboration associations, owner capabilities and recovery files stay there. Treat this directory as private. Source folders do not need Throughline files.

The first development launch copies the old checkout's `.data` into OS storage if no desktop data exists. The original remains untouched, and `migration.json` records the source. Migration refuses live legacy locks, invalid locks or unfinished guards. Stop all old Throughline instances first. To import from a different checkout on first launch:

```sh
AI_RELAY_LEGACY_DATA_DIR=/absolute/old/AI-Relay/.data npm start
```

For an existing installation, perform that one-time development launch before moving to the packaged build. Packaged apps deliberately exclude `.data`; they use the same OS storage. Migration never merges over an existing destination. For rollback, quit all instances and retain both copies; reopen the original checkout with its original `.data`. Restoring old data does not undo later file edits. Workspace mutation locks also exclude overlapping folders across different history roots on the same user account. A surviving provider process after a crash blocks conflicting edits until it has stopped; guards with a known dead owner recover automatically. Empty guards left by older versions and unrecognized guard content still fail closed with recovery instructions; stop all instances before inspecting those guards.

For a browser-only development session use `npm run web`, optionally with `-- --workspace /absolute/project --port 4318`. This uses checkout `.data` by default. Set `AI_RELAY_DATA_DIR` explicitly if you want it to use another history store. The execution server binds to loopback, checks Host/Origin and mutation headers; desktop additionally uses a per-launch token and isolated renderer with narrow folder/external-link IPC.

## Running from source

Build a standalone app for your OS and architecture with `npm run package`; the result is written to `dist/`. Regenerate the app icons from `assets/icon.svg` and `public/icon.svg` with `npm run icons`.

Electron starts and stops the loopback backend itself. No separate server terminal is required. Close the app to stop its managed provider processes. A second desktop launch focuses the existing window. Run from source (`npm start`), the app is **Throughline Dev**: a separate app with its own data folder (`~/Library/Application Support/Throughline Dev`) and its own window, labelled **Dev**, so it runs alongside an installed release without sharing workspaces, conversations or settings. Without a signing identity, `npm run package` signs macOS builds ad hoc; they are not notarized.

The development launcher clears an inherited `ELECTRON_RUN_AS_NODE` flag before opening Electron, so `npm start` also works from terminals hosted by an Electron-based editor or coding agent. Provider workers run in Node mode themselves but clear the flag before starting an agent, so an Electron app an agent starts, such as Throughline from source, opens normally.

To replay onboarding from the welcome screen, run `npm run start:fresh` or `npm start -- --fresh`. Each launch uses an empty temporary profile and skips legacy-data migration. Setup changes and imported chats in that session are discarded when the window closes; existing saved workspaces stay intact. Installed agent sign-ins are still detected. To preview a new user with no agents installed, run `npm run start:fresh -- --no-agents`; this hides the agents only for that temporary session and leaves their installations and sign-ins unchanged.

If package installation disabled lifecycle scripts, run `node node_modules/electron/install.js` once to install Electron's official runtime. Build a fresh app for the current OS/architecture with `npm run package`; output goes to `dist/`. `AI_RELAY_SIGN_IDENTITY` can supply an installed macOS signing identity. Notarization requires separate Apple credentials/configuration.

## Limitations

- macOS builds are signed ad hoc and not notarized, so macOS asks you to approve a browser download once. Windows and Linux builds are not provided yet.
- The private-link sharing service is not hosted for you. Run the container image yourself with HTTPS and persistent storage (see `sharing/README.md`) before sharing remote links.
- Returned patches support UTF-8 text files only; binary files and symlinks are rejected, and stale baselines need a new solution.
- Built-in verification covers reviewed JavaScript syntax and `git diff --check`, not arbitrary test scripts.
- Secret scanning and redaction help you review what you share; they cannot guarantee that every secret is removed.
- Claude's and Gemini's restricted tools are not an operating-system sandbox. Hidden reasoning and native process state do not move between providers.
- Claude plan usage comes from an experimental Claude Agent SDK call and may stop being reported after an SDK update. Antigravity quota requires native Google sign-in for this connection. The advanced Gemini CLI connection does not expose account quota here.

## References

Official integration documentation: [Codex app-server](https://learn.chatgpt.com/docs/app-server), [OpenAI sign-in token-sharing guidance](https://developers.openai.com/siwc/token-sharing-open-source), [Claude legal and compliance](https://code.claude.com/docs/en/legal-and-compliance), [Claude headless](https://code.claude.com/docs/en/headless), [Google Antigravity](https://antigravity.google/), [Gemini CLI](https://geminicli.com/docs/get-started/), [Agent Client Protocol](https://agentclientprotocol.com/), [Electron distribution](https://www.electronjs.org/docs/latest/tutorial/application-distribution).
