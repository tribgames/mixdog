# Changelog

Notable changes, newest first. The Deploy pipeline refuses to release while
the Unreleased section is empty, and stamps it with the released version.

## Unreleased

Added Worktrees settings and branch cleanup, replaced Goal tasks with session todo lists, and introduced customizable composer styles.

### New features

- **Worktrees settings** — Added Settings → Worktrees with disk usage, open and delete actions, and automatic cleanup after 15 worktrees or 30 unused days.
- **Worktree branch actions** — Added New branch, New worktree, and Clean up actions to the branch menu footer, with search highlights and safe cleanup previews.
- **Session todo list** — Added a session todo list replacing goal tasks, showing live agent progress, and preserving the last todo and Goal when an agent closes.
- **Composer styles** — Added Simple, Normal, and Detailed composer styles in Settings with live preview, responsive toolbar layouts, and optional question-answer confirmation (#270, #276).
- **Delegation settings** — Added a dedicated Settings → Delegation page for orchestration instructions, and inline prompt editing in Output style with reset to defaults (#291).
- **Sub-agent routine executors** — Added picking an executor sub-agent with its own model for scheduled tasks and webhooks.
- **Claude Desktop Cowork import** — Added importing conversations from Claude Desktop Cowork, listing starred conversations first (#283).
- **Chat path links** — Added opening path links anywhere on your PC from chat: folders open as File panel roots and previewable files open in Visualize (#277).
- **Phone image gestures** — Added pinch, pan, and double-tap zoom for images in chat and Visualize on phones (#275).
- **Fast call usage** — Added a dedicated usage breakdown row for a model's Fast calls, with responsive tables formatted for phone screens (#288).
- **Session lifecycle automation** — Added automatic archival of inactive sessions after 7 days and deletion after 90 days during idle periods.
- **Active PC notification pause** — Added pausing phone push notifications while you are actively using this PC.

### Changes

- Changed tool activity rows to group repetitive operations into counted labels with task names, such as "Worktree management ×4".
- Changed settings and prompt edits made anywhere to apply on the next turn without restarting sessions or breaking prompt caches.
- Changed web search to load immediately without a deferred tool call hop, speeding up lookups.
- Changed remote browser streaming on phones to swipe shut only from the left edge strip, preventing accidental closes during web page interactions.
- Changed the composer bar's agent token usage readout to update within about a second of each model call.
- Adjusted idle garbage collection to sweep external buffer memory, reducing daemon memory footprint.

### Bug fixes

- Fixed uncommitted turns being lost after crashes or restarts by adding durable turn handoff and checkpoint recovery.
- Fixed desktop renderer crashing on mouse-up after drag-selecting text.
- Fixed session switching rebuilding transcripts or replaying animations by keeping recent conversations mounted.
- Fixed stalled Goals counting idle time against budget, repeating notifications, and replacing existing Goals without confirmation.
- Fixed connector sign-ins expiring after an hour by requesting refresh tokens, and prevented account switching when reusing removed account names (#285).
- Fixed plugin updates on Windows failing with `EPERM` file-lock errors during folder renames (#284).
- Fixed installation failures caused by onnxruntime-node scripts being removed during embedding prune (#282).
- Fixed memory service startup hanging on orphaned PostgreSQL locks after unexpected process exits (#278).
- Fixed reCAPTCHA and authentication widgets failing in the in-app browser by granting Chrome-compatible storage access.
- Fixed sub-agent reports failing to reach the Lead agent when interrupted by reminders, queued input, or later failures.
- Fixed Computer Use restarting the input host on slow screen reads and reporting observers broken during brief input gaps.
- Fixed recall searches dropping Korean content words in mixed queries, and optimized exact-term scanning.
- Fixed web links and streamed browser tabs on paired phones failing to fit mobile screens or open in Visualize.
- Fixed Settings color rows overlapping descriptions on narrow windows, and prevented instruction edits from overwriting concurrent changes (#287).

## v1.4.2 - 2026-10-29

Improved the agent harness with Explore, a dedicated exploration agent, and stronger verification with the Test Suite skill, plus Vertex AI and several accounts per connector.

### New features

- **Explore** — Added an optional read-only exploration agent the Lead can hand several code questions at once; pick its model under Workflows → Built-in agents.
- **Test Suite skill** — Added a built-in skill for writing, running, diagnosing and pruning a project's tests.
- **Vertex AI** — Added Vertex AI with Gemini, Claude and open models, signing in with a service-account key, your gcloud login or an express-mode API key (#249).
- **Accounts inside a connector** — Added several accounts to one connector; agents use the last-used account unless you name another.
- **Custom provider keys and headers** — Added extra API keys that take over when one runs out of quota, and your own HTTP headers on every request (#233, #239).
- **Connector tool permissions for bots** — Added per-tool Auto, Needs approval and Disabled choices for each connector on a bot's profile (#264).
- **Approve from the on-screen bot** — Added the request and its Allow and Deny buttons to the speech bubble of the on-screen bot.
- **Stop every background command** — Added `/stop` to stop all background commands of a session, plus `/shells` and `/mcp login` on desktop.

### Changes

- Changed agents to fix the cause of a failing check instead of rerunning it, raising its timeout or skipping it.
- Changed bot check-ins and prompt-cache warming to be off by default.
- Changed the desktop and CLI to follow the system proxy, with PAC scripts and exceptions applied per address on desktop, keeping local and LAN hosts direct.
- Changed tool activity rows to show elapsed time only while a command is still running.
- Changed agents stopped as stalled to leave a `stall_abort` row in `history/tool-failures.jsonl`, so a wrongly stopped agent can be reported.
- Changed Git on Windows to start `git.exe` directly and record turn changes with fewer processes, making turns, Undo/Reapply and git tool calls faster.

### Bug fixes

- Fixed stopping commands on Windows: child processes kept running after Stop, Release anyway, a timeout or closing a session, a background command could hang when stopped, and an unrelated older process could be taken for a leftover (#259). Each command now runs in its own Windows job; `MIXDOG_SHELL_ALLOW_BREAKAWAY=1` lets a command start processes outside it.
- Fixed a group room repeating "could not reply" for every bot when the usage limit ran out; it now stops once and says why.
- Fixed session views: long or compacted sessions not scrolling back to their first message, "Session unavailable" while other sessions sent large updates, and the phone's Sessions drawer opening the Bots page instead of the chat.
- Fixed Codex conversations kept only as compressed files failing to import (#262).
- Fixed connector sign-in repeating an "Unrecognized client_id" error after the service forgot Mixdog's registration (#269).
- Fixed the TUI cutting off long sign-in URLs, and added `Ctrl+Y` to copy them (#261).
- Fixed voice input failing to start, and settings or session saves failing, on busy Windows PCs.
- Fixed Chinese and Japanese table cells pushing the table past its frame.
- Fixed Vertex AI models missing the Service tier choice (Standard, Flex, Priority), and queued Flex requests being cut off after a minute (#271).
- Fixed an agent being stopped as stalled after a single failed progress read stopped its activity timer from updating.
- Fixed Computer Use `verify` giving up after 2 seconds regardless of `timeout_ms`, and waiting needlessly when an elevated window's text cannot be read (#274).

## v1.4.1 - 2026-10-27

Fixed sign-in over SSH, PC access setup failures and agents stopping on Anthropic models, and added a view switch for side-by-side Visualize tabs.

### New features

- **Sign-in without a browser** — Added device-code sign-in for ChatGPT and Grok, with the sign-in URL or code shown in the TUI panel over SSH or without a display (#242).
- **Visualize view switch** — Added a view switch to the zoom pill of a side-by-side Visualize tab, to show both panes or one at a time.
- **APK install from chat** — Added opening a downloaded APK in the Android package installer instead of the share sheet (#241).

### Changes

- Changed bots to reach another bot by its bot id when sending to, reading or checking it.
- Changed the sidebar, unread dots and agent spawns to respond faster with long session lists.

### Bug fixes

- Fixed PC access setup failing on PCs whose drive root carries an inherit-only permission, and showing why an approval did not finish (#251).
- Fixed agents on Anthropic models being stopped as stale while thinking or writing a large file (#248).
- Fixed agents on custom Responses routes going stale before their first output (#244).
- Fixed Computer Use, Browser Use and sign-in callbacks failing with a "bad port" error on some PCs.
- Fixed choosing a main model on a fallback's provider failing with "duplicate route provider".
- Fixed an automatic switch to a fallback model sending every MCP tool at once.
- Fixed imported Claude and Codex conversations losing early history, titles or pages, and showed their tool use as collapsed activity rows (#245).
- Fixed orphaned worktrees staying behind and the default branch being taken into a managed worktree (#247).
- Fixed a bot showing as working after its delegated work ended, and a compacted session missing its done dot.
- Fixed the prompt cache being rebuilt after an interrupted request or a restart.
- Fixed a table or code block that ends a reply losing its bottom border, and narrow phone tables losing their cell gap.

## v1.4.0 - 2026-10-27

Improved remote work from your phone together with Browser Use and Computer Use, and streamlined the agent harness to skip redundant checks and finish work faster.

### New features

- **Remote PC screen** — Added viewing and controlling your PC screen from your phone over a direct WebRTC connection with special keys and an on-PC status pill.
- **PC access** — Added optional access to administrator prompts, the lock screen and `Ctrl`+`Alt`+`Del` from your phone, approved once in Computer Use setup or with your Windows password.
- **Browser live view** — Added streaming the in-app browser to your phone over WebRTC, fitting takeover pages to your screen with direct typing from your mobile keyboard.
- **Notification controls** — Added per-device notification settings, conversation mutes, quiet hours and error notifications under Settings → Notifications, with Allow on approval notifications (#221, thanks @dislight1123).
- **Bot-delegated work** — Added one live line per job under the reply for work a bot delegates, showing progress and letting you answer questions in chat.
- **Saved sign-ins** — Added automatic sign-in with saved logins and one-time codes, managed under Settings → Authentication, without the model ever seeing the secrets.
- **Chrome login import** — Added importing Chrome saved logins, including newer app-bound encrypted ones, into the rebuilt Logins page with a saved/stay-signed-in switch.
- **Sign-in from your mail** — Added opening sign-in links and filling codes from your verified mail, and remembering which identity provider each site used.
- **Saved login in Chrome and Edge** — Added Computer Use filling a saved login into your own Chrome or Edge without exposing it to the model.
- **Prompt-cache warming** — Added automatic prompt-cache warming for Anthropic models under Settings → Context, learning your return habits and warming bots ahead of scheduled runs.
- **More Google connections** — Added connecting more Google accounts to Gmail, Calendar and Drive, choosing the account per request, with a clear sign-in prompt.

### Changes

- Changed agents to verify once after all edits instead of mid-task, run independent tool calls together, and keep progress updates short.
- Changed Settings into four sections: Basics, AI behavior, Integrations and Support.
- Changed the Sessions menu to let you choose which sidebar sections to show.
- Changed typing, session and tab switching, Search, Settings, side panels, the terminal and Changes to open instantly, with smoother status animations.
- Changed approvals from bot-delegated sessions to appear in every chat waiting on them, with the same wording and keys on every approval card.
- Changed session and bot rows to show an amber triangle for an approval wait, a question icon for a question, and waiting work counts.
- Changed bot task sessions and sub-agents to carry their own unread dot, read together with the chat they report to.
- Changed a paired phone to read, preview, download and open files the same way the PC does.
- Changed the `@` file picker to rank shallow paths first, open with recent work, and find files in linked folders (#228, thanks @reeves-ai-lch).
- Changed Visualize to open pages from any local folder, naming index pages by their folder.
- Changed the usage popup and pinned usage rail to show each limit as one line over a full-width bar.
- Changed the shell tool to accept an optional working directory and refuse sleeps of 2 seconds or more.
- Changed agent terminal runs and browser pages to reveal their tab on the PC and paired devices, opened directly from transcript lines.
- Changed Browser Use to cap background pages per session and close them after a turn finishes.
- Changed retry waits to show a fixed reason and a live countdown instead of raw error text.
- Changed bot chats to show no changed-files card under a reply, separate distant messages, and share one line for hand-off and time.
- Changed the language list to show Korean by its own name.
- Changed Mixy's regular check-in to run every hour by default, with the interval selectable under Settings → Bots.
- Changed the phone app to connect to your PC directly when the network allows, falling back to the relay automatically.
- Changed side panels to share one width, adjustable from 280 to 1160 pixels.
- Adjusted the phone side dock to close by swiping anywhere on the sheet, and animated drawer rows and text shimmers more smoothly.

### Bug fixes

- Fixed the split-pane layout being lost when the app's local storage is reset.
- Fixed panel edges, dividers and colours shifting when a side panel opens or closes.
- Fixed the phone drawer's content disappearing while it slides closed.
- Fixed the pinned bot leaving the composer's right end after a side panel closed, and chats dropping by a line on entry.
- Fixed a bot's row not spinning or taking unread dots while its task sessions work.
- Fixed clicking a desktop notification leaving the sidebar on the previous session, or doing nothing with the window hidden.
- Fixed answering a question card at the end of a chat stopping the transcript from following the reply.
- Fixed task sessions created with an explicit model failing with "service is not defined".
- Fixed Mixy's regular check-in running while you were still using the desktop app.
- Fixed Computer Use typing into windows that raise themselves, and writing into read-only or disabled fields.
- Fixed saved passwords longer than 4,096 characters being cut short, and secrets shorter than four characters going unmasked in chats.
- Fixed a queued retry of a failed turn, and a routine's skill choice, being lost after a restart (#229, thanks @22nsuk).
- Fixed quota auto-resume over SSH reading the server's quota instead of the PC's when the PC holds the sign-in (#232, thanks @22nsuk).
- Fixed `Option`+`Left`/`Right` not moving by word in text fields on macOS (#230, thanks @wudys).
- Fixed an agent profile's context selection not being preserved (#226, thanks @22nsuk), and Cursor failing on stored context conflicts (#225, thanks @22nsuk).
- Fixed a waiting task session reading as stalled, and a disabled connector account that could not be turned back on.
- Fixed a sign-in-expired turn error losing its retry, and the browser panel showing a blank page after its last page closed.
- Fixed clicking an attachment in a long or compacted conversation failing with "This conversation has no such attachment."
- Fixed the phone agent panel showing a duplicate Profile title above its own tabs.
- Fixed the side panel's Changes view being titled Profile after a bot's profile was last open there.
- Fixed the session list and chat on Android phones freezing after a fling and then jumping.
- Fixed sidebar section headers remaining highlighted after a click, and their spinner hiding while the menu button showed.
- Fixed compacting a conversation dropping current skills and rules instead of rebuilding them from active sources.
- Fixed Mixy appearing on her own after a failed startup check, reading out check-ins and then vanishing (#243, thanks @Jichiro-S).
- Fixed existing sessions ignoring current compaction settings, and forks compacting too early (#237, thanks @22nsuk; #238, thanks @skywhale345).
- Fixed bots asking you in chat to solve a CAPTCHA or sign-in step instead of handing you the page.

## v1.3.5 - 2026-10-24

Added emoji reactions, regular check-ins and SSH server model logins, with verified Google connectors, phone drawer swipes and broad fixes.

### New features

- **Emoji reactions** — Added bot emoji reactions on user messages with a toggle in Settings → General → "Reactions".
- **Regular check-ins** — Added 30-minute background reviews under Settings → Profile where your representative bot checks active sessions and wakes only when something needs attention.
- **SSH server logins** — Added running models using an SSH server's own provider logins and setting a private key file when connecting (#204).
- **Google connectors** — Added built-in Google Calendar and Drive connectors with verified sign-in, requiring all permissions and keeping Gmail on app passwords.
- **Phone swipe navigation** — Added horizontal swiping anywhere on the phone to open the session list or files dock.

### Changes

- Changed Office previews to render through Microsoft Office when LibreOffice is missing, detect installs immediately, and ask for the password of protected files.
- Changed schedules, bots, rooms and Lead sessions to be renamable from their menus, keeping one-shot run times intact.
- Changed Linux secret storage to fall back to protected local files when no keychain is available, explaining why keys cannot be read (#204).
- Changed bot chats to show exchanges with other sessions inline, and clicking the representative bot's speech bubble dismisses it.
- Changed the app to open faster by showing your chat and session list before agents load, and switching back to a recent session now shows it instantly.

### Bug fixes

- Fixed switched-off room bots continuing to take turns, naming them clearly when addressed (#215).
- Fixed approval cards stealing focus while typing in the composer, and showed a waiting browser-approval mark in the phone session list.
- Fixed long tool outputs on the phone failing to load through Show full output, and opened chats sticking on loading skeletons.
- Fixed switching between sessions sending an in-progress composer draft to the wrong chat (#217).
- Fixed right-click and row menus closing unexpectedly whenever a background agent updated or transcript scrolled.
- Fixed browser auto-sign-in failing on CAPTCHA challenges or worker crashes, keeping consistent browser identity across Cloudflare checks.
- Fixed broken emoji surrogate pairs failing model requests, and isolated full quota windows so they block only affected models (#209).
- Fixed finished agents being marked as canceled when closed, and allowed editing definitions directly in place (#211, #216).

## v1.3.4 - 2026-10-23

Fixed phone scrolling that stopped or jumped, model lists missing provider models, and tables shaking while a reply streams.

### Bug fixes

- Fixed a fast flick on Android stopping partway in the session list, also right after returning to the app.
- Fixed scrolling up through a chat on Android stuttering or jumping partway.
- Fixed tables shaking sideways while a reply streams in a coding chat.
- Fixed a room's Stop missing a member reply, approval or message that finished just after it (#201).
- Fixed options picked on a question card being lost when answering from the composer (#202).
- Fixed a sub-agent failing to start when its model was given by its display name (#203).
- Fixed agents asking you to close their finished sub-agents instead of closing them themselves.
- Fixed model lists in the agent editor, bot profile and composer missing models from OpenCode Go, OpenRouter and other providers (#205).

## v1.3.3 - 2026-10-22

Added a 12/24-hour time setting, legacy Office attachments and long-paste folding, with smoother phone scrolling, steadier compaction and broad room and bot fixes.

### New features

- **Time format** — Added Settings → General → "Time format" (phone: Settings → Display) to show times as System, 12-hour or 24-hour.
- **Legacy Office attachments** — Added sending `.xls`, `.doc` and `.ppt` files; they are converted through LibreOffice when the Office feature is installed (#163).
- **Long pastes** — Added folding pastes over 1,000 characters in the composer, and sent messages longer than 20 lines behind "Show more" (#186).
- **Everyone in a room** — Added `@all` to address every room member, and naming a room member from another session to reach it (#164, #180).
- **New task without a project** — Added `Ctrl+Alt+N` to open a new task that is not tied to a project (#185).
- **All usage accounts** — Added expanding every signed-in account in the usage panel and the side rail.
- **Image input per model** — Added an Auto/On/Off "Image input" choice to each custom provider model (#191).
- **Goal bar** — Added a progress ring, a compact count-only bar and an inline stop confirmation to the Goal bar.

### Changes

- Changed the session list to hide sub-agent and archived sessions; idle sub-agent sessions are archived after 3 days and deleted after 30 (#165).
- Changed a bot's model change to apply to its open chats from the next turn (#166).
- Changed bot approvals to ask only in the bot's own chats, with room members following their home chat's rules (#167).
- Changed Mixy's look to both ears down and a thick tail with a lighter tip.
- Changed the representative bot's position to one dropdown in Settings, added a Free placement, and showed its uploaded picture (#178, #179).
- Changed agent sessions in the sidebar to show only the model name, and a bot's task session to show as one result card.
- Changed coding replies to appear word by word, with finished tool groups named in the past tense and the status line last.
- Changed custom providers to show their registered name in model pickers, usage, workflows and notices.
- Changed connectors with several accounts, such as three Gmail accounts, to show as one row and one icon.
- Changed tapping a notification to open the session at its latest message.
- Changed phone browser tabs to pair directly instead of showing the Add to Home Screen guide.
- Changed the Android notification icon to the Mixdog mark.

### Bug fixes

- Fixed scrolling up on the phone stopping midway or jumping when older messages loaded.
- Fixed taps and drags not reaching the browser panel when using Mixdog remotely from an iPhone or iPad.
- Fixed agent reports, tool results and late MCP tools being lost after a conversation was compacted.
- Fixed the conversation stopping to follow a long reply, or releasing it when text was pressed.
- Fixed the unread dot staying on a chat you were reading in a side pane.
- Fixed editing a previous message dropping its attachments, and rewinds that ignored later history (#186).
- Fixed open conversations not noticing agents that were enabled or disabled (#184).
- Fixed replies stopping at the output limit and a broken reasoning-effort judge staying broken (#183).
- Fixed a removed bot continuing its work in rooms and conversations (#180).
- Fixed bots escaping the bot-to-bot limit by passing through background tasks.
- Fixed a failed settings backup pushing out good backups early (thanks @22nsuk).
- Fixed Windows Computer Use losing screen elements during a snapshot (#173, thanks @22nsuk).
- Fixed memory sorting rejecting classifier answers that list row ranges (#170, thanks @134634623).
- Fixed staging Git changes in files that are not UTF-8 (#177).
- Fixed the mascot not showing when its picture had no size.

## v1.3.2 - 2026-10-21

Added themes and photo skins, the representative bot overlay, and switching the workflow and delegation mode mid-conversation, with Windows code signing and broad fixes to compaction, approvals and attachments.

### New features

- **Themes** — Added Settings → Themes to pick System, Dark or White, one of four moving photo skins or your own photo or short video, and the font and text size on one screen.
- **Representative bot overlay** — Added the representative bot sitting above the PC app's composer, showing replies in a speech bubble that pages through long answers on its own; click it to send a message, or right-click for size, position pinning and settings. Choose it in Settings → Bots.
- **Fallback models** — Added fallback models to Lead, the representative bot and bot profiles, moving to the next model when one hits its usage limit.
- **Workflow and delegation switch** — Added switching the workflow and delegation mode from the model menu during a conversation; it applies from the next turn to that conversation only.
- **Smart compaction** — Added Settings → Context → "Compaction summary model" with Smart, Maintainer or Conversation model. Smart is the default.
- **Auto reasoning base** — Added Settings → General → "Auto reasoning base" to pick the effort Auto works around.
- **Image generation** — Added image generation in Studio with OpenRouter and NanoGPT image models.
- **Side panel position** — Added Settings → General option to place the side panel on the right, at the bottom or automatically.
- **Bots page layout** — Added dragging bots to reorder them, showing or hiding the representative bot, bots, rooms and agents from the `…` menu, and one place for running tasks.

### Changes

- Changed the Windows installer and app to be code-signed, so Windows security warnings and antivirus false positives are reduced.
- Changed browser-use approvals from OS windows to approval cards in the chat, and file uploads now ask too.
- Changed approval cards to show the requesting bot and a one-line question, decline in one click, and never decline on their own while waiting.
- Changed sub-agent approval requests to also appear in the top-level chat, with "Open session" to jump there.
- Changed bot profiles to list items set to "Always allow" and turn each back with "Ask again".
- Changed schedules and webhooks to ask once when saved and not again while running; payments and permanent deletion never run unattended.
- Changed a linked phone to only narrow, never widen, bot permissions and connectors.
- Changed a disabled bot to stay on the Bots page as "Off" so it can be turned back on, and to be hideable from the sidebar separately (#153).
- Changed sub-agents to expand by clicking the face or right-click "Show sub-agents" instead of an arrow.
- Changed the model picker to drop the "Auto reasoning" switch and list Auto at the top of the effort list.
- Changed the model picker to open right below its row, and custom providers to show the name you gave them.
- Adjusted bot rooms so bots talk naturally instead of agreeing with each other every time; without a Maintainer model, each mentioned bot answers once.
- Changed bot-to-bot messages to show the sending and receiving bot, and limited back-and-forth between bots to three exchanges.
- Changed bot reply notifications on PC and phone to use the bot's or room's name as the title.
- Changed the composer's Git button to open the Git tab, where Create PR, Commit & push and Commit each have their own Run button.
- Changed the end-of-task card to show thumbnails only of files the answer linked or opened in the side panel.
- Changed scrolling so the view moves only when you scroll and follows new replies again once you reach the bottom; long answers arriving at once start from their first line.
- Changed a slow MCP server to delay the first reply by at most 3 seconds; tools that connect later are available from the next turn.
- Changed streaming replies to appear in small steps with a brief fade on new words, so text no longer pops in chunks.
- Added pinning agents on the Bots page from the right-click menu, and "Keep finished agents" in the `…` menu for 1 hour, 1 day, 7 days or forever.
- Added "Unlimited" to idle session auto-clear.
- Adjusted the agent window's token and cost line to hold its place from the start so the view no longer shifts.
- Adjusted the setup tool's guidance so the AI can set a skill's trigger line (`when_to_use`) when it creates or edits a skill.

### Bug fixes

- Fixed Anthropic chats with a large image or PDF failing repeatedly with "attachmentReference: Extra inputs are not permitted".
- Fixed attaching several PDFs blocking the chat by exceeding the context; large attachments stay on this PC and only needed parts are read (#150).
- Fixed rich text copied from Word, Excel or a browser being attached as an image (#135).
- Fixed unsent attachments disappearing after visiting another session (#139).
- Fixed Lead's model and reasoning effort changing whenever a new task opened (#149).
- Fixed Claude Opus 5.5 answering in English instead of Korean at the end of long tasks; Lead and bot final answers now come in Korean.
- Fixed settings and account files breaking after a forced shutdown and losing sign-ins and settings; they are now restored from the last good copy (#151).
- Fixed creating or editing files in sync folders such as NAVER MYBOX failing with EPERM (#138).
- Fixed the model list staying empty after signing in to OpenCode Go (#141).
- Fixed an interrupted code-tidy engine install getting stuck and never reinstalling; it now reports the failure and reinstalls per engine (#152).
- Fixed saving a custom provider with a slow model list failing with a timeout.
- Fixed starting a new task returning to a blank screen.
- Fixed the finished sub-agent list disappearing after restarting the app or background service.
- Fixed sub-agents in work handed off by the representative bot reporting an interim answer as the result before finishing.
- Fixed tasks waiting for approval showing as stalled or being cut off by a timeout.
- Fixed sub-agents following the main chat's context, reasoning effort and speed settings, and ignoring the Maintainer setting.
- Fixed a long answer arriving at once looking blank and faint for a moment.
- Fixed a stopped queued input running again after recovery (#142, thanks @22nsuk).
- Fixed shell jobs whose exit was never confirmed being treated as finished (#133, thanks @22nsuk).
- Fixed running tasks losing their protection when the workspace record was damaged (#117, thanks @22nsuk).
- Fixed Cursor models losing tool call IDs and stalled tool handoffs never ending (#156, thanks @22nsuk).
- Fixed the typing indicator never ending in bot rooms, and messages sent mid-reply going missing.
- Fixed the "results omitted" notice not appearing in a bot's chat when many routine results piled up.
- Fixed the Bots list's unread count also counting tool calls.
- Fixed completion notices for other sessions not appearing while the app was in view.
- Fixed the session list jumping on phones when its order changed while scrolling, and iPhone settings sheets not closing on an outside tap.
- Fixed email links in answers doing nothing when clicked.
- Fixed PreToolUse hooks being skipped on sessions reopened later, such as an agent's follow-up turn (#161).
- Fixed GitHub sign-in getting stuck at "Starting GitHub sign-in…" (#162).
- Fixed the reasoning effort still showing Auto after you picked another one (#131).
- Fixed the fullscreen button of videos in the side panel doing nothing (#160, thanks @Deno2026).
- Fixed the app showing "Object has been destroyed" when its window closed with the representative bot overlay on.
- Fixed a slow Git command making the app reconnect to its background service and briefly lose live session updates.

## v1.3.1 - 2026-10-20

A stabilization patch for issues found since 1.3.0, with an upgraded reasoning-effort judge.

We're sorry that the 1.3.0 update reset some workflow data for some users.

### Changes

- Changed messages sent during a running task to appear in the chat right away, with **Send now** until they are read; the queue above the composer is gone.
- Changed outbound approval cards to appear only when a bot sends, posts or deletes; coding sessions no longer ask.
- Changed the representative bot and Lead to keep separate models, and sending without a model to open the model picker instead of choosing one automatically.
- Changed bots and agents to pass attachments and produced files along when they hand work to each other.
- Changed visualize cards to one card per task, gathering the pages it opened as thumbnails.
- Changed confirmation dialogs such as delete from the Windows default to dialogs that match the app theme.
- Removed the model picker and context indicator from the bot room composer.
- Changed GitHub to no longer be a connector; it uses the signed-in GitHub CLI directly.
- Adjusted error notices to give a clear error instead of the raw message when a model is unavailable or a key is invalid.
- Adjusted output styles so replies pick paragraphs, tables or lists to fit the content.
- Changed the composer's tok/s to count the wait for the first token, matching the Usage window.
- Changed Auto reasoning effort to use effort judge v7, which agrees with reference ratings more often than v6.

### Bug fixes

- Fixed saving Lead's model options failing with "model selection contains an unsupported field" (#132).
- Fixed bot chats failing with "provider message prefix changed outside compaction".
- Fixed an empty Lead model after updating to 1.3.0; it now takes the model you last used in a new task, and bots keep the model they chatted with.
- Fixed older custom agents showing up as bots after updating to 1.3.0.
- Fixed the representative bot's persona leaking into coding sessions.
- Fixed the representative bot not reporting back after handing work to another session; reports now continue after a restart.
- Fixed agent task sessions created by the representative bot opening with an empty model ("Select model").
- Fixed switching to the Bots page replacing the main area with the representative bot's chat.
- Fixed the composer not accepting input after deleting a bot room.
- Fixed agents not moving to their next model when the first one hit its usage limit.
- Fixed the phone loading forever when the connected PC was off; it now says it can't connect and lets you retry (#134).
- Fixed phone scrolling stopping or jumping while earlier messages loaded.
- Fixed the visualize panel opening slowly on the phone.
- Fixed Gemini 4 Argon failing with 404 when signed in with Antigravity.

## v1.3.0 - 2026-10-20

Added a bot system, support for more connectors including Gmail via app password, and improved client stability.

### New features

- **Bot chats** — Added messenger-style bot chats with persistent home threads, customizable bot profiles, and the default representative bot Mixy.
- **Group rooms** — Added group rooms where multiple bots collaborate, with `@` mentions, attachments routed to addressed bots, and light supervisor orchestration using the Maintainer model.
- **Approval cards for outbound actions** — Added approval cards for sending messages, emails, posts, payments and deletions, showing exact details before anything runs.
- **Routines in bot chats** — Added running schedules and webhooks as turns inside their owning bot's chat.
- **Setup guide** — Added a first-setup guide with role-by-role model recommendations and subscription plan detection.
- **Connectors** — Added connectors for outside services, including Gmail with an app password, so bots can work with your accounts.

### Changes

- Changed the PC composer to a one-line input bar that grows with longer prompts.
- Changed long session lists and long transcripts to scroll more smoothly.
- Changed session diff views to fold unchanged lines and drop missing-file banners.
- Changed phone app updates to download in the background, with status in Settings and the activity rail.
- Adjusted the visualize side panel to widen across the same range as the browser panel.
- Changed routines to drop their own model and workflow fields and use the owning bot's settings.

### Bug fixes

- Fixed phone transcript scrolling stalling when a streaming word finished fading during a drag.
- Fixed queued messages and their attachments being lost or skipped after a restart (#119, thanks @22nsuk).
- Fixed settings restoring an older backup when two saves landed at the same moment (#120, thanks @22nsuk).
- Fixed shell commands finishing while child processes were still running after a failed start or cancel (#124, thanks @22nsuk).
- Fixed search listing the same file twice under different path spellings (#118, thanks @22nsuk).
- Fixed the session list jumping when favoriting, unfavoriting or deleting a session (#129, thanks @oh1701).

### Other

- Updated interface translations across all supported languages.

## v1.2.6 - 2026-10-18

The desktop now idles lighter and switches sessions faster, shell commands move to the background after 60 seconds, and Model management and OpenCode Go sign-in are new.

### New features

- **Model management** — Added a Settings page to favourite and hide models, plus a right-click menu in the model picker.
- **OpenCode Go sign-in** — Added signing in to OpenCode Go with your OpenCode account; it replaces the old API key.

### Changes

- Changed the desktop to use less CPU while idle and to switch sessions faster.
- Changed the shell to move a command to the background after 60 seconds; completion notices now include the exit code and output.
- Changed provider lists to show why models failed to load instead of an empty list, and added an API key link to connected providers.
- Changed archiving or deleting a busy session to ask for confirmation first (#109).
- Changed replies to read shorter and group results, causes, and decisions; tables now wrap instead of scrolling sideways.

### Bug fixes

- Fixed the backend stalling under heavy agent load and restarting itself, which stopped running agents.
- Fixed cancel leaving child processes and servers running (#115).
- Fixed pasted text being hard to read or edit when long (#110), and typing a plain `/` in the composer (thanks @oh1701).
- Fixed the shell confirm dialog pushing its buttons off screen (#114) and empty `.git` folders blocking tasks (#108).
- Fixed agent usage totals leaving out closed agents (#99, thanks @22nsuk).
- Fixed attachments being lost while loading, and a failed agent marking its whole session tab as failed.
- Fixed every turn failing with "Workspace activity cannot be verified" after a crash damaged the workspace ledger.
- Fixed expired account cooldowns not retrying (#106), settings backups losing originals (#105), and unreadable usage history blocking totals (#103), thanks @22nsuk.

## v1.2.5 - 2026-10-18

Phones now connect faster and without popups, the desktop no longer slows down once many agents have run, and streaming replies appear more smoothly.

### Changes

- Changed phone connections to reconnect automatically without popups or countdowns; a small dot appears only during a long outage.
- Changed streaming replies to appear word by word with a soft fade, without jumps from unfinished Markdown; code blocks appear with their content.
- Changed agent status to show Done until you open the result, then Idle.
- Changed the branch menu to open from a `…` button or right-click; on phones, long-press a branch.
- Changed visualize pages on phones to open directly without a Run prompt, as on the desktop.
- Adjusted the usage panel and the composer island summary to keep their height while figures load.
- Changed the Android install QR code to download the app directly.

### Bug fixes

- Fixed sent messages and replies not appearing in the conversation after the app restarted until it was reopened (#113, thanks @oh1701).
- Fixed the desktop pausing about a second at a time once more than 256 agent sessions existed.
- Fixed phone requests waiting behind slow usage and Git reads on the desktop.
- Fixed phones being disconnected while the desktop was busy, and the first connection after opening the app taking over 10 seconds.
- Fixed phones staying on "Allowed. Connecting…" forever, or showing "Request expired" after the PC had approved.
- Fixed a phone asking for approval again on launch after its saved sign-in was lost.
- Fixed phones looking connected while the PC restarted, with every message timing out.
- Fixed paired phones being cut off for good when the PC failed to read its connection identity.
- Fixed one slow file-path check holding up every other phone request.
- Fixed scrolling up in long conversations stalling while older messages load (#104).
- Fixed the conversation pulling back down while scrolling up on phones during a streaming reply.
- Fixed overlapping icons on file cards and repeated download-failure notices.

## v1.2.4 - 2026-10-17

Added agent session control and fallback model assignment, automatic worktree preparation, harness output optimization, and overall performance improvements.

### 1. Harness improvements: reduced output, cleaner styles, and general stabilization

- Adjusted agent completion reports and question cards to be more concise, and reduced Git, search, and GitHub tool outputs to save tokens.
- Changed background shell and external tool process cleanup to be more reliable, and adjusted unresponsive agent detection during long tasks.

### 2. Media generation improvements

- Added transparent background support and preferred model pinning by media type, and improved ChatGPT image generation stability.

### 3. Agent fallback model assignment

- Added fallback models that engage in order when the primary model fails, and allowed specifying a model directly when spawning sub-agents (#86).

### 4. Worktree improvements

- Added automatic package installation and environment setup when creating a new worktree, and improved branch menu responsiveness.

### 5. Provider tool call stabilization

- Fixed Claude thinking handling errors and added usage tracking on Antigravity, and reinforced reasoning and tool call reliability on custom gateways (#79, #94, thanks @22nsuk and @sukjong2002).
- Adjusted Antigravity connection and retry handling for better stability, and improved tool execution in Cursor and OpenAI-compatible environments.
- Added the ability to check the status of PC-registered providers directly from remote SSH windows (#77, thanks @22nsuk).
- Changed Anthropic and ChatGPT request compression to handle large requests with safe fallback, speeding up initial responses.

### 6. Agent session management refresh

- Changed finished agents to remain in the panel for one hour, and restored the task count summary by status and waiting notices.

### 7. Lead agent session management

- Added the ability for lead agents to view other sessions and their contents, and manage them directly by sending messages, cancelling, or deleting sessions.

### 8. Remote and desktop performance optimizations

- Adjusted remote reconnects to quickly catch up on missed content, and improved mobile streaming smoothness and session switching speed.
- Added reopening the two most recent sessions directly on mobile, and fixed freezes on the launch screen.
- Adjusted desktop panels, sidebar, session switching, editor, and settings screens to open faster and transition more smoothly.

### 9. Remote app download improvements

- Added zip downloads for folders excluding unnecessary files in the remote web app, and expanded the range of downloadable files via conversation links.
- Adjusted mobile file saving and notification enabling (file saving on Android/iOS applies after an app update).

### 10. Other bug fixes and minor improvements

- Changed SSH remote model connections to remove call and rate limits (#101).
- Fixed paused Goals to resume automatically after usage resets, and fixed several bugs in the Changes panel and command status display.
- Fixed the internal browser getting blocked by Google login and bot detection checks (#102).

## v1.2.3 - 2026-10-16

Since launch, far more of you have been using Mixdog than we expected, and we are truly grateful. Some parts are still unstable, and we are fixing them as quickly as we can. Your issues and pull requests shaped much of this release. If something goes wrong, please let us know from **Settings → About → Feedback**.

New to Auto reasoning? A small judge model on your PC picks how hard the model thinks for each message and step. Read how it works and how it did on Terminal-Bench 2.1 in [Auto reasoning effort](https://github.com/tribgames/mixdog/blob/main/docs/auto-reasoning-effort.md).

Added moving a chat into a worktree from the composer island, smoother streaming text, and a faster, more reliable background service.

### New features

- **Worktrees from the island** — Added a branch segment to the composer island that moves a chat into a worktree, carrying or leaving uncommitted changes.
- **Question cards** — Added a card for questions an agent asks you, in the desktop app and the TUI.
- **`/btw`** — Added `/btw` to ask a quick question without interrupting the current task.
- **Session tool** — Added a tool that lets the agent rename, compact, fork, and move the current session (#14, thanks @hyeon1035298).
- **Several PCs on Android** — Added switching between up to 16 saved PCs in the Android app (#83, thanks @yupguni).
- **Recover interrupted edits** — Added a recovery panel that shows file edits interrupted by a crash and restores or discards them safely (#60, thanks @22nsuk).

### Changes

- Changed streaming replies to appear smoothly as they are written instead of in line-sized bursts.
- Changed quitting, new chats, and the Changes panel to respond much faster.
- Changed MCP tool schemas to be converted for each provider, so tools that work in other apps work in Mixdog; a broken tool is skipped with a notice.
- Changed usage totals to stay hidden when a provider did not report usage for every call (#90, #91, thanks @22nsuk).
- Changed moving changes into a worktree to refuse files Git hides from status, so no edit is lost.
- Changed settings backups to stay with each profile, so one profile's settings are never overwritten by another's.
- Changed the Visualize version strip to a Versions menu, and added tab renaming by double-click and slash command highlighting.
- Changed provider icons to the official logos.
- Changed Auto reasoning to also run on ChatGPT sign-in routes.

### Bug fixes

- Fixed Claude models on Antigravity failing with HTTP 400 because of tool schemas (#80, thanks @ProofPage).
- Fixed the New branch button in chat doing nothing (#85, thanks @oh1701).
- Fixed newly started agents not seeing MCP tools on their first turn (#88, thanks @oh1701).
- Fixed the background service freezing when deleting sessions, and deleted sessions or their tabs coming back.
- Fixed the database sometimes staying open after quitting the app.
- Fixed the first message after switching a chat's model failing with "Session state changed unexpectedly".
- Fixed the Android back button not closing the right side panel.
- Fixed the island branch name appearing late and shifting the layout, and shell rows flickering as a command finished.
- Fixed the side panel staying open after its last tab closed, and the Visualize panel staying collapsed when a visual opened.
- Fixed developer provider switches showing off after turning them on, and custom provider errors showing internal messages.
- Fixed the transcript jumping when the composer changed height.

### Other

- Fixed a desktop build error (#89, thanks @22nsuk).

## v1.2.2 - 2026-10-14

Added explicit MCP OAuth sign-in, in-place model switching, and a one-line quota banner.

### New features

- **MCP sign-in** — Added explicit OAuth sign-in for MCP servers with status, a shared login dialog, remote paste, and TUI commands (#74, thanks @oh1701).
- **Switch model in place** — Added switching a chat's model without starting a new session, and Fork in the session menu (#73, #52, thanks @grapefruit0205).
- **Quota banner** — Added a one-line banner above the composer when a limit is reached; Resume reserves the next run for the reset time.
- **Files menu** — Added an island Files count that tracks uncommitted session changes, with View changes and Delete history.
- **Chat text size** — Added a per-device chat text size setting.

### Changes

- Changed provider retries to follow each provider's own limits and wait times, showing the remaining wait with a way to cancel.
- Changed error messages to name the cause and next step, and to hide Retry when retrying cannot help.
- Changed shell commands to stay in the foreground for 10 seconds by default, up to 30 seconds, before moving to the background.
- Adjusted the desktop app, auto reasoning, and the background service to use less polling, rendering, and memory in long sessions.

### Bug fixes

- Fixed the background service freezing for one to two seconds every 30 minutes.
- Fixed Agent completion notices being dropped when a turn that already had output was cancelled.
- Fixed the composer island showing running Agents as idle or done.
- Fixed switching sessions stalling when waiting on other sessions' change scans.
- Fixed browser page dialogs leaving the pane, leave confirmation failing to complete, and browser copy shortcuts failing.
- Fixed prompt caching failing on custom Responses providers and inherited session projects not matching the sidebar (#70, #75, thanks @sukjong2002).
- Fixed streaming tables flickering, the transcript bouncing while a turn works, and the quota card staying after switching providers.

### Other

- Removed unused helpers (#67, thanks @22nsuk).

## v1.2.1 - 2026-10-14

Added conversation import from Codex and Claude Code, the Command Code provider, and `$` skill mentions, and fixed Computer Use input observation, skill scripts, auto reasoning, and several session issues.

### New features

- **Conversation import** — Added Settings > General > Import conversations to bring Codex and Claude Code chats on this PC into Mixdog.
- **Command Code** — Added Command Code as a provider that signs in with your Command Code account.
- **Account switching policies** — Added Manual, Switch at limit, and Most headroom first for providers with several accounts.
- **`$` skill mentions** — Added `$` in the composer and TUI to pick a skill and apply it to that message.
- **5-hour usage bar** — Added a usage menu option that shows a 5-hour bar next to the longest period on the sidebar rail (#66).
- **Visualize feedback cards** — Added composer cards for queued visualize pins, picks, and tweaks, and pins on images, video frames, and dragged regions.
- **Dismiss Goal** — Added a button to dismiss a finished Goal.

### Changes

- Changed Claude Code and Codex plugin MCP servers to connect automatically without a manual enable step, and added Claude Code plugin skill loading (#58).
- Changed the session list to load from a local database and caches so it opens faster.
- Changed skills on SSH servers to route model calls through your PC, so the server needs no credentials.
- Changed `@` file mentions to list folders first.
- Changed Muse Code and MiMo to their own icons.
- Changed sent image thumbnails to load as downscaled previews on the PC and paired phones.
- Adjusted MCP tool loading, file searches, and account saves so they no longer block the background service in long sessions.
- Adjusted the Goal progress mark to always show five cells.
- Adjusted the composer island to sit 12px above the prompt card and restored 14px tool activity lines.

### Bug fixes

- Fixed Computer Use staying unavailable with "foreground input observation is unavailable"; missed input now counts as user input, observation recovers on its own, and diagnose names the cause (#66).
- Fixed adding an SSH server in the installed app staying on "Connecting…" forever by packaging the server lockfile (#69, thanks @victorwon2001).
- Fixed chat links opening the in-app browser on a blank `about:blank` page instead of the link (#63).
- Fixed bundled skill scripts, including the skill validator, failing in some installs and shells (#62).
- Fixed new tasks that remembered a deleted workflow so they start on Default (#64).
- Fixed auto reasoning not applying on Claude routes in 1.2.0, and one slow judgment timing out the ones after it.
- Fixed Gemini, Anthropic, OpenAI, and OpenAI-compatible providers not listing models when the key was added after startup.
- Fixed a second message sent right after a new task started opening a separate session.
- Fixed fast upward scrolling on phones stopping short and then jumping far up on the next touch.
- Fixed the rename editor closing at once for sessions listed in both a project folder and Recent.
- Fixed thumbnails showing the wrong image in restored conversations with several images.
- Fixed hook commands inheriting Mixdog's internal runtime settings.
- Fixed headless runs, such as model calls from skill scripts, being unable to use Muse Code or MiMo.
- Fixed the confirmation dialog not appearing when removing an MCP server or plugin.
- Fixed the ONNX runtime failing to load on Windows PCs without the Visual C++ runtime by shipping that runtime with the app.

### Other

- Reviewed translations across all 11 languages.
- Removed unused helpers and formatted desktop tests (#68, thanks @22nsuk).

## v1.2.0 - 2026-10-13

This release introduces the Changes panel and per-turn change cards with per-turn undo and reapply controls, keeps earlier conversation history visible after compaction, and adds a built-in visualization tool for interactive UI mockups and diagrams. Remote workflows expand with SSH server connections, isolated Git worktree sessions, background shell management, and direct file downloads on paired phones. The interface also brings higher contrast styling, smoother mobile scrolling, and flexible session organization.

### New features

- After a conversation is compacted, its earlier messages, tool cards, and diffs stay readable above a "Conversation compacted" divider instead of disappearing. They are kept for display only (never sent to the model), reload by scrolling up after a restart, use up to about 32 MB per session (with the oldest trimmed first), filter sensitive values like other history, and are deleted with the session, while continued sessions link back instead of duplicating them. Undo, reapply, and retry are not offered for turns before the compaction.
- The Changes panel provides a single scrolling view of every changed file's diff with tabs at the side: the "Changes" tab shows all files, while clicking a file in a turn card opens just that file's tab. The panel works without Git using the session's own change records, highlights syntax, wraps long lines instead of scrolling horizontally, folds or unfolds when clicking anywhere on a file row, opens a file in a tab with `↗`, undoes a file with `↶`, and lists files outside the project read-only with their full path in the tooltip. Closing the last tab closes the panel.
- A turn changes card under each turn displays the number of changed files, a +N −N line diff summary, a View changes button, and the list of modified files.
- Redesigned tool cards show the change made by each individual edit rather than the turn's running total, rendered in the same diff view as the Changes panel, and display line additions and deletions while the tool is still running.
- A built-in visualize tool generates project mockups and inline diagrams (Mermaid, SVG, ECharts, HTML, and Markdown) in dedicated side-panel tabs. You can inspect elements, capture page errors, leave pinned feedback with data selections for the next message, compare and restore versions, and export designs to PNG or PDF.
- Git worktree sessions let you work on isolated branches without touching your current checkout. A branch chip above the composer lets you choose or create a new worktree branch when starting a task, with guarded merges that prevent merge conflict residue.
- Connect to remote servers over SSH from Settings > Connection. Mixdog installs automatically on the server, opens in its own window with a Ports panel with port forwarding, remote file browsing, and terminals, and proxies model calls through your PC so credentials never need to live on the server.
- Paired phones can now download and share assistant-produced files and generated media directly from chat links, complete with transfer progress, retries, and cancellation (saves to Downloads on Android and the share sheet on iOS; with the next Android app update or iOS app build) (#40). Paired phones are also strictly limited to registered projects and files produced in that session.
- Background shell commands can be stopped directly from the app or remotely. Finished commands stay listed until dismissed instead of disappearing immediately, and the composer island's jobs panel expands inline to show running background commands alongside agents with cumulative token usage and tool call counts.
- Move a session to another project from the sidebar menu or by drag and drop without moving its folder on disk; sessions located in a project's subfolders and worktrees are grouped under that project automatically.
- Side panels on phones (browser, terminal, changes, and preview) share the same header as on PC, complete with tabs, a menu to switch panels, and a close button. In the phone browser, `+` opens a new tab in that session's side panel, and tabs switch and close just like on the PC (needs the updated PC app).
- Images you send retain thumbnails after restarting the app, and visualize and HTML file cards display a real visual preview of the page rendered locally in an isolated sandbox with no network access for files inside the project.
- The composer island lists running agents in the same format as the Agents window, and automatically hides the shell section when no background shells are active.
- Closing the last terminal, browser, or file tab closes the side panel, and opening the terminal again starts a fresh tab (based on #49 by @moveju112).
- Project folders and sidebar sections stay open by default and remember their collapsed state, while selecting a session inside a collapsed folder opens it automatically. Sessions can also be reordered by dragging or sorted by recent activity.
- The Android app can now check for updates in the background, download, verify signatures, and install new versions directly (with the next Android app update).
- Auto reasoning can now be configured individually per model route in route settings and disabled for automations with `+noauto`. In Settings > Connection, you can also assign custom local nicknames to paired remote devices.

### Changes

- Sharper accent colours and higher text contrast; tool and turn card headers use a subtle grey with outline-only boxes; inline code shows as grey chips and quotes with a left rule; selected text and diff line numbers meet 4.5:1 contrast in both themes.
- The drawer opens without a shadow and dims the screen behind it by 40%.
- The branch and worktree chip above the composer appears only in Git projects and only before the conversation starts.
- The composer island's changed-file count now covers the whole session instead of resetting after each turn.
- The visualize toggle left the panel header; visualizations open automatically or from their card in the conversation.
- The context ring opens only when clicked, not on hover (#48).
- On phones, Enter inserts a line break; send with the button.
- Messages fade out under the composer and island instead of being cut off.
- Files outside the project show their name with the full path in the tooltip instead of a badge.
- Smoother scrolling, especially on Android: the conversation redraws at most once per frame, the spinner animates on the GPU, the scroll position is saved when scrolling stops, touches are no longer blocked, and the fade under the composer no longer repaints the whole list.
- MCP tool calls enforce execution timeouts (default 120 seconds) without hanging or retrying, report stdio process crashes with error details, and support pagination for long tool listings.
- Auto-clear runs on idle sessions before background completions wake the conversation.
- On macOS, launching the desktop app appends Homebrew directories to `PATH` without dropping existing path entries.
- The remote terminal on mobile includes a dedicated key bar with modifier and navigation keys (with the next Android app update or iOS app build).

### Bug fixes

- Tapping a chat link opened the in-app browser blank; the page now loads, and on phones the browser panel opens full screen (#41).
- The thinking indicator stayed in English until the app language loaded; the phone shimmer animation is fixed.
- The turn card, the island, and the Changes panel could show different numbers of changed files.
- The first upward scroll in a long conversation could jump.
- Closing the last terminal tab created a new tab and flickered (#49).
- Reading a file never returns stale content or claims line ranges that were not actually delivered, even when a large file is rewritten in place at the same size (#54, thanks @22nsuk).
- File saving and batch recovery maintain text encoding, reject lossy saves, protect dirty buffers during conflict reads, and track batch writes while retaining file permissions and path casing (#39, thanks @22nsuk).
- On macOS, `Cmd+Up` and `Cmd+Down` jump within text fields instead of triggering workspace shortcuts.
- Configuration and state files starting with a byte order mark (BOM) load cleanly instead of failing or reinitializing.
- Signing into OpenAI preserves the complete model catalog instead of inadvertently hiding available models.
- On Linux, pasting or reading an image crashed Mixdog's background service and cancelled the running turn; images now go through a build of the image library that works there (#56, #57, thanks @cronoboris).
- After Mixdog was shut down abnormally (Windows shutdown, an installer, ending it from Task Manager), the app could fail every action with "daemon session endpoint is unavailable" and show no chats until a leftover lock file was removed; it now recognises the stale lock and recovers on its own. An unreadable file in the temp folder no longer stops the background service from starting either, and when it still cannot start, the error's details show the actual cause and where the logs are.

### Other

- Translations of new and changed strings reviewed across all 11 languages.
- Published raw evaluation artifacts for DeepSeek V4.1 Flash on Terminal-Bench across 89 tasks comparing Mixdog against DSH (#43), and added the full GPT-6.1 Sol evaluation preset.
- Mobile app icons updated to match the desktop titanium mark (with the next Android app update).

## v1.1.2 - 2026-10-12

The "What's new" notice now appears after an update even if the app's local storage was lost, waits until the starter welcome or tour is closed, and no longer reappears after a downgrade.

The starter guide no longer reappears for existing users after local storage is lost or the app updates.

Muse Code and MiMo usage now appears under its own row in the sidebar instead of being shown as Grok.

The Ultrafast speed is shown in orange on model labels, including the agent rows in the side dock.

In the composer island, clicking the files segment opens the changed-file list in the right side dock when several files changed (a single changed file still opens its diff). The agent and shell segments open their lists in the side dock too, formatted like the Agents sidebar and navigable with the keyboard.

Tool rows no longer show the light sweep while running.

Adding an MCP server from the add dialog now creates it, and a name that already exists is rejected instead of overwriting the existing server.

On Linux, "Allow" for Computer Use input access now verifies real access to `/dev/uinput`, repairs it when needed, and explains what to do if it still fails: sign out and back in, add your user to the `input` group, or enable the missing uinput module (#32).

## v1.1.1 - 2026-10-12

Continuing a session after switching its model ("Continue in <model>"), and retrying a failed turn ("Retry"), no longer fail with "submit options contains an unsupported field."

Muse Code (Meta) is available as a subscription provider: sign in with a device code in your browser, and see your rolling and weekly usage directly in Mixdog.

MiMo (Xiaomi) sign-in is available under Settings → Developer options, alongside Cursor and Antigravity (off by default).

A new "Instruction files" setting under Settings → General can automatically include AGENTS.md / CLAUDE.md rules in new sessions, from your home folders (~/.codex and ~/.claude) and the project folder. Choose AGENTS.md, CLAUDE.md, All, or Off. It is off by default; because these files are trusted as instructions, only enable it for repositories you trust.

Daybreak Blue is now a per-route switch under "Auto reasoning" on the models that support it, based on the provider's model list. The separate Blue model is retired, and existing routes move to a supported model with Blue turned on.

- The Auto reasoning judge v6 installs automatically after updating. It is EmbeddingGemma 2 fine-tuned solely for judging reasoning effort, and it judges both requests and agent tool steps. On the same 12,029 held-out items it is more accurate than Jev 1.13 (exact level 78.5% vs 72.7%; two or more levels off 0.6% vs 1.4%), and it decides in about 115 ms on your PC. Details: `docs/auto-reasoning-effort.md`

Auto reasoning now appears as "Auto" wherever a model and effort are shown, including the agents sidebar, Workflows, schedules, and webhooks. The working status line shows the effort that Auto actually chose, translated into your language (for example "Thinking (medium)").

The composer island above the message input is redesigned. Goals show a state icon, per-task progress pips, and "In progress"; agents, shells, and changed files are counted separately with their own icons; and agents waiting for your approval show "Waiting for approval" and a "Needs you" count instead of appearing busy. Clicking an agent opens its session, agent elapsed time now counts from the current turn instead of from creation, and the island stays briefly after work finishes instead of flickering away. The Agents pane also marks agents waiting for approval.

Your own messages no longer show "from <this PC>"; device attribution appears only on messages sent from other devices.

The Usage window opens immediately with your last figures while the latest numbers refresh in the background.

macOS auto-update now works. Earlier releases were missing the macOS update feed, so Mac installs could not update themselves.

The "what's new" notice after updating is no longer lost if it fails to appear; it is marked as seen only once it has actually been shown.

The Connection settings page no longer jumps when it opens, and the "Use" button on the phone's "Reset credits" is more compact.

Tool paths like /C:/… are now accepted, edit accepts old_str / new_str as aliases, several paths joined in one string are understood (inside the project), and error messages are clearer.

Long-running background shell commands, such as dev servers, no longer block new shell commands.

Temporary files are now cleaned up more safely, and new tasks are no longer reported as failed when only the automatic title fails to save.

Mixdog Desktop now runs on Linux as an AppImage or a .deb package, for x86_64 and arm64 (glibc 2.31 or newer (Ubuntu 20.04, Debian 11 and later)), and updates itself automatically. On GNOME with Wayland, Computer Use captures screenshots through the bundled Mixdog GNOME Shell extension, shows its "in use" indicator in the shell without taking focus from the window being controlled, and stops with Ctrl+Alt+Esc; after the extension is first installed, sign out and back in once.

Mixdog for Android 0.1.12 has new pairing: on your PC, open Settings > Connection > Phone, scan the QR code to install the app, then enter the 6-digit code shown there in the app and allow it on your PC. It also fixes the message box being hidden behind the keyboard on Android 15.

## v1.1.0 - 2026-10-11

- A new Phone option in Settings > Connection displays a QR code to install the Mixdog mobile app (available on iPhone via TestFlight beta and on Android as an APK). Once installed, pairing completes by entering a 6-digit code in the mobile app and approving it on your desktop PC.

- The web app can now receive push notifications from all paired PCs, keeping you notified of completed tasks and model responses across your computers.

- Markdown files now feature Preview, Rich, and Source views, an outline, and a side-by-side preview. The rich editor writes edits directly back to the file while preserving frontmatter, line endings, and untouched formatting, with conflict detection and held backups if the file changes on disk.

- Registered projects in the session sidebar are now organized into folders above Recent sessions, showing their latest conversations and a button to start a new task in that project. Categories and folders can be reordered by dragging, and right-click context menus let you quickly open, rename, favorite, archive, delete, or inherit sessions.

- Desktop app support returns for Intel-based Macs (macOS x64) without ONNX dependencies. Memory retains lexical search, while local semantic search and auto reasoning are omitted on Intel hardware.

- Save As downloads no longer overwrite or delete the existing file if the download fails. Removing a paired device from Settings > Connection retries automatically when reconnecting if the relay was temporarily unavailable.

- File reading and editing align cache reuse and range indexes with verified exact file versions. Deleting or patching large files over 8 MiB in apply_patch bounds memory use instead of reading files whole, and local HTML preview permissions stay strictly scoped to their originating session.

- Configuration settings keep their defaults in code rather than on disk: configuration files now store only your custom changes, allowing untouched settings to seamlessly adopt updated defaults in new versions.

- Background resource usage is significantly reduced when idle, with fewer daemon reviews, debounced file watching during search, and cached daily rollups for usage statistics.

- Shift+Enter reliably inserts a line break in the message composer even after shifted characters, and single-line Enter commits no longer trigger prematurely while composing Korean text in an IME.

- Translation quality pass across all 11 supported languages, correcting interface labels and updating localized dialogs.

## v1.0.12 - 2026-10-10

- The changelog in Settings > About lists the installed version's notes;
  in v1.0.11 it still ended at v1.0.10, on the desktop app and the remote
  web page alike.

- The changelog is available in every app language, and after an update
  the app shows what is new in that version once.

- Auto reasoning is on by default on supported models: each message and
  each tool step gets the reasoning effort it needs. Its model downloads in
  the background on first use instead of at startup, and the Built-in card
  shows the model and what it is based on.

- File links in a conversation open beside it in the side panel as tabs. A
  new link replaces the preview tab, so links no longer pile up tabs; a tab
  is kept once you double-click it, choose Keep open, or edit the file. At
  most eight file tabs stay open. Settings > General > Link preview turns
  this off.

- CSV and TSV files open as an editable table: copy and paste cells, add or
  remove rows and columns, save with Ctrl+S, and undo or redo with Ctrl+Z
  and Ctrl+Y.

- PDF and Office files (Word, PowerPoint, Excel) preview in the side panel.
  Office pages reopen instantly, and a link starts converting its document
  as soon as you point at it.

- Conversations can be starred: favorites stay at the top of the session
  list, and the star appears when you hover a row.

- Search finds text across past conversations. A deleted conversation
  leaves no search results behind, whichever way it was removed.

- Scrolling up while a reply streams keeps your place instead of jumping
  back to the bottom.

- GitHub actions in a reply are grouped into one GitHub card, and the
  thinking indicator's loop no longer jumps when it restarts.

- Provider accounts show their sign-in email, and connecting the same
  account again keeps its name and usage history instead of adding a new
  entry. The usage dialog no longer lists accounts that were disconnected.

- A prompt pulled back from the queue into the draft no longer reappears
  after a restart, and reopening the app quickly keeps the conversation
  editable instead of opening it read-only.

- Translation fixes: wrong labels such as Git in Italian, Models in
  Vietnamese and Effort in Chinese and Japanese now read correctly.

- On the phone web UI, Enter inserts a line break and the send button
  sends.

- Memory starts on Windows profiles whose user folder name is not plain
  ASCII.

- Security updates for the image-size and js-yaml dependencies
  (CVE-2025-71329, CVE-2026-84375).

## v1.0.11 - 2026-10-08

- The built-in browser shows pages again on Windows displays scaled above
  100%, instead of failing with "Browser display did not recover after the
  page changed" (#8). Pages also follow display scale changes, including
  tabs that were not on screen at the time.

- Word, PowerPoint and Excel files (.docx, .pptx, .xlsx, .xlsm) can be
  attached to messages and automations, and their text reaches every model.
  File types that cannot be attached now say so and insert the file path
  instead, and empty files or files that are not real PDFs are rejected with
  a clear message.

- PDFs and images from earlier in a conversation are still sent to the model
  after the app restarts. Models without native PDF support receive the
  PDF's text. Reading a PDF over 100 pages returns its first pages as text,
  and password-protected or invalid PDFs return a clear error instead of
  breaking later requests.

- Images and files returned by MCP tools reach the model as images and files
  instead of raw encoded text; unsupported or oversized media is described.

- Summaries made when a long conversation is compacted now include long
  messages and note attached images and files.

- Local text-only models keep the text of attached documents, and earlier
  images become a short note instead of stopping the conversation.

- Feedback, with optional screenshots, can be sent from Settings > About,
  and the changelog can be read there too.

- Recent conversation messages can be found by meaning in memory recall
  right after they are saved.

- Search results are reused only while they are still fresh (#7), and a
  file-list search after a content search returns file names instead of the
  earlier content (#9).

## v1.0.10 - 2026-10-08

- Custom API providers can be registered in Settings with provider-specific
  connection adapters.

- Remote connection QR codes appear only after the relay is ready, and stale
  pairing cards are cleared.

- OpenRouter rolling model aliases can be selected and saved for Main and
  agents. Latest aliases and stable models are no longer incorrectly hidden
  by catalog age, newer previews, or the model picker's family limits.

- Native patch initialization keeps its process alive while verification is
  pending, preventing an early exit when prewarming and verification overlap.

## v1.0.9 - 2026-10-07

- Common and project instructions reach every new conversation even when
  the Memory extension is not installed or is turned off; that switch now
  covers only the memory and recall tools. Saving an instruction no longer
  waits several seconds on the embedding model, instructions go in as
  written without internal ids, and they can total up to 32 KB.

- Signing in to GitHub from Settings, and every other feature that starts a
  terminal process, works again in the installed desktop app instead of
  failing with "posix_spawnp failed". A stale extra GitHub account stored by
  gh no longer makes a successful sign-in report "no account is signed in".

- Browser Use and Computer Use no longer ask for approval before their first
  call in a session, and `setup set_first_use_approval` is gone.

- The tool approval card matches the cards stacked above the input: the
  warning icon, title and tool share one line, the reason sits under it with
  only the command, path or URL being approved (no folder row or argument
  dump), and Deny sits quietly beside Allow.

- New models pick up their abilities from the provider catalogs instead of
  waiting for a release: mid-conversation effort changes on the ChatGPT
  route, Fast mode and cache settings on the OpenAI API route, Fast mode on
  Claude, and reasoning effort on xAI. GPT-6.1 Sol and Claude Sonnet 5.5 are
  covered now, and the Fast toggle no longer appears on Claude models that
  cannot use it.

- Claude Sonnet 5.5 shows its notes between tool calls again, and Claude
  Fable and Mythos models can use hosted web search.

- The client version each provider expects is remembered between runs, so a
  restart or an offline start no longer falls back to an old built-in value.

- More "conversation too long" errors from GLM, Kimi, Qwen, MiniMax, xAI and
  other backends now trigger compaction instead of ending the turn, and a
  mid-reply Claude overload follows the same retry and fallback rules as one
  at the start of a reply.

- Notices and errors no longer stack above the input: slash-command
  confirmations and microphone, attachment and command failures appear as
  notifications, and voice download progress shows only on its Settings card.
  Every error now reads the same way, without a boxed card, and local model
  downloads show a full-width progress bar under their row.

## v1.0.8 - 2026-10-05

- The macOS app is signed with a Developer ID certificate and notarized by
  Apple, so a downloaded copy opens without a Gatekeeper warning and macOS
  auto-update can install new versions. Microphone and AppleScript prompts
  now explain what Mixdog uses them for.

## v1.0.7 - 2026-10-04

- Browser Use on the phone streams the desktop page live instead of
  refreshing snapshots, and takes the same mouse, touch, wheel, keyboard and
  IME input as the desktop pane. When an agent hands the page over (for
  example a CAPTCHA), the phone opens it too.

- Tool activity in the transcript is easier to scan: each row opens with a
  short verb, reads and searches show per-file results, listings show file
  rows, commands sit in their own box, `git diff` output renders as a diff,
  and a page the browser visited gets a card that reopens it in the pane.

- Finished-turn notifications arrive sooner, show plain text instead of raw
  Markdown, end on a whole sentence, and are no longer held back by
  long-running background shell jobs.

- Recently used sessions open faster after a restart and when revisited.

- The setup tool can manage OAuth accounts, developer options, activity rail
  pins and a plugin's MCP server, and requests from split-pane sessions are
  handled. A provider's own auto-clear window now overrides the global one.

- The Git tool turns on wherever `git` is installed, without installing an
  extension. Schedules and webhooks always deliver to the app session.

- The app interface stays at 100% scale, settings saved in another window or
  terminal apply right away, and borders, icons, list spacing and dialog
  entrances are more consistent.

## v1.0.6 - 2026-10-03

- Phone push notifications stay quiet while the app is on screen, follow a
  subscription the browser renews on its own, and the toggle turns off when
  notifications are blocked in system settings.

- The phone app no longer stays on its loading screen when it returns after
  a relay update; it finishes loading as soon as the desktop reconnects, and
  a fast first launch no longer skips installing the app's service worker.

- On Android, the back gesture closes the open panel or menu without
  flashing the navigation bar.

- Workspace tabs, the side panel header and the Studio cleanup button are
  more compact, and the selected tab stands out more clearly.

- Usage labels are shorter, the allowance to reset reads per hour once less
  than a day is left and never exceeds what remains, and translations are
  polished across languages.

## v1.0.5 - 2026-10-03

- The desktop app can raise an OS notification, with a sound, when a turn
  ends with its final answer, and the notification leads back to that
  session.

- The Office tools author docx, xlsx and pdf documents from HTML through one
  shared browser session.

- Usage shows quota value estimates and per-session totals.

- Browser and Computer Use hosts are more robust: frame transforms, visual
  privacy, tiled screenshots and recovery after failures.

- The PowerShell syntax check no longer mistakes verb-hyphen fragments inside
  paths for cmdlets.

- `adm-zip` is updated to 0.6.1 for CVE-2026-102282.

## v1.0.4 - 2026-10-01

- Model pickers refresh as soon as a provider changes. Browser-based OAuth
  sign-ins (OpenAI, Grok, Cursor, Antigravity) and account switches now
  reload the picker immediately instead of after a restart, and a provider
  connected, removed or switched in one window also refreshes every other
  desktop window and paired phone.

- Closing the window no longer asks what to do. Settings offer a "When
  closing the window" choice between hiding to the tray (the default) and
  quitting completely, the tray icon is available from launch, and the
  in-app quit confirmation prompt is gone.

- Workflow agent rows read the same way everywhere: a row without a pinned
  model, including Web Search, shows "Default", and agent names and model
  labels stay untranslated. Unselected workspace tabs rest on a faint plate
  instead of thin dividers.

- The Goal tool and goal-management skill describe Goals as a task list for
  approved work carried across turns, and exclude recurring schedules and
  objectives that wait weeks on external events.

## v1.0.3 - 2026-10-01

- Media generation records one usage row per image or video job with the
  tokens, images, seconds and cost the provider reported, so Gemini,
  Antigravity, Codex and xAI media appear in usage and cost totals alongside
  text models. Media rates come from the published price catalog.

- Computer Use Stop and Resume recover cleanly after a failed cleanup: idle
  workers are retired instead of timing out, and a user's Stop or Resume
  clears the stale "input not confirmed released" state.

- Sessions waiting on background shell jobs show as waiting rather than idle,
  and the shell job indicator no longer shows a previous owner's jobs or loses
  updates that arrive during a poll. Session and agent lists skip redundant
  redraws when nothing changed. The usage chart, rail pages, workspace tabs,
  extension lists and dialogs have refreshed styling.

- Identical concurrent grep and read scans share one native scan, cached
  results are invalidated per path after edits, and a canceled patch stops
  before writing further files. Code graph search matches Windows paths
  regardless of case, separators, verbatim (`\\?\`) and UNC prefixes. A
  failing pre-tool hook now blocks the tool instead of letting it run.

- The browser skill keeps pages in the background unless the page itself is
  the deliverable or the user must act on it. Desktop development
  (`npm run dev`) and the Windows direct E2E scripts run in a fresh isolated
  profile on CDP port `9342`.

## v1.0.2 - 2026-10-01

- Transcript copy buttons can write to the clipboard from the trusted desktop
  window. Response text, code blocks, tool output and per-file diffs have
  regression coverage for exact copied text, retries and changing content;
  clipboard reads and permissions for other windows remain blocked.

- Model and effort commands open the current conversation's model picker, and
  disabled agents keep the model selected for them. The starter tutorial
  explains the Maintainer model recommendation, and diagnostics now cover
  local providers, built-in features, voice and missing or invalid plugins.

- Windows file links handle encoded separators and paths with spaces or
  Korean text. A file mention that failed its initial lookup can be clicked
  to retry. Studio's Select all includes every item in the tab, not only
  the pages already loaded.

- Computer Use keeps capture references aligned with accessibility re-reads,
  safely rebinds rebuilt controls only when their observed identity matches,
  and waits while the input desktop is locked instead of treating the lock as
  an observer failure.

- Workspace tabs and the starter tutorial have clearer styling, the session
  sidebar starts open, and tool groups no longer show the aggregate failure
  badge. Project instruction text is no longer added to the system prompt's
  environment block. Published packages exclude nested development tests.

## v1.0.1 - 2026-09-30

- The desktop app on Windows 11 now sits in a Mica window frame with a calmer,
  monochrome shell: popups and panels separate by shadow instead of borders,
  selections no longer turn blue, and the accent is kept for live state. Text
  follows one type scale (12px captions up to 20px page titles and headline
  figures), the selected tab is a raised card, destructive buttons stay
  neutral until hovered, and the usage and context charts share one palette.

- Closing the window asks once whether to keep Mixdog running in the tray or
  quit completely, and remembers the answer. Quitting while an agent is still
  working asks every time.

- Subscription usage shows each model's share as a stacked area under the
  total line, and its hover card only follows the pointer inside the chart.

- The conversation stays attached to its latest message when a card changes
  height during a scroll. SVG files an agent writes appear as image results
  and open in the system viewer, and agents hand over visual work such as
  SVGs or HTML pages as saved files instead of pasting their source.

## v1.0.0 - 2026-09-30

- Memory can no longer be knocked out by a runtime rebuild. A rebuilt memory
  runtime is published under a new release tag instead of replacing files
  that installed apps verify, a new runtime installs beside the one in use
  instead of deleting it while PostgreSQL still runs from it, and two
  processes installing at once no longer delete each other's download. Local
  development deploys refuse to run from a branch behind its upstream.

- Tool cards no longer mark finished calls as failed. A command whose output
  contains a `status:` line, a `git diff --quiet` or `git grep` that reports a
  difference or no match, a code_graph lookup that finds no symbol, and paging
  stored tidy results now show as completed; a git command that exits non-zero
  shows as an exit, like the shell; and a browser or computer command stopped
  because the user took control shows as cancelled.

- Fewer tool calls fail on a first-attempt argument slip: the git tool adds a
  missing leading `git`, read declares its 10-target limit in its schema, and
  a Goal full of completed tasks says how to make room for new ones. Failure
  logs now record read targets and the full size of path batches.

- Requests are priced at the tier they were actually sent with: Fast and
  Priority requests use their published rates, a Fast request retried as
  standard is billed as standard, and Cursor Fast variants bill as their
  catalog model. Toggling Fast updates the status line immediately.

- Excel data validation rules are checked before a workbook is created, so an
  unknown rule type or a missing bound fails up front on both backends. The
  live-activity glint is a shorter, paler band, and tool summary names use the
  medium weight.

## v0.9.175 - 2026-09-29

- Claude agents now keep their conversation cache for 5 minutes instead of an
  hour. When an agent's next request comes after that cache has expired —
  after a long build or test, or when a finished agent is picked up again — it
  compacts its conversation first, so the request rewrites the compacted
  conversation instead of everything the agent had accumulated. In a replay of
  recent Claude agent usage this cut agent token cost by about a quarter. Lead
  sessions are unchanged.

- Many sessions running side by side no longer slow each other down. Pending
  messages are kept per session, session summaries and gateway usage are
  appended instead of rewritten, stored transcripts are parsed off the main
  loop, and a failing memory cycle backs off instead of retrying in a tight
  loop. When the daemon exits it records why. The separate multi-process
  session host is gone; sessions run in the daemon itself.

- Subscription usage recorded before an account switch now counts for the
  account that was in use when recording began. Grok, Claude and Cursor
  report their current client versions instead of fixed ones.

- The desktop app no longer shows a blank session when the daemon delivers
  its contents just after replying to the open request. The packaged app's
  boot script is allowed by the content security policy, and project-root
  checks, relay dispatch errors and browser session restore are fixed.

- Workbooks and documents edited without Office: clearing an empty cell no
  longer deletes the cell after it, deleting a comment finds comments with
  author formatting, parts linked by absolute paths resolve, and text that
  looks like a replacement pattern is inserted literally.

- Downloaded runtimes (PostgreSQL, pgvector, fonts, FFmpeg) are checked
  against pinned checksums before use. Native tools fix a window-id parse
  that could split a multi-byte character, a time calculation that could
  overflow, and a snapshot replace that could leave a partial file.

## v0.9.174 - 2026-09-29

- The usage dialog now answers a second question: how a subscription's quota
  was used up. Next to token usage, a Subscription usage tab follows each
  provider's own limit windows — Codex, Claude, Grok, Cursor, Antigravity and
  OpenCode Go — as they rise and reset, with the models that moved the meter
  and the history of earlier windows. Mixdog records every quota reading it
  measures; a rise with no Mixdog request behind it shows as use from outside
  Mixdog, such as the provider's web app. A provider meter in the usage
  flyout opens its own subscription directly.

- `/doctor` works in the desktop app too, as a dialog (also under Settings →
  System → Doctor). It runs the same read-only health checks as the TUI, all
  at once with a deadline per check so one stalled check cannot hide the
  others, and every warning or failure says how to fix it.

- New PowerPoint decks are designed in HTML. The model lays each slide out in
  HTML and CSS, a local Chrome or Edge renders it, and `author` turns what the
  browser drew into native, editable PowerPoint objects: text boxes that keep
  the browser's line breaks, shapes, lines, tables, charts and pictures.
  Korean text breaks where a reader expects, a geometry check refuses slides
  whose declared alignments the browser cannot confirm, and `render` shows
  each HTML page beside its PowerPoint render. The script route stays for
  decks that want the kit's measured devices, or when no local browser exists.

- Inserting or deleting rows and columns in a workbook without Excel now
  rewrites everything that names those cells, the way Excel does: formulas on
  every sheet, defined names and print areas, conditional formats,
  validations, chart series, pivot sources, filters, links, merges, tables and
  drawings. The cells used to move while their references stayed put, so a
  report total kept summing the old range and read 72,200 where Excel read
  74,700. An edit whose references cannot be rewritten is refused, with the
  list, before anything changes.

- PDFs and composed spreadsheet bands keep Korean dates, times, fractions and
  amounts on one line. "10월 14일", "14시 30분", "3분의 1", "12만 6천 원" and
  "24억 원" no longer break in the middle, which had split a decision date or
  a saving across two lines.

- Office files come out the same whether Microsoft Office or the built-in
  portable writer produced them. A long side-by-side comparison of both
  aligned Word spacing, compatibility mode and tables; Excel autofit, indents,
  borders, print setup and preset charts; PowerPoint Korean wrapping, East
  Asian fonts, footers, cover crops, shadows and transparency; and PDF
  alignment and table widths. Review checks report the same issues on both
  backends, Excel charts can read another sheet's range, and `set_chart_data`
  keeps a chart's links and series names.

- Computer Use runs on macOS and Linux. Desktop builds for those systems
  bundle a native backend that speaks the Windows host's protocol and enforces
  the same action lists and limits. A sequence can now also act on several
  elements of one observation: each later step re-proves its element against
  the live accessibility tree, and the chain stops at a window switch, a
  failure, or a disabled or off-screen element.

- The phone app opens and reconnects faster and moves far less data. The
  transcript shows right after the first sync, short reconnects resume as
  deltas instead of a full resync, the phone mirrors only the tab it shows,
  the collapsed turn review reads file names and counts without patch text,
  and slow project searches no longer hold up other calls. A phone app kept
  open checks for a new deploy when it comes back to the foreground, and
  adopts one off screen even mid-turn.

- The daemon uses less memory and stalls less: sessions save only what
  changed, the usage ledger works off the main thread, file locks and git
  calls no longer block it, and long transcripts page in 1 MB steps. Desktop
  and phone render streaming Markdown and touch scrolling with fewer layouts,
  and the web app's transcript no longer jitters while rows are measured.

- Voice input shows that it is preparing until capture really starts, warms
  up transcription while you speak, and transcribes faster without blocking
  the app.

- Tool results cost the model fewer tokens. `read` returns its rows without
  line numbers — the TUI and desktop still draw the gutter — for about 16%
  fewer tokens on recorded sessions; shell and task notices are shorter; and
  edits report paths relative to the working directory.

- Compaction carries less stale material in large context windows. The
  verbatim conversation and the recent tool history kept through a Compact are
  capped at 20,000 tokens instead of growing with the window. A browser
  snapshot or desktop observation that a later one of the same page or window
  replaced keeps only its outcome and a pointer to the archived original, and
  older replies drop their opaque provider replay while keeping their tool
  calls and results.

- A provider that is briefly unavailable no longer ends the turn the moment
  its own retries run out. While nothing has reached the screen, the turn
  waits through a few more recovery cycles, from 15 seconds up to a minute,
  and follows a server's own Retry-After. When a stream is cut while a tool
  call's arguments are still arriving, that call is not run, and the model is
  told to split the content across smaller calls instead of resending it
  whole.

- Cursor and Antigravity (Gemini) OAuth are separate switches under Settings →
  Developer, and each turns on only after you confirm the risk of account
  restrictions that comes with using that provider through OAuth. The
  `MIXDOG_DEV_PROVIDERS` environment variable no longer turns them on.

- The conversation no longer jumps when the bars above the composer open or
  close: they slide over the motion instead of shifting the transcript by
  their full height at once, and opening a session no longer flashes a turn
  review count that disappears a moment later.

- Renaming a file or folder in the explorer keeps its open editor tabs on the
  new path. A file with unsaved edits is refused until it is saved, since its
  buffer belongs to the old path.

- Studio cleans up in bulk: the selected items, everything before a date,
  entries whose files are gone, or all of one kind. Settings → About lists a
  support address with Copy and Email buttons, and the built-in browser's
  Clear browsing data dialog has been removed.

- An automatic goal turn that calls no tool now waits instead of prompting
  again.

## v0.9.173 - 2026-09-22

- A restored queued message keeps the text the daemon confirmed. Restoring one
  publishes twice in the same breath — the local guess first, the daemon's
  answer a moment later — and both were stamped with the clock. When they
  landed in the same millisecond the prompt treated the second as the first and
  kept the guess, so an edited message could come back subtly wrong. The prompt
  now follows the text itself, not only the stamp.

- Jumping twice in one instant no longer loses the second jump. Two "go to this
  line" requests inside the same millisecond carried the same stamp, and the
  editor read only the stamp, so the second one was dropped and the cursor sat
  on the first line.

- A search that crashes no longer takes the whole search engine with it. The
  engine already knew how to answer one bad request with an error and keep
  serving, but the shipped build was compiled so that any crash killed the
  process instead — losing every other search in flight and the warm file
  index. It now survives, answers that one request with an error, and keeps
  its caches. If a crash does happen while files are being collected, the
  collected paths are still published rather than quietly disappearing from
  the answer.

- Apply and Delete on a local provider row sit on the same line. They differed
  by two pixels because the row mixed a taller input with a shorter button.

- Cleaning up code tells you when a tool is not the tool you think it is. If a
  formatter or linter with the same name is reachable on your machine but is
  not the one Mixdog runs, the report now names both, with versions — running
  that other binary says nothing about the result you were shown. A cleanup run
  also separates findings in files you have already touched from findings in
  files that are untouched in the repository, so applying fixes to a whole
  directory no longer rewrites files you never meant to change.

- Updating your installed app no longer stops because your antivirus removed a
  file the update discards anyway. Staging unpacked the whole installed app and
  deleted the part it was about to replace; one quarantined renderer asset was
  enough to abort the deploy.

## v0.9.172 - 2026-09-21

- A page no longer opens by announcing downloads it never made. Saved files
  belong to the session, but each page tracked what it had reported starting
  from zero, so every page opened afterwards greeted the caller with the whole
  backlog — a search page reporting a file another tab had saved minutes
  earlier. A new page starts already aware of what happened before it existed;
  a file saved while it is open still reaches it.

- The browser's own faults no longer read as the page's. A timed-out CDP call,
  a child frame that could not be attached, an interception that could not be
  answered — all of them were logged as page console errors, so a reply about a
  healthy site could open with `CDP Runtime.evaluate timed out` as if the site
  had logged it. They stay readable through `console`, marked `[browser]`, and
  no longer count among the errors a page is answerable for.

- A deadline reached behind an open dialog says so. An alert, confirm or prompt
  freezes the page's main thread, so the next call died on its timeout with
  nothing but the deadline — and the obvious retry timed out the same way. The
  error now names the dialog and its text, and says to answer it with
  `handle_dialog` before acting on the page again.

- A client-side route change is answered with the screen it produced, not the
  one the caller left. Single-page apps move the address with `history.pushState`
  and render the new view a moment later; no document loads, so the settle saw a
  quiet page and returned at once — and an `expect.url` was satisfied by the new
  address before anything was drawn. Clicking "Learn" on react.dev answered with
  the home page under the `/learn` address. When an action changes the address
  without a load, the reply now waits for the page to go quiet and a URL
  condition may not cut that short. Measured on the real-device harness:
  navigate, click and snapshot latencies are unchanged, because only same-
  document route changes take the extra wait.

- A WebSocket detail shows the upgrade request it actually sent. Only the
  address and the handshake response were recorded, so `network` answered with
  an empty request-header section — and a refused upgrade is usually explained
  by `Origin`, `Sec-WebSocket-Protocol` or a cookie. Credentials stay redacted.

- A click that opens a tab is no longer reported as a click that did nothing.
  A `target="_blank"` link leaves the current document untouched, so the reply
  answered "No observable change" and told the caller to look for a covering
  element — while the page it had just opened sat in `list_tabs` unmentioned.
  The reply now names the page that opened and how to act on it.

- `drag` takes snapshot-free targets like every other pointer action. Its two
  ends only accepted refs or raw coordinates, and the elements a page makes
  draggable — cards, list rows, drop zones — often carry no accessible name and
  therefore no ref, so moving one meant grounding a visual snapshot first even
  when the CSS selector was known. `target` and `dropTarget` now name the two
  ends, resolved together in one observation; refs and coordinates work as
  before, and both ends still have to be addressed the same way.

- A saved file is no longer announced as a failed request. An address that
  turns into a download cancels its own navigation, and Chromium reports that
  cancellation as `net::ERR_ABORTED`, so a reply that listed the download also
  listed it as a recent network failure. Cancelled requests — downloads, fetches
  the page abandoned, navigations replaced by another — stay readable through
  `network` but are no longer volunteered as faults of the page; a request that
  genuinely failed still is.

- A `brief` reply no longer turns one filled field into a page-wide change. It
  compares against the caller's previous observation, and when that observation
  was capped or filtered it had never reported the rest of the page — so every
  element outside it was listed as "changed or new". Filling three boxes on a
  form answered with fifteen elements, and typing one search word answered with
  a hundred and forty-six. The reply now keeps what the action demonstrably
  changed apart from what the earlier observation simply never covered, and says
  how much of the page that observation held. Nothing is omitted either way.

- Request headers in `network` are the ones that were actually sent. Chromium
  reports a provisional set first and adds language, encoding, client hints and
  cookies afterwards, so a request detail could show two headers and read as if
  the page never asked for Korean content. The later set is merged in;
  credentials are still named and never shown. Header names are case-insensitive
  and the two reports spell them differently, so the merge keeps one entry per
  header — the spelling and value that went on the wire — instead of listing
  `User-Agent` and `user-agent` as if the request carried both.

- Sites see Browser Use as the Chrome build that renders them. The agent string
  still carried the desktop app version and the Electron runtime, while the
  client hints the same pages received named Chromium alone; GitHub answered
  that contradiction with a sign-in wall on a public repository. The browser
  partition now presents the plain Chrome string — one less fingerprint, and
  fewer "unsupported browser" detours — and an emulated user agent still wins
  when a task asks for one.

- Pages that keep attaching frames can be observed again. Portals and news
  front pages open ad slots and widgets in bursts, and a snapshot that started
  mid-burst used to give up with "frame topology changed during observation" —
  reproducibly, on the first and second try. Observations have no side effects,
  so the collector now waits briefly for the burst to settle and reads again,
  up to a small ceiling, instead of handing the caller an error for a page that
  was merely busy. When a reading still fails, the reply now says the page is
  loaded and only the reading of it failed, so the next step is to observe
  again rather than abandon a page that is fine.

- A page reports only its own failures. Requests and console errors from the
  previous document stayed in the ledgers, so a snapshot of a healthy page could
  list aborted requests from the site visited before it, and `console` on a
  clean page could answer with the errors of the page before — both sending the
  reader after a fault that was not there. Loading a new document clears them;
  navigating inside the same document keeps them, because nothing reloaded.

- Browser Use display races are no longer failures. A capture that loses to a
  navigation or a window resize now answers with a resample marker instead of
  an error, because the pane was always going to ask again for whatever the
  page shows next. Ordinary browsing used to fill the app log with capture
  failures — seventeen in one harness run, none now — and a paired phone
  reported the same race as "could not connect to browser screen"; it now
  re-samples at the active cadence and reports only a display that genuinely
  stops making progress.

- Clear Browser Use browsing data. The browser pane has an eraser button that
  removes the cache, the data sites stored on this device, and cookies, each
  as its own decision: cache is preselected because losing it costs one slower
  reload, while cookies sign you out of every site and are never the default.
  Each scope is cleared on its own, so one failure is reported as a failure
  instead of disappearing behind the scopes that worked. Clearing cookies also
  rewrites the sealed file that carries session sign-ins across restarts, so a
  login you cleared does not come back the next time the app opens — and if
  that file cannot be rewritten, cookies are reported as not cleared rather
  than as done. Until now the shared partition grew on disk with no way to
  reclaim it.

- Browser Use `performance` metrics report the memory of the process painting
  the page, not just the JavaScript heap: a page whose images and layers hold
  the memory used to look small. The reading names the process, since one
  renderer can paint several pages of the same site.

- Browser Use domain policy covers peer connections. When an operator
  restricts the domains a page may reach, WebRTC no longer walks past the
  filter through STUN and TURN: peer connections are refused in the page and
  in every child frame. Without a domain policy nothing changes, and this
  remains containment for page code rather than a network boundary.

- Browser Use element screenshots. `snapshot mode=visual` accepts `ref` or
  `target` and returns that element as its own image. The box is measured in
  top-document CSS pixels — same-process frames fold their offset in on the
  page side, a cross-origin frame adds its session offset without the hit
  test that guards input, because a picture dispatches nothing and a frame
  under a CSS transform still deserves one — and the crop is scaled by the
  image-to-viewport ratio, so it holds
  on a zoomed or high-DPI display. An element taller or wider than the window
  is cut out of the document capture instead of the viewport, so a long table
  or article arrives whole rather than ending at the fold; only a page too
  large to capture falls back to the visible part, and says so. The image is
  inspection-only: it is never bound as coordinate grounding, because the ref
  remains the way to act on the element. `mode=semantic`, `fullPage` and
  `format=pdf` refuse a target rather than ignoring it.

- Browser Use input fidelity. `drag` now completes a page's own HTML5 drag:
  Chromium's drag interception hands over the payload the page started and
  the gesture finishes as `dragEnter`/`dragOver`/`drop`, which is what a
  kanban card, a sortable list or a file drop zone actually listens for;
  pages that only track mouse events keep the previous path. `type` sends a
  real key event per character instead of inserting the whole string, so
  keystroke-driven autocomplete and combo boxes react, while characters
  outside the US layout (Korean, emoji) are still inserted as text. `press`
  sends the US key codes for punctuation (`.` was Delete, `-` was Insert),
  keeps a shortcut from typing a character, and no longer infers Shift from a
  capital letter, which had turned `Control+A` into `Control+Shift+A`.
  `upload` drops files on an element that never opens a file chooser, with a
  guard that neutralizes an unhandled drop — otherwise the browser navigates
  the page to the dropped file — and reports plainly when nothing accepted it.

- Browser Use observation fidelity. `scroll text=` searches frames and shadow
  roots like `read` and `expect` do, picks one match across them, and no
  longer scrolls to a collapsed element. `expect.text` normalizes spaces
  within a line but keeps line breaks, so indented markup matches while two
  separate blocks never merge into one sentence. Console diagnostics keep
  what a page logged: object arguments arrive as a readable preview instead
  of an empty message, entries name the script and the line a reader would
  open, and an uncaught bare `throw` carries its location. Snapshots mark
  `aria-hidden`, a failed native `select` lists the options it did find, and
  `aria-labelledby` resolves inside a shadow root.

- Browser Use counts the diagnostics it could not fit. A page report shows the
  three newest console errors and network failures, which read as the whole
  story: twelve failures arrived as three. The report now names the total and
  points at `console` or `network` whenever the list is capped.

- Browser Use admits when a page excerpt stops early. The visible text in a
  snapshot is capped, and the report said only "condensed", so a long article
  read as if the excerpt were the whole page. Both snapshot paths — the
  accessibility capture and the DOM fallback — now mark a clipped excerpt, and
  the report names how much it carries and says the page holds more.

- Attachments report the size of the image they actually produced. Fitting an
  image to a vision patch budget trims the edges one at a time, which can ask
  for a box the picture does not fill; the rendition then came out smaller
  than the size reported beside it, and coordinates mapped through that size
  were off. The resize now reports the dimensions of the produced image.

- Browser Use says where a page script failed. `evaluate` kept only the first
  line of the browser's error, so a script of several lines reported
  `TypeError: ...` with nothing to locate it. The failure now carries the
  innermost stack frame with it, and the integration harness pins the position
  a throw on a later line reports.

- Browser Use names a PDF instead of reporting an empty page. Opening a link
  to a PDF committed the address, but the guest has no viewer for it, so the
  snapshot showed an untitled page with no text and console noise about a
  blocked viewer stylesheet — nothing that says what happened. The page report
  now states that the document is a PDF this browser cannot display and that
  the file has to be read from its URL, and the failures Chromium's own
  bundled components raise for their `chrome-extension://` resources no longer
  appear as the page's console or network errors. The integration harness
  covers the navigation, the quiet report, and a later snapshot of the page.

- Browser Use stops bouncing `close_tab` off the visible tab. `list_tabs`
  prints the visible page with an ordinary page id, so aiming `close_tab` at
  it was answered with `unknown background tab "p12"; call list_tabs` — the
  listing that handed the id out. The refusal now says the page belongs to
  the browser panel and points at navigating it elsewhere or `hide`, and
  unrelated names still report an unknown background tab.

- Browser Use says what a leave confirmation actually did. A page that guards
  unsaved work stopped a navigation with a `beforeunload` dialog, and the
  reply asked for `handle_dialog` — but Chromium answers that confirmation
  itself, so the call always came back "no JavaScript dialog is currently
  open" while repeating the navigation repeated the same instruction. The
  reply now states that the navigation was abandoned and the page stayed,
  that there is nothing left to answer, and that the work the page holds has
  to be finished or discarded first; the integration harness holds the whole
  sequence, including the navigation going through once the guard is gone.

- Browser Use locale emulation reaches the server. `emulate locale` set
  `navigator.language` alone, so the page kept asking for the old language
  and sites negotiated content the emulation contradicted; it now carries the
  locale as `Accept-Language` too, and clearing it restores the browser's own
  negotiation.

## v0.9.171 - 2026-09-18

- Release recovery: the staged production relay artifact is keyed to the run
  alone (`production-relay-<run_id>`) and uploads with `overwrite: true`. The
  name carried the run attempt, but a partial re-run preserves the successful
  `stage-production-web-relay` job while re-running
  `deploy-production-web-relay` as a dependent of the failed job, so the
  attempt-scoped artifact never existed and the deploy died on "Artifact not
  found" before it could reach production. That is exactly how v0.9.170
  published its GitHub release and npm package without deploying the web
  relay. `overwrite: true` keeps a full re-run, where the stage job does
  execute again, from colliding with the earlier attempt's artifact, and the
  release gate asserts both the name and the overwrite.

## v0.9.170 - 2026-09-17

- System prompt consolidation. Every rule now has one owner: the shared
  layer (`rules/shared/*.md`) is tool policy only and opens with
  `# Tool Calls` (batching first; `05-parallel-calls.md`), the Lead role is
  one file (`rules/lead/LEAD.md`: user communication, agent briefing and
  completion notifications behind `<!-- tools: agent -->`, tone), and the
  common agent contract is one file (`rules/agent/AGENT.md`: chain of
  command, no self-verification, English, handoff shape). `00-general.md`,
  `02-persona.md`, `lead-brief.md`, `00-core.md`, `00-common.md` and
  `75-goal.md` are gone — their surviving sentences moved to the file that
  owns them, and sentences a tool description already states (`load_tool`,
  `Skill`, `goal`, `memory` approval, `task wait`, `code_graph` outline,
  read call shape, Git routing, browser/computer routing) are stated there
  only. Precedence is per role: the user's latest explicit request for Lead,
  Lead's latest brief for agents. Lead's preamble rule now carries its
  reason (the user sees only your text) and asks for one line, not a word
  count; the briefing rule says an agent never sees the conversation, that
  findings are synthesized into paths, lines and the exact change ("based
  on your findings" never), and that an agent's result is never predicted.
  Destructive-action rules that were spread over four sections sit in one
  `# Destructive Actions` section. Role files (`agents/*/AGENT.md`) drop the
  blocker/handoff sentences the contract owns; `maintainer` gains name and
  description frontmatter. Output styles: the `## Depth` heading replaces
  `## Depth Variation`, and progress-report wording lives in the Lead rules
  only. The Default workflow no longer carries the reviewer-fallback
  paragraph; it rides with the orchestration-mode block that delegating
  modes inject. Tool descriptions: `edit` no longer points at `apply_patch`
  on surfaces that filtered it out, `shell` says Git goes to `git` only when
  that tool is present, `read`/`grep` drop byte caps the runtime reports
  anyway, `code_graph` states that `symbols` is the outline. Providers that
  deliver the round reminder themselves (`anthropic-oauth` as a turn-scoped
  system message, `cursor` through its relay) declare `deliversRoundReminder`
  so the runtime channel stays silent — Cursor sessions no longer receive the
  batching reminder twice per round. The batching nudge's provenance check
  normalizes path separators and accepts a directory shown as a prefix of a
  deeper path in the previous result, so a follow-up call on a path the last
  result revealed no longer reads as an unrelated single call (two
  false positives per session before). The `setup` route schema states
  `contextPercent` as bounded integer (the executor still requires a
  multiple of 10) so Gemini stops receiving an unrepresentable-enum
  placeholder. Stale test expectations left behind by the batching commit
  are brought current, and two timing/environment-dependent tests are made
  deterministic. Project skill `gamerscroll-article` is scoped to its
  project.
- GitHub releases now carry the version's CHANGELOG.md section as their
  notes, followed by the compare link; the draft previously relied on
  GitHub's generated notes, which list merged PRs only and left the page
  with a bare `Full Changelog` link because Deploy commits straight to main.
- Tool batching: after three single-call rounds of one tool in a row whose
  calls did not need each other (no argument taken from the previous result,
  no step ordered behind a mutation; a different tool restarts the streak, so
  read → shell → apply_patch is never reported; task waits, Computer Use,
  browser steps and schema/skill loads never count), or one
  round of same-tool calls that differ only in an array field, the runtime appends one
  short `<system-reminder>` naming the array arguments on the session's tool
  surface; it repeats whenever the pattern recurs and only a batched round
  clears it (traced as `batching_nudge`). A single-file `read` right after
  a grep/code_graph/glob/find round that located several files gets the
  located set back in the shape one `read` call takes
  (`[{file_path, offset, limit}, …]`; one read per file in the same response
  on providers whose read schema takes path strings only), traced as
  `located_sites`: a recorded Gemini 3.8 Flash session located files with
  grep 13 times and still read them one window at a time (63 reads, 20 of
  28 files read twice or more). The `read` and `grep` descriptions now say
  what the batch is — every file and range you will touch, before editing,
  in one call — and the windowed-read footer asks for one wider read instead
  of the next window. The shared rules now state the order of work on files
  once (`# Tool Calls`: enumerate only when the scope is unknown → locate
  every site → one read stage of `{file_path, offset, limit}` windows, ≤10 per
  call → every edit in one response → one verification) and drop the
  sentences that used to say parts of it in three places; the `read`,
  `grep`, `edit`, `apply_patch` and `code_graph` descriptions shrink to that
  contract (code_graph from ~150 to ~90 words), and a windowed read's
  smart-cap marker names the located-window form; a further pass trims
  parameter prose that repeated the rules or internal detail (`Skill`,
  `find`, `cwd`, `git`, `code_graph.mode`, `grep.path`/`text`,
  `include_noise`, shell's PowerShell cheat and `timeout_ms`) — the lead
  tool surface drops from 13.4 KB to 12.7 KB. Eight-task GPT-5.6 runs before
  and after stay at 8/8 with the same round, time and cost envelope; the
  one regression found on the way (a backup round for read-only inputs and
  `git log` surveys after two guarding clauses were cut) is restored. The
  backup rule now says where the copy goes — the same response as the first
  inspection, never a round of its own — because "inside the first inspection
  call" made GPT-5.6 open 2.8 backup-only rounds per eight-task run when the
  first inspection was a `read` or `git` call; with the wording fixed it
  opened none and batched every backup with that inspection. The serial
  reminder no longer treats an array inside a single call as a batch: a
  recorded Gemini 3.8 Flash review ran fifteen one-call rounds, alternating
  one- and two-command `git` calls, and never earned it because every array
  round reset the streak. The provenance check also remembers six rounds
  instead of two, so a file list from `git diff --name-only` walked one item
  per round no longer passes each item off as something the previous diff
  revealed. Two more runtime
  reminders: `late_locating` (a search after a read that took nothing from
  it) and `located_sites` handing over one window per located site —
  code_graph `(Lstart-end)` rows included — split into several read calls
  past ten. Route policy files
  (`rules/routes/*.md`) now also declare a one-line `turn-reminder:` (read
  once in the user turn's trailing `<system-reminder>` block, before the
  turn's first response) and a one-line `round-reminder:` next to their
  static rules; the agent loop resolves the latter per provider/model and it
  reaches the model after every tool round — as Anthropic's turn-scoped
  system message (`clear_at: next_user_message`) on `anthropic-oauth`, the
  pattern Anthropic documents for Claude Fable 5.1, or as a runtime
  `<system-reminder>` after single-call rounds elsewhere (`per_round`). The
  Fable 5.1 reminder moves from a hard-coded provider constant to the
  route files; histories recorded under the earlier sentence replay it
  byte-for-byte. One file, `routes/common.md`, carries the batching
  reminders for every route (an unrestricted file is the base; a file naming
  `models:` or `providers:` adds to that line for its routes rather than
  replacing it) —
  Gemini goes one call per round once tool results arrive, Grok
  batches calls but never used array arguments: its flattened tool schemas
  kept only the scalar branch of every one-or-many field
  (`read.file_path`, `grep.pattern`, `git.command`, …). The Grok flattening
  now keeps the array branch of such fields (one value travels as a
  one-element array) and says so in the field description, so the batching
  contract holds on that provider too. The shared rules gain a
  `# Parallel Tool Calls` section that states the contract plainly (recorded
  Gemini 3.8 Flash sessions issued one call per round in 105/105 rounds;
  with the section in place a headless run batched four files and git in
  one response). Provider/model-bound rules load from `rules/routes/*.md`
  through `providers:` / `models:` frontmatter and render after the shared
  rules in BP1.
  `MIXDOG_ANTIGRAVITY_DUMP_DIR=<dir>` writes every Antigravity request body
  (contents, tools, config; never headers or tokens) for wire inspection,
  the Gemini counterpart of `MIXDOG_OAI_WS_DUMP_DIR`; `mixdog exec` also
  passes `MIXDOG_XAI_CACHE_TRACE` and `MIXDOG_XAI_RESPONSES_CACHE_SCOPE`
  through for xAI cache probes.
- xAI Responses requests no longer send a per-session `prompt_cache_key` by
  default (`MIXDOG_XAI_RESPONSES_CACHE_SCOPE` now defaults to `none`, Grok
  Build's literal body): the session key split the service cache into lanes
  and measured two cold rounds per run against one, and no cross-session
  prefix reuse. `session` and `prefix` remain selectable.
  `MIXDOG_ANTIGRAVITY_FC_MODE=AUTO|ANY|VALIDATED` overrides the Antigravity
  function-calling mode for A/B runs, and
  `benchmarks/terminal-bench-2.1/analysis/tool-batching-by-model.mjs` reports
  multi-call and array-argument rates per model from `agent-trace.jsonl`.
- `mixdog exec` binds the OAuth account selected in the host's
  provider-accounts pool (the credential sign-in writes today), falling back to
  the single legacy credential file; previously only the legacy file or an
  explicit `*_CREDENTIALS_PATH` was accepted, so pool-only hosts failed with
  "credentials are unavailable". `mixdog exec` also no longer sits 2–4 minutes
  past its answer before emitting `result`: the pristine-root removal retried
  on Windows for the full rmSync budget (50 linear retries ≈ 128s, twice when
  the postmaster path re-ran it) while the usage ledger's SQLite handle and a
  winding-down memory daemon's `pg.log` were still open. The ledger is closed
  before removal and exec passes a 10-retry (≈5.5s) budget
  (`cleanup({ rootRemovalRetries })`); a straggling root is left to the
  periodic orphan sweep instead of the caller.

## v0.9.169 - 2026-09-16

- Code Tidy: Install now downloads the core engines (Biome, ruff, shfmt,
  shellcheck, PSScriptAnalyzer) with progress, and the built-in card lists
  every engine with its version, language, source and size; engines picked
  up later by a project appear in the same list. Engines missing at tidy time
  download automatically by default (`tidy.downloads` still honors `ask` and
  `never`). PSScriptAnalyzer is a sha256-verified managed download from the
  PowerShell Gallery instead of a host-only module, and C# gets a real
  dotnet-format runner. Fixes: rustfmt 1.9 diff headers and `\\?\` paths are
  parsed, large Biome reports no longer collapse to zero findings when the
  output is chunked, fixability is classified through `biome explain`, and
  the history-comment rule only removes comments that are entirely history
  and never extends past the comment (it could delete the next statement).
- Sidebar rows share one status tag next to the title across built-ins,
  plugins, skills, MCP servers, schedules, webhooks and agents: nothing when
  enabled, otherwise `Not used`, `Not installed`, `Installing… N%`, `Failed`
  or `Not connected`. Disabled agents keep their model line.
- FastDirect refuses to repack or install an `app.asar` whose production
  dependency closure is incomplete and falls back to a full build, so a
  broken updater (`Cannot find module 'graceful-fs'`) is no longer inherited
  by every incremental update.
- Agent workers that were reaped are no longer resurrected by session scans
  or by the desktop agent list; re-registered finished sessions keep their
  real finish time, so leases expire instead of restarting every hour.
- Orchestration modes `none`, `focused`, `balanced` and `swarm` replace the
  Solo workflow and are chosen per session; settings are localized.
- Desktop: local path links in markdown open in the editor, and the editor
  opens files outside the project.
- Browser Use serializes snapshots per page and hardens the settle and
  capture paths.
- Computer Use: a frozen overlay renderer is retired and replaced, input
  recovery state survives the switch, and the overlay fixtures no longer exit
  early on a single-display machine.
- Shell: PowerShell hosts no longer hard-block `grep`, `sed` and `awk` in
  preflight; the tool description routes dedicated-tool work instead. Rules,
  skills, README and the new `docs/context-efficiency.md` are refreshed.
- The repository is formatted with Biome 2.5.13 (`biome.json` pins the
  existing style), rustfmt, dotnet-format and PSScriptAnalyzer; unused
  imports, dead helpers and in-file-only exports are removed.

## v0.9.168 - 2026-09-16

- Closing a Computer Use session always sends its own release request. The
  idle timer's speculative release used to be inherited when it was still in
  flight, so a refused early release could leave the closing session's worker
  and window claims pinned until the app restarted.

- Computer Use overlay: two controls, Stop and Resume. The pause button is
  gone (touching the desktop already hands control to the user); the pill now
  shows why a control is unavailable or why a request failed instead of
  reacting silently. Stop recovers a latched cleanup failure once every input
  worker has exited, so the host no longer needs an app restart, and worker
  exit confirmation waits up to 5 seconds instead of 1.
- Computer Use captures a window from its own rendered surface rather than
  copying the desktop, with a bounded capture budget; an unconfirmed resource
  release retires that worker. Background keyboard and type are checked
  before any input is sent, so an unsupported route does nothing. A new
  command waits until the previous session release is confirmed. Stop also
  waits for agent-turn cancellation, independently of native input cleanup.
- Browser Use waits honor cancel and refuse to mix a URL with text from a
  later document; a failed full-page screenshot restore is terminal. CSS
  selectors keep interior whitespace, refuse oversized match sets, and
  address each match uniquely. Concurrent downloads share one session byte
  total; approval prompts describe actions and addresses, never form values.
- Code Tidy is an installable built-in, like Office: Settings → Built-in
  installs and toggles it, and the `code-tidy` skill drives the `tidy` tool.
  Scan detects a project's languages and resolves each formatter or linter
  from project config, then project-local binaries, PATH, or a sha256-verified
  managed download (ask, auto, or never). It runs Biome, ruff, clang-format,
  shfmt, shellcheck, StyLua, gofumpt, dprint, Air, and Mago, plus toolchain
  rustfmt, gofmt, and PSScriptAnalyzer, and applies structural packs
  (history-comment removal, `debugger`, empty catch, TODO markers) across 31
  languages. `fix` is dry-run unless apply is set, and writes go through the
  same pipeline as other edits. Engine licenses ship with the tool.
- `code_graph` callers and callees come from parsed call sites, not text
  search; call-shaped references use those sites too. An older graph binary
  that cannot emit them fails with a rebuild remedy instead of an empty
  answer. Outline rows use one kind vocabulary, mark exports, show
  signatures, and nest members under their parent. `find_symbol` prefers an
  implementation file over a companion `.d.ts` and reports when the
  declaration sits outside the requested files. Identifier tokens come from
  the parse tree, so a name that appears only in a comment no longer counts
  as a reference. Solidity, Haskell, and HCL join the extraction set with
  import edges (24 extraction languages, 31 parsed). Call-site data lives in
  a sidecar cache so the main graph cache stays the same size.
- The native graph binary embeds tree-sitter 0.27 and ast-grep 0.45.3, adds
  `--scan`, `--langs`, and `--outline` modes, and extracts symbols, imports,
  and identifier tokens from YAML rules.
- The desktop editor's graph-fallback outline parses the new symbol rows into
  a nested outline with kind icons.
- Structure questions (exports, signatures, members, callers, importers) go
  to `code_graph` before `read` or `grep`; the tool-workflow parallelism
  wording is one rule.
- Memory maintenance no longer promotes conversation summaries into standing
  instructions: there is no third cycle. Cycle 2 reviews search history for
  duplicates and lineage without rewriting summaries. Standing memory stays
  user-curated through `memory`; `recall` searches all history by default,
  including previously archived rows.
- Antigravity Gemini usage shows shared 5-hour and weekly windows from the
  account quota summary, not per-model catalog counters, and requests use the
  daily channel without automatic host failover.
- The Agents pane expands only rows you open, shows a descendant count on
  the lead, and says "Waiting for agents" while descendants are still
  working instead of treating the parent as idle or complete.
- The composer offers a small slash-command palette for frequent commands
  (`/new`, `/model`, `/compact`, `/context`, `/goal`, `/inherit`, `/fast`);
  the full registry still runs when typed directly.
- Conversation file mentions stay plain text until the path is confirmed in
  the owning Project; folders and documents still open in the OS, and editor
  opens pass an access token.
- The sidebar usage roster aligns provider labels, meters, percentages, and
  reset times on one grid; the model catalog keeps seven recents.
- A new session waits until pending settings saves finish, and MCP tools
  that left the current catalog are not called mid-turn.

## v0.9.167 - 2026-09-15

- Session start reports which common shell tools are present ("Shell tools
  at startup"), measured in the login shell on POSIX and in the process PATH
  on Windows, so a model no longer guesses `python` against `python3` or calls
  `file` where it is absent; an unknown answer renders nothing.
- `read` renders overlapping windows of one file once, no longer reports
  unread edit ranges as already delivered, and never inherits a stale
  whole-body-delivered mark after a file changes; array reads honor their
  no-stub option and the description states the real output caps.
- `git` runs `&&`-chained commands as an ordered array (up to 10) instead of
  rejecting them, and recognizes bare repositories.
- The session read cache honors the tool allowlist, detects `ctime`-only
  changes, never stores a body captured before a mid-read change, keeps public
  and legacy offset hints apart, and covers public array reads.
- `web_search` arrays keep partial and total failures flagged as errors.
- Rules and built-in tool descriptions are shorter with the same behavior: the
  `shell` description carries the command→tool map and forbids tool names as
  shell commands; `timeout_ms` guidance covers throwaway checks; Lead guidance
  that only applies with the `agent` tool is omitted from delegation-free
  workflows; rules ask for every independent action the current evidence
  requires in one response, patching directly from decisive evidence, one
  sample before parsing logic, and bounded slices for large or binary data.
- Desktop runtime synchronized with the current browser and computer harness
  work, and tool contract tests hardened accordingly.

## v0.9.166 - 2026-09-14

- Studio recognizes the selected ChatGPT account after provider login and
  account switches, using the same credential path as chat without falling
  back to another account's credentials.

## v0.9.165 - 2026-09-14

- The Source Control dock keeps its row window bound to the live list: a
  rebuilt dock (tab switch, first-run surface to list) no longer scrolls into
  empty rows.
- macOS release assets upload through the delete-then-retry script on both
  architectures, so a recovery run no longer fails on an asset that already
  exists on the hidden draft.
- Release gate: every lane runs green on the hosted runners. Linux installs
  NanumGothic for Hangul PDFs and the current LibreOffice for rendered
  reviews; the Windows cursor check pins its motion preference; test
  expectations follow the shipped contracts.

## v0.9.164 - 2026-09-14

- Compact the shared and Lead rules and the built-in tool descriptions to the
  same behavior in fewer tokens; the `shell` description keeps only its role,
  the boundary with the dedicated file/search/Git tools, and the background
  task contract.
- Headless (`mixdog exec`) runs state that no user intervenes mid-run: the
  request is treated as approved and carried out to the end before reporting,
  instead of stopping to ask a question nobody can answer.
- `apply_patch` typed into the shell is no longer rerouted to the patch
  engine; the model calls `apply_patch`/`edit` directly.
- A stopped Goal retires like a completed one: the user's next prompt
  archives it, and confirming a stop archives it at once.
- Usage stats attribute measured tokens and cost per request in the ledger,
  and the desktop usage explorer shows the resulting breakdown.
- Cursor provider wire fixes.

## v0.9.163 - 2026-09-10

- Refine UI localization, startup language selection, native menus, and
  translated formatting; keep the web language bootstrap fresh across updates.
- Harden Computer Use input ownership and observation-only checks, confirm
  Electron text targets before typing, and improve cursor and session handling.
- Improve native file search and ranged reads, and prevent invalidated or
  cancelled in-flight computations from repopulating the result cache.
- Include search benchmarks, regression coverage, localization audits, and
  generated project and document deliverables.

## v0.9.162 - 2026-09-09

- The Set-a-goal dialog opens centered in the pane whose composer raised it,
  dimming only that pane; sibling panes stay visible and usable and the title
  bar is no longer dimmed. Outside a pane it falls back to the window layer.
- A focused pane no longer covers the split handle on its own edge: a browser
  pane (or any focused pane) can be resized from its left/top boundary again.
- Web fetch reports a stage that times out at the total deadline as
  `FETCH_TIMEOUT` instead of `STAGE_TIMEOUT`.
- Computer Use defaults to background delivery for supported semantic input;
  `foreground_unavailable` now asks the user to activate the target window
  instead of describing a foreground-lock failure.
- The v0.9.162 release run stopped at the test gate and shipped nothing; its
  notes below are delivered by this release.

- Mixdog is now licensed under Apache-2.0 instead of MIT. Third-party
  components retain their existing licenses and attribution notices.

- Browser Use and Computer Use ask once per session before their first live
  call. The first `browser`/`browser_devtools` or `computer` call a model makes
  in a session goes through the tool-approval prompt with the action it wants
  to take; allowing it covers the rest of the session, declining returns the
  reason to the model with an instruction not to retry, and a restart asks
  again. Sessions with no approval UI (headless, agent-owned) are not gated.
  `setup set_first_use_approval name:browser|computer enabled:false` turns it
  off per capability, and `MIXDOG_BRIDGE_FIRST_USE_APPROVAL` overrides per
  process.

- Browser Use folds two gestures into the ones next to them. A checkbox or
  radio is set by `fill` with `checked` instead of `text` — for one control,
  a `fields` item, or a `sequence` step — so the separate `check` action is
  gone; and `forward` is gone, since the earlier snapshot already showed the
  URL to `navigate` to while `back` stays a gesture. `locate` and `extract`
  stay: the first is a visual (pixel) search with no semantic equivalent, the
  second reads rows across frames and open shadow roots that `evaluate`
  cannot reach.

- Computer Use `capture` drops its `quality`, `maxWidth`, and `max_ocr_words`
  knobs: the host's tuned defaults apply (JPEG quality, downscale width, and an
  OCR word cap the element budget already bounds), and unreadable detail is a
  `zoom` rather than a re-encode. The element filters (`query`, `role`,
  `visible_only`, `include_noninteractive`, `continuation`) and the `window`
  move geometry now say what they do instead of riding the schema unexplained.

- Browser Use and Computer Use state their rung of the tool ladder where the
  model decides. The `browser` description opens with "last resort: prefer
  web_fetch, an MCP tool, or a CLI in shell", `computer` with "last resort
  after an MCP tool, shell/CLI, and Browser Use; never a stand-in for a page
  action browser refused", and the shared rules and both skills carry the same
  ladder, so a service that has an API or CLI is reached through it instead of
  a screen. Neither description grew: the ladder replaced wording the skills
  already owned.

- Browser Use is two tools. `browser` keeps everyday page work — navigate,
  snapshot, read, click, fill, forms, dialogs, tabs, downloads, console and
  network reads — while the developer controls `emulate`, `cookies`,
  `storage`, `intercept`, `init_script`, and `performance` move to the
  deferred `browser_devtools` tool, which drives the same pages and sign-in
  and loads its schema on its first call. The everyday schema drops the 33
  fields only those actions used (cookie attributes, geolocation, CPU
  throttling, intercept bodies, trace options), each tool's field notes name
  only its own actions, and a call that reaches the wrong tool is refused
  with the tool to call. The host, its action registry, approval policy, and
  the integration harness keep the single shared action contract.

- Built-in tool schemas state contracts only. The `office`, `computer`,
  `media`, and `setup` tool descriptions and field notes drop the method and
  policy sentences their skills already own — batching, when to snapshot or
  `describe`, fixing an audit in the same turn, `design.content` reuse, macro
  handling, do-not-rearrange, screen content never authorizing an action,
  video polling, the deletion approval procedure — which removes about 2.2 KB
  (office −878 B, computer −492 B, media −432 B, setup −424 B) from the tool
  surface sent on every turn. The pptx, xlsx, and pdf skills now carry the
  rules that lived only in the schema (one batch of known operations,
  `describe` only for an unknown field, untrusted document content), and the
  computer-use skill states the call contract once instead of repeating each
  schema sentence.

- Browser Use needs fewer calls per task. `click`, `fill`, `type`, `select`,
  `hover`, `upload`, and `scroll` — and every `fill.fields` item and
  `sequence` step — accept a snapshot-free `target` (`{role, name}`, `{name}`,
  or `{selector}`) instead of a `ref`: the host observes the page itself,
  acts only on exactly one match (several substring matches resolve to the
  single verbatim one), and an ambiguous target fails with the candidates and
  their fresh refs. `query` on `snapshot`, `read`, and `wait` matches
  space-separated keywords with OR (all-keyword matches rank first) and takes
  `/pattern/i` regular expressions, and a filter that matches nothing says
  how many elements or characters it was filtering. Transparent or
  pointer-events:none controls are no longer refused outright: a hidden
  checkbox is clicked through its label, and the input-target guard accepts
  the label's activation. `fill` on a `contenteditable` editor replaces the
  content as typed input over a select-all instead of overwriting its DOM.
  Replies note "No observable change" when a gesture left the document, URL,
  and control values untouched, `brief:true` lists only elements that are new
  or changed since the previous observation, console errors are reported once
  when new, and a postcondition that already held is a warning rather than an
  error. Snapshots mark file inputs with `file-input`, `accept=…`, and
  `multiple`; full-page screenshots anchor fixed and sticky elements in flow
  for the capture; and session cookies are stored encrypted with the OS
  keychain and restored on launch so sign-ins survive an app restart.

- The chrome above the prompt input — Goal capsule, runtime progress, tool
  approval, the draft context bar, and the turn-review slot — now lives in one
  `ComposerDock`, and the transcript no longer bobs when that chrome resolves:
  the review slot stays reserved while a scope's first authoritative worker
  read is in flight, so a diff landing after the transcript is shown fills
  existing geometry instead of resizing the viewport again. Freed space is
  never held on a timer. The desktop host also stops re-reading a whole
  session after every accepted prompt (the daemon-log "missing baseline"
  recovery): a reply or lane frame that repeats the revision the projection
  already holds is applied state, not a crossed baseline. Goal capsule
  mount/unmount flips are attributable under `MIXDOG_DESKTOP_PERF=1`.

- A Goal capsule no longer pops in and vanishes on its own. Two publication
  paths produced the blink: the 2s route pulse read the raw Goal record while
  a completed Goal's user-input archive was still being written, so the
  retired capsule came back for one frame; and on Windows a Goal read that
  landed inside the atomic file replace (`EPERM`/`EACCES`/`EBUSY`, or the
  runtime's own in-flight write) surfaced as "no Goal" for that frame. Route
  publications now read the Goal through the goal-continuation archive mask,
  and Goal storage answers such reads from the last committed record.

- Browser Use no longer stops for approval: the desktop "Allow once" dialog
  that guarded `upload` and shared cookie/localStorage `clear` is gone, the
  `confirm` field leaves the browser tool contract, and the browser-use skill
  drops its in-conversation go-ahead rules. `MIXDOG_BROWSER_CONFIRM_ACTIONS`
  and `MIXDOG_BROWSER_DENY_ACTIONS` remain the only way to confirm or refuse
  named actions.

- The pane reading column — composer, transcript, and the Studio dock — no
  longer waits for a 1536px pane to widen: from 768px it holds 800px until
  the pane passes 1000px, then follows 80% of the pane up to the 1000px
  ceiling at 1250px, so 1536/1680 windows and 1920 with a side panel open
  stop parking at 800px, and a divider crossing the step no longer snaps
  the column by 200px.

- The Sessions panel leads with two fixed launcher rows, `New task` and
  `New Studio`, pinned above the session list. Studio therefore leaves the
  activity rail: its launcher-only rail entry and the launcher exceptions in
  the side-view layout, pane dock, and dock toggles are retired, and a stored
  rail layout drops the `studio` id on load.

- The activity rail's Workflows destination folds into the Projects panel: a
  `Project | Workflow` toolbar — the Extensions panel's section switch, now
  shared as one `SidebarSectionToolbar` component — swaps between the project
  list and the workflow packs, default agents, and agent definitions; the
  header `+` follows the Project tab; `/workflow` and `/websearch` open the
  Workflow tab; and a stored rail layout drops the retired `workflows` view
  on load.

- The pptx skill's kit gains a design vocabulary in the manner of token-based
  design systems: `palette()` derives three line strengths (`lineSubtle`,
  `line`, `lineStrong`) and four state colors (`T.state.positive | warning |
  critical | informative`, each as `solid` / `weak` / `text`, contrast-
  guaranteed and kept under the reviewer's saturated band so a verdict column
  never trips `accent_hue_overuse`); every distance sits on one spacing ladder
  (`SPACE`) named by relation (`GAP.bind` / `within` / `between`, `GUTTER`,
  `PAD`, `M`); each text role carries a fixed leading; the repeating carriers
  (badge, callout, chevron run, stat, table) read their anatomy from `SPEC`
  with `tone` variants, a `stat` scale step, and a `statBand()` helper; icons
  map to four size bands; and a new `references/writing.md` fixes sentence,
  register, number, date, money, unit, and translation-room rules, linked
  from the docx and xlsx skills. Each spec carrier signs its shape, and the
  composition receipt reads the signatures back (`slides[].specs`,
  `deck.specs`: count, slides, variants, anatomies) so a carrier whose type
  size or face drifted between slides shows as a second anatomy.

- Office design tokens derive the same four state colors (`positive`,
  `warning`, `critical`, `informative`, each with a `Weak` field and a `Text`
  step, contrast-checked against the canvas, the light panel, and the field);
  the docx and xlsx decision gates draw Release and Stop on the positive and
  critical states instead of a literal tint and the second accent, and a
  `compose_document` section's `calloutTone` puts its callout on a state.
  A `compose_sheet` dashboard's print area now follows the decision panel,
  so a Stop gate in a column past the canvas is no longer cut from the
  rendered and exported page.

## v0.9.161 - 2026-09-06

- Office audits measure Arial, Helvetica, Times New Roman, Courier New,
  Calibri, Cambria and Georgia in their metric-compatible open faces
  (Liberation, Arimo/Tinos/Cousine, Carlito, Caladea, Gelasio) wherever the
  original is not installed, instead of reporting the font unavailable and
  approximating the fit — a Linux machine with the Liberation faces now
  audits a deck the way Windows does. The root package gains `test:slow` and
  `test:live` lanes, and the CI runtime lanes install the Liberation faces.

- Source Control commits take a summary typed by hand plus an optional
  description: commit-message presets, format checks, autocomplete and AI
  generation leave the Git & GitHub card and the commit form, and the legacy
  `desktop.git` preferences are neither read nor written.

- Computer Use drops the settings-side authorization editor (window and
  action lock, expiry): it stays unrestricted by default with the standing
  guards — input guards, elevation handling, user takeover, environment
  guards — and a saved authorization file can no longer expire into a
  lock-out. In-process narrowing survives for an embedding host through
  `MIXDOG_COMPUTER_POLICY_FILE` and `host.updateAuthorization`, nothing is
  persisted, and the failure-diagnostics export stays. The tool gains
  `wait_for_user`: when the user takes control, the model waits for a
  bounded interval and captures fresh state afterwards instead of guessing
  at permissions.

- Every Extensions and Built-in card opens the same detail dialog — identity
  plate and title, sections on one rhythm, a footer ladder with the
  destructive action parked left, one action button style — and the Projects
  add/edit dialogs join it. The Git & GitHub card carries the GitHub account
  (gh sign-in by device code); the Local Provider
  card lists installed models with size, context and running state, a Model
  loading section for idle unloading, and live facts (runtime build, GPU,
  free memory, server), while repair and verification stay chat-driven
  through the local-provider skill. Status/platform facts leave the dialogs
  because the header control and the list badge already say them. The
  extension stylesheets split into `extension-list.css`,
  `extension-dialog.css`, `extension-editors.css` and `rail-controls.css`.

- Goal: resuming a paused Goal and starting its approved task are one durable
  write — `resume` accepts task updates and additions, marking a task
  `in_progress` resumes the Goal, and bookkeeping alone never grants
  approval. A paused Goal's state reaches the model when the request is
  prepared, after hydration, instead of a one-off reminder on the user's
  reply, so no turn can lose the fact that a Goal is waiting.

- Phones synchronize their views on reconnect: after the secure handshake the
  browser asks the desktop for one consistent baseline of its open sessions
  (snapshot, session list, agent pool, session states) and live publications
  are held until it lands, so a reconnected phone no longer paints a stale
  transcript or misses the tail of a turn. The transcript handed to phones
  omits provider replay material in deltas and baselines alike.

- New-task creation survives a dropped remote connection: each request
  carries a durable receipt, so a retry after a timeout or reconnect lands on
  the same reserved session instead of creating a duplicate, and the project
  store watcher recovers on its own and reconciles the catalog while it is
  down.

- Conversations and tab strips reveal without a jump: a visited transcript
  shows once its visible rows and end offset agree across frames (bounded by
  one second, so streaming or a slow font never hides it), and a tab strip
  decides overflow from the destination layout rather than a half-grown tab.

- The Local Provider catalog actions (`searchLocalProviderModels`,
  `inspectHuggingFaceModel`, `registerHuggingFaceModel`) exist on the
  session surface the daemon resolves them on, so a setup call routed through
  the desktop no longer fails as an unavailable session action.

- Desktop UI language catalogs are back in step with the renderer: strings
  the source control views and slash commands read through `t()` were
  missing from every catalog (the tab read "History" in Korean), the retired
  legacy translation pack's Korean phrases are migrated into `ko.json` so
  dynamic labels ("Ln 42", "Callers of …") translate again, and the native
  menu and dialog strings are generated from the same catalogs. Korean is
  complete; the other ten languages fall back to English for the newer
  phrases until they are translated.

- The browser importer build replaces a half-written upstream checkout under
  TEMP instead of failing on it. Test harness: renderer suites can import
  modules that pull in a feature stylesheet (a `.css` import resolves to an
  empty module under Node), the built-artifact daemon import check runs in
  the live lane after a build, and the settings-store path fixtures resolve
  in the host's own path grammar.

- The pdf skill and runtime take the inspect-first discipline of the
  reference PDF skills. Reading: a snapshot reports `encrypted` and
  `passwordRequired` instead of pdf-lib's own error, `open`/`snapshot` with
  `password` read a locked file's text for that call without keeping the
  password, every edit on an encrypted file points at `secure` → decrypt,
  pages carry their size and rotation, bookmarks come back under `outline`
  with the page each opens, and text extraction (office snapshots, chat
  attachments, the read tool) keeps line ends as newlines so paragraphs and
  table rows survive. Forms: fields expose the
  `text|checkbox|radio|dropdown|optionlist` type, `options`, `readOnly`, and
  `multiline` a fill needs; `fill_form` names an unknown field or option
  together with what exists and reports `filled`; `add_form_field` and
  `create` accept `optionlist`, `required`, `readOnly`, `maxLength`, and
  `fontSize`; the lint flags a box too small to use (`formIssues` on create,
  `field_too_small` in `issues`); `preview_fields` writes a copy with every
  field and any proposed box outlined and named so a render shows placement
  before a fill; a dropdown or list with Korean options no
  longer fails at creation because the widget is painted with the embedded
  face from the start; and a multiline field defaults to 11 pt instead of
  pdf-lib's auto size, which drew the first line huge and dropped the rest.
  Fonts: `create`, `add_text`, `watermark`, `fill_form`, and OCR embed an
  installed Unicode font on their own when the text is Korean, CJK,
  Cyrillic, or Greek (`pdf-fonts.mjs`; `fontPath` still chooses; `detect`
  names the face as `portable.pdfUnicodeFont`). Writing: `create` wraps
  unspaced prose by character, honours `\n`, wraps table cells and grows
  rows, repeats the header after a page break, numbers multi-page output,
  and accepts `columnWidths`, heading `level`, image `align`, `orientation`,
  `footer`, and more page sizes. Editing: `merge_pdf` takes `sources:[path | { path,
  pages, title }]`, `index`, and `bookmarks:true`; `add_bookmark` writes an
  outline entry; `extract_pages` writes to `output` and `split_pages` one
  numbered file per page or per `every` pages without touching the session
  document; `extract_attachment` round-trips embedded files; `rotate_pages`
  adds to the current rotation; `delete_pages` keeps one page; `compress`
  reports `bytesBefore`/`bytesAfter`; `add_text` takes `align:'center'|'right'`
  and numbers an existing file through `{page}`/`{pages}`; `highlight` marks
  every match of `find` (or one box; `wholeWord`, `regex`, and `first` narrow
  it) with a multiply-blend mark that leaves the text legible; `add_link`
  lays an invisible link over a match that opens a URL or another page, or
  with `urls:true` makes every http(s) address in the text open itself;
  `stamp_image` fits inside the margins unless sized;
  `issues` no longer reports a scanned page twice and names active content
  (`active_content`: JavaScript, Launch, actions on open, links to files or
  other non-web schemes) without following it. Analysis: `pdf-layout` with
  `query` returns only the matches with their boxes; its text boxes follow
  the run on rotated pages and for diagonal text, it and the snapshot report
  `origin` when a page box does not start at 0,0. Marks by `find` invert the
  display transform to handle both origin offsets and 90/180/270-degree page
  rotations without reorienting the document; `first:true` preserves document
  row order at every rotation. The layout lists each page's
  links (`url` or the target `page`) and adds each page's rules (`lines`) and
  `boxes` (small squares flagged `checkbox`), which is what filling a form
  that has no fields needs; `pdf-tables` reads a bordered table from its
  cell rectangles (`source:'ruled'`, wrapped cells intact) before the
  text-alignment guess (`source:'alignment'`) and writes one CSV per table
  when `output:<dir>` is given, as `pdf-images` writes PNG files and reports
  where each picture sits on the page; OCR fits
  each invisible word to its box so the text layer keeps single spaces. Page
  previews (`render`, `qa`, `finalize`) hand pdf.js its bundled standard
  fonts, so a page set in Helvetica or Times no longer renders
  letter-spaced. The adapter is split into `pdf-writer`, `pdf-forms`,
  `pdf-draw`, and `pdf-fonts`, and the skill is rewritten as inspect →
  create → edit → secure → verify with the qpdf requirement (PATH or
  `MIXDOG_QPDF_PATH`), the permission-bits caveat, and the in-place-text
  limit stated.

- The xlsx skill and runtime take the modelling discipline a reader expects
  of a spreadsheet: a backend-neutral formula audit (shared by portable
  `issues` and the quality review) reports an unquoted multi-word sheet
  reference, an external-workbook link, a percentage stored as a whole
  number, a year under a thousands separator, and a figure stored as text
  for every workbook (plus, as information, a long sheet whose header is
  not frozen and a table column of numbers under General), and
  under `auditProfile:'financial-model'` an inline rate in a formula, an
  unguarded division, a lone formula that breaks its row or column pattern,
  a single reference past the sheet's populated extent (the off-by-one that
  recalculates cleanly), a hardcode inside a formula row, and inputs
  indistinguishable from
  formulas, plus an input a formula reads that carries no source note and a
  Checks-sheet tie-out that evaluates FALSE — on both backends, since Excel's
  `issues` now folds the shared audit into the host's own findings. Snapshots
  expose each styled cell's number format, font, color, and fill (Excel's BGR
  integers normalize to the same RRGGBB shape), legacy notes per cell and per
  sheet, Excel tables per sheet (records inside one are data the table
  sources, so the audit asks for a note only on assumptions outside it),
  merged ranges and freeze panes in Excel's shape,
  booleans as booleans, the workbook `defaultStyle`, and a
  `document.conventions` summary (default face, faces in use, number formats
  by column, input markers, sample inputs) so an edit can match the file's
  own conventions; `set_formula` quotes the multi-word sheet names the
  workbook holds (and, on both backends, any multi-word name written
  before `!` and a reference) and reports the `normalizedFormula`, LibreOffice
  recalculation returns a `status` with `totalErrors`, an `errorSummary` by
  error type and cell, and the `unparsedFormulas` LibreOffice wrote back in
  lower case, and `finalize` refuses a workbook whose recalculation found any
  error even when the review was skipped. The skill rewrites its rules around zero
  formula errors, formulas over pasted results, literal specs, documented
  assumptions, the fill-in legend, and matching an existing file's
  conventions, with `references/model-conventions.md` for colors, number
  formats, structure, the Checks sheet, and sourcing.

- The pptx skill opens with a route table — a new deck is an `author`
  script, an existing deck is `open` → `snapshot` → `batch`, and reading is a
  paged `snapshot` or the source extractor — and resolves its script paths
  through `${MIXDOG_SKILL_DIR}`, so page QC, the independent reviewer, and
  `source-extract.mjs` (moved into the skill with a test) run from any
  Project. The editing section names the pitfalls the runtime actually has:
  a duplicated slide shares its chart part with its source, template
  decoration stays where the placeholder's line count put it, and a script
  that declares its own `pres` inherits pptxgenjs's 10 × 5.625 in canvas.
  The docx, xlsx, and pdf skills add the triggers users actually write
  ("Word", "Excel", "PDF 읽어", "PDF 만들어"), and the docx skill says how a
  snapshot shows a line break.

- Portable PowerPoint editing resolves a chart's relationship target the way
  the package does: pptxgenjs writes it as an absolute part name
  (`/ppt/charts/chart1.xml`), which `set_chart_data` and the other chart
  operations on an authored deck used to report as a missing part. Portable
  snapshots now keep line breaks and paragraph ends as newlines — a deck's
  shape and notes text, and a Word document's paragraph, cell, comment,
  revision, note, and content-control text — instead of running "4주차" and
  "잔존율" together.

- Pane tab strips animate adds and closes on the chrome clock: a new tab grows
  in from nothing while its neighbours shrink, so the run never overflows the
  strip and slides back, and a closed tab collapses in place while the
  survivors glide into its space instead of jumping. A draft promoted to its
  session still swaps instantly, and the strip drops its unused width-hold
  state.

- Office authoring gains three output-quality structures: `author` and
  `batch` return a measured `audit` (fit, bounds, contrast, spacing, package)
  with per-slide counts and a same-turn fix mandate that counts its rounds;
  `author` refuses to land a deck whose figures have no fact behind them
  (`facts_gate`) unless the brief declares `facts: sample`, which carries an
  illustrative-figures disclosure through qa and finalize; and the pptx skill
  ships `scripts/qc-pages.mjs`, a per-page fixer that runs one fresh session
  per slide with the office tool alone and adopts its working copy only when
  the page's measured defects did not grow and no other slide changed.

- Skills split their listing line into a one-sentence description and a
  `when_to_use` trigger; the model's skill list shows `description — trigger`
  cut at 250 characters, the skill editor gains a separate Trigger field, the
  skill-creator validator warns when a listing line will be cut, and every
  built-in skill is rewritten to the new shape.

- The session Goal island aligns its task list with the collapsed header,
  separates rows with hairlines, and collapses on outside click or Escape.

- The phone surface follows the desktop chrome: the context gauge sits beside
  the composer's model trigger, the toolbar marks share the lucide family,
  and the right sheet opens as one dock unit whose header carries the same
  view toggles as the desktop strip.

- Built-in skills ship from a bundled skill source, and the Office guides
  become pptx, docx, xlsx, and pdf skills gated on the feature they drive.
  Settings group dependent skills, MCP servers, and hooks under their plugin
  or built-in feature.

- Office authors PPTX decks from pptxgenjs scripts with a design guide,
  helper kit, layout menu, and model-led visual QA, and tolerates
  presentation and chart child order differences.

- Tool calls coerce JSON-text arguments to their declared schema shape,
  including internal registry schemas.

- Browser Use splits URL, tab, partition, redaction, and snapshot-script
  policy into dedicated modules; Computer Use refines the overlay model,
  input backend, and session coordination.

- Desktop boot warmup, side-dock restore, usage reset timing, bridge-owned
  discovery files, and session transport recovery keep cold starts and
  reconnects responsive. FastDirect deploys prewarm the installed runtime.

- The test runner separates fast, slow, and live tiers with timing reports;
  session stores cache transcript summaries and listing sweeps; provider
  request utilities harden Anthropic, Cursor, and OpenCode wire handling.

## v0.9.160 - 2026-09-02

- The TUI now installs its patched Ink runtime from a versioned release asset.
  Production builds, frame harnesses, and load probes resolve the installed
  package while preserving the custom cursor, selection, and render behavior.

- Desktop startup now reveals usable pane shells before slower catalog and
  runtime hydration completes. Browser, Terminal, Editor, and side-dock
  surfaces restore independently, with focused readiness probes and deferred
  host services keeping cold starts responsive.

- Browser Use and Computer Use now have role-based host modules instead of
  flat monoliths. Browser actions share explicit routing, guest lifecycle, and
  reply contracts with stronger file chooser and dialog handling, while
  Computer Use separates discovery, observation, input, session, overlay, and
  backend responsibilities with expanded safety coverage.

- Office runtime modules are organized by core, design, quality, portable,
  PDF, COM, and benchmark roles. Freeform composition, reference-driven layout
  selection, authored PowerPoint scenes, and rendered assurance checks improve
  visual quality without weakening editable output or transaction boundaries.

- Anthropic OAuth sessions now learn a provider-required minimum CLI version,
  persist only safe upward updates, and retry the rejected request once without
  overriding explicit version configuration.

## v0.9.159 - 2026-09-01

- Windows release acceptance now checks the canonical 16-item settings
  inventory instead of the stale pre-navigation count.

- Computer Use now coordinates foreground target leases, recaptures after
  window transitions, validates bounded action sequences, and exposes a
  user-takeover overlay. Capture, keyboard, targeting, and recovery paths are
  split into focused modules with broader host and bridge coverage.

- Browser Use gains session-scoped registries and persistent per-conversation
  surfaces. Browser, diff, and utility views can stay attached to each
  conversation's side dock, while local file reads replace the retired
  duplicate folder-explorer path.

- Fresh-context compaction now carries a bounded Memory handoff, preserves
  active-turn continuation and tool-envelope state, and keeps provider cache
  layouts stable across compaction. Memory ingestion projects the compacted
  transcript consistently instead of relying on the retired fast-track path.

- Office deck generation adds creative direction, layout grammar, semantic
  visual flow, rendered-aesthetic review, and a release-quality score so
  presentation output is more varied and catches weak composition earlier.

- Verification and release plumbing churn drops sharply: the 3,500-line
  tool-smoke monolith is now fourteen focused `node --test` suites under
  `scripts/tool-contracts/` with brittle exact-wording assertions relaxed to
  key-phrase contracts, CI path selection is single-sourced in
  `scripts/release-paths.mjs` for both the release gate and deploy planning,
  and a release skips re-running the critical lane when the gate already
  verified the exact same commits.

- No suite can rot silently any more: the remaining test monoliths
  (provider-toolcall, session-transport, shell-hardening) are per-domain
  suites under `scripts/`, the release gate now executes the tool-contract
  and compaction (recall-fasttrack) contracts on every gated push, and a
  weekly `suite-health` sweep runs every registered `test:*`/`smoke:*`
  script through an opt-out catalog that opens a tracked issue on failure.

## v0.9.158 - 2026-08-31

- The Extensions hub now gives Git, Memory, Browser Use, Computer Use, Office,
  and voice a consistent install, progress, enable, and disable flow. Optional
  runtimes are prepared on demand, Office can install LibreOffice through the
  platform package manager, and disabling voice preserves downloaded assets.
- Desktop runtime packaging is smaller and more deterministic: optional feature
  payloads stay out of the base app, runtime code is prepared once, snapshot
  deploys tolerate concurrent edits, and release CI shares one cross-platform
  runtime build with explicit Git and Computer Use gates.
- Studio preserves per-item drafts and makes detail editing, selection, and
  keyboard interactions resilient across navigation. Context usage and voice
  dictation controls also report their current state more consistently.
- The OpenAI OAuth route leaves WebSocket prompt prewarming off by default,
  avoiding an unnecessary warmup request unless it is explicitly enabled.
- Terminal-Bench 2.1 publishes the full Codex CLI `k=5` comparison with raw
  Harbor artifacts, source-commit verification, recovered-cost provenance, and
  reproducible report generation.

## v0.9.157 - 2026-08-31

- Browser Use gains a smaller, more reliable host split across tabs, downloads,
  interception, permissions, snapshots, dialog reporting, and page lifecycle.
  Chromium profile import now includes offline App-Bound v20 cookie decryption
  through the packaged native importer without exposing decrypted secrets to
  the renderer or agent.
- Computer Use is decomposed into bounded capture, discovery, targeting,
  observation, input, and worker modules. Fairer resource ownership, fresher
  post-action state, stricter input guards, and expanded repeat scenarios make
  long-running native and Chromium sessions faster and safer.
- Memory moves to a compact E5 embedding runtime with incremental latest-first
  backfill, cache compression and retention, Korean-aware lexical ranking, and
  idle worker reclamation. The old token native addon and heavier legacy model
  path are removed from the shipped runtime.
- Session recovery promotes the checkpoint journal to the durable resume
  boundary, preserving provider usage, compaction anchors, recall handoff, and
  Anthropic thinking replay across interruption, retry, and restart without
  duplicating context.
- Office authoring adds model-authored composition plans, a reusable design
  library, document preview, and broader portable Word, Excel, and PowerPoint
  primitives while retaining structural and rendered assurance checks.
- Desktop and mobile web surfaces gain remote Browser Use, share-target intake,
  push notifications, richer document editing and preview, quieter startup
  restoration, and more predictable service-worker cache updates.
- Native search now bounds broad inventory leases and fairly admits concurrent
  find, glob, and grep work. Release automation incrementally rebuilds changed
  native and voice assets, verifies packaged sidecars, and reuses unchanged
  platform runtime artifacts.

## v0.9.156 - 2026-08-29

- Portable Office authoring gains chart rendering and text metrics, so more
  PPTX and XLSX work completes without handing off to the Office COM host.
- Browser Use and Computer Use tool contracts are revised together with the
  desktop settings store, IPC validation, and transcript tool formatting.
- Desktop virtual scrolling now tracks the upstream packages, and the
  transcript's bottom pin relies on the core's own scrolling deferral.
- Development deploys can run from a frozen snapshot of the working tree
  (`update:dev:snapshot`), which lets an install succeed while other sessions
  keep editing the repository instead of failing the input-fingerprint check.

## v0.9.155 - 2026-08-29

- PPTX slide import, image replacement, and table data authoring now run in the
  portable engine, so those operations no longer require the Office COM host.
- Office authoring gains portable packaging, composition, sheet-style, and
  slide-shape modules behind the existing assurance and quality pipeline.
- Goal tracking gains reminder and text extraction handling for continuations,
  and the desktop keeps session metadata in sync with a bounded renderer cache
  budget for unread-session state.

## v0.9.154 - 2026-08-29

- Computer Use sessions are reclaimed on every exit path instead of depending on
  an unref'd timer a departing runtime never fires: daemon and worker shutdown
  release them, a closing session releases its own, idle host workers expire on
  the same clock as the window claims they hold, and a dropped client connection
  aborts in-flight input rather than letting it drive the desktop until the
  command timeout. The client also retries once against a republished bridge, so
  restarting the desktop app no longer fails the next command outright.
- A crashed Browser Use page recovers on the next command instead of failing it.
  Refs bound to the dead document are dropped with it, so recovery can never
  hand back coordinates from a page that no longer exists.
- Compaction that runs between a prompt and the provider request no longer hangs
  when the memory runtime stalls: the recall-fasttrack memory call is bounded for
  every caller, not just the one path that happened to wire a timeout in.
- The Windows Explorer hidden-entry parser splits attrib.exe output with Windows
  path rules on any host, and the commit-hook capability probe now works across
  git versions that disagree about whether a non-native hook name needs a flag.
- Deploy stops rebuilding byte-identical platform runtimes. Test sources leave
  both the published package and the runtime cache key, so a test-only change
  hits the prepared-runtime cache instead of paying a seven-minute Windows
  rebuild. Desktop suites run as parallel gate jobs, including a Windows leg that
  finally exercises Computer Use in CI, and the 240-second git suite no longer
  sits in the default local run.

## v0.9.153 - 2026-08-28

- Windows Computer Use now runs a smaller CUA-style observation loop: compact
  accessibility and a plain screenshot are returned together by default,
  post-action state is immediately refreshed, AX and fallback OCR share one
  strict element budget, unusable black, white, or mismatched captures never
  issue a coordinate frame, mutations invalidate prior pixel frames, one new
  same-process popup becomes the deterministic verification target, app-owned
  Electron text fields use renderer-native background insertion, recovery names
  one next escalation rung, and dangerous session-ending keys, shell payloads,
  or shell/script-host launches are blocked at the host boundary. A 23-scenario Windows dashboard now covers
  native, Electron, Chrome, Korean OCR, secondary-display, stale-state, focus,
  popup, safety, and cleanup paths.
- Computer Use observations and turns are faster without weakening the input
  boundary: lightweight Win32 transition/frame snapshots, exact-window capture,
  bounded modern Chromium accessibility, adaptive launch polling, capture
  resource guards, and verified focus/cursor recovery replace repeated full app
  enumeration and unbounded fallbacks. Element-targeted literal typing can
  focus and type in one action, and bounded OCR can be included in the mandatory
  post-action capture. The final 23-scenario × 10 source-host matrix reached
  230/230 semantic passes and reduced baseline p50/p95 scenario latency by
  90.55%/94.01%; a separate dense/minimized/stale-target stress matrix passed
  40/40. All 30 redundant post-action recaptures were removed, and calls fell
  36.84% in the five batchable action workflows. Arbitrary mutation batching
  remains unsupported.
- Computer Use now exposes one strict 15-action contract instead of 28
  overlapping actions or a flat optional-field schema. Observation/search/zoom
  use `capture`, window and clipboard lifecycle use operation fields, and one
  shared `capture_after` object configures automatic verification. Reference-
  aligned guidance requires fresh exact targets, prefers semantic elements,
  and keeps Browser Use separate. The final schema was 2,644 estimated tokens
  before the frontier extensions; the pre-removal frontier contract passed
  36/36 first-call model scenarios. The current direct-dispatch contract is
  3,210 estimated tokens and 14,485 wire bytes. Read-only
  `diagnose` reports Windows OCR/UIA readiness without screen pixels; bounded
  `sequence` stops on failure or target transition and returns one final fresh
  state; strict call cardinality prevents parallel cross-target mutations both
  in model guidance and before runtime eager dispatch. Extra same-turn
  `computer` calls are not executed and receive a fresh-state recovery error.
  Natural-language selection passed 4/4 safe focus chains and 4/4 transition
  boundaries. In 10 repetitions, a two-action continuation used 50% fewer
  model-facing calls and captures, with p50/p95 latency down 12.34%/32.31%.
  Model-facing Computer Use confirmation and Office transaction approval
  prompts were removed; user-requested actions now execute directly while
  blocked key, payload, and script-host patterns remain hard errors.
  Measured provider usage is 5,150 input tokens and 4,026 ms p50 per model
  call. A 12-action post-observation schema reduced input 18.16% at 27/27
  accuracy but was rejected because repeated latency outliers and mid-loop
  schema changes would break the immutable provider-prefix cache contract.
  Semantic actions with deterministic exact-window transitions now report
  confirmed verification. No legacy call-shape fallback remains. After one
  development deployment, installed-app validation confirmed that left
  `click(ref)` uses semantic activation and that a native file-association
  launch returns its selected target with fresh state; marks and coordinates
  remain explicit pointer operations.
- Browser Use can import Chromium passwords, cookies, and history, suggest only
  masked accounts for the current HTTPS origin, and fill a selected login form
  inside an isolated CDP world without exposing the stored password to the
  renderer, agent, diagnostics, or logs. Utilities now defaults to the first
  right-side tab, migrates the old default placement without resetting custom
  layouts, and includes the Browser entry point.
- FastDirect now fingerprints, stages, backs up, and atomically restores the
  browser-import native sidecars together with `runtime.asar`, so incremental
  development updates cannot leave the installed app without its importer.
- Session context usage now records a canonical post-compaction snapshot that
  survives persistence and restart until the next turn invalidates it. Goal
  state and compaction recovery stay consistent across restarted services
  instead of repainting stale token usage or losing resumable work.
- Office generation now shares a semantic content model, structural and
  rendered assurance checks, prompt-injection review, checklist gates, and a
  polish pipeline across Word, Excel, and PowerPoint. Spreadsheet page/view
  controls, template-capacity selection, native chart data persistence, and
  live save-and-reopen verification strengthen release-quality documents.

## v0.9.152 - 2026-08-27

- Goal mode can now carry a long-running objective across turns with durable
  completion conditions, pause and resume controls, time limits, automatic
  continuation, model-facing management tools, and a session-scoped Desktop
  status island.
- Browser Use and Windows Computer Use are available as opt-in built-in
  capabilities. Browser Use can inspect and operate in-app or background pages,
  while Computer Use combines UI Automation, screenshots, keyboard, pointer,
  scroll, and window actions with DPI-aware input and safety guards.
- Provider recovery now preserves the original order of reasoning, text, and
  tool calls across Anthropic, Gemini, OpenAI, and compatible streams, including
  retries, stalled turns, saved sessions, remote projection, and compaction.
- Compaction starts a fresh read-cache epoch after it changes the transcript,
  and existing sessions synchronize newly available runtime tools at turn
  boundaries instead of keeping a stale tool catalog.
- Desktop and mobile navigation is cleaner and more predictable: mobile
  relaunches start from one New task while reconnects retain the current panes,
  pane swipes work across rich content and overlays, and side pages, extensions,
  Markdown, status labels, and trailing actions share tighter responsive
  layouts.

## v0.9.151 - 2026-08-26

- Editing a symbolic link now changes the file it points at instead of being
  refused: patch and edit follow the link through every engine, write
  atomically beside the real target, and leave the link itself intact.
- Headless and benchmark runs no longer leave temporary databases and processes
  behind. Each run gets an isolated runtime root, shutdown waits for the session
  daemon instead of reporting success ahead of it, and orphaned clusters are
  swept on the way out.
- Conversation compaction keeps everything it should. Automatic, manual, and
  cleared compaction share one path, the stored summary leads with full raw
  history behind it, and the most recent turns survive verbatim instead of being
  trimmed by a row or size cap.
- Exploration reads the original file before deciding how to parse, count, or
  summarize it, so a format guess no longer drives the answer.
- Desktop polish: attached images open in the system viewer, the usage panel's
  quota rows read in a natural order, and context and route panels lose their
  leftover frames and focus outlines.
- Terminal-Bench 2.1 results are republished from a `k=5` run of all 89 tasks,
  with the raw verification artifacts for every published run committed
  alongside the harness and metric scripts.

## v0.9.150 - 2026-08-25

- Tool results stay scannable and honest about size: search output and
  multi-file reads hold to a fixed budget instead of flooding an answer with
  thousands of lines, and a path that simply does not exist — or an ordinary
  repository state verdict — comes back as the answer rather than a failure
  that sends the assistant into recovery.
- Sessions no longer carry a stale provider fingerprint across a restart, and a
  new message immediately wakes a turn that is waiting on a background task, so
  a reply lands instead of sitting behind the wait.
- Terminal text selection recovers from a drag whose button was released
  outside the window, and a selection dragged past the top or bottom edge
  follows normal start-of-line and end-of-line behavior instead of freezing at
  the last column the pointer held.
- Voice dictation asks for confirmation before installing its runtime, tool
  cards and diff frames line up on the shared theme, and ten interface
  languages are refreshed.

## v0.9.149 - 2026-08-24

- OpenAI OAuth sessions now speak the reference client's wire shape by default:
  stable installation and thread identity, the lighter request form on current
  models, and provider-correct handling of a socket that reaches its lifetime
  limit mid-session.
- Session startup reserves its pre-warmed connection for the first turn only
  when the prompt it warmed still matches, so a turn whose environment or tool
  surface changed starts clean instead of resending the whole request.
- Directory listings return a first page sized for scanning rather than a dump,
  and code structure lookups fetch full symbol bodies only when the exact
  implementation is needed.

## v0.9.148 - 2026-08-24

- Desktop and mobile conversations preserve drafts, history, follow behavior,
  pane gestures, and remote state more reliably while reducing relay transfer
  and renderer deployment overhead.
- Agent sessions recover provider streams, compaction, worker state, and tool
  results more consistently, with clearer Git conflict and environment
  outcomes and more accurate search telemetry.
- Voice input gains a verified cross-platform runtime release path, while
  memory retrieval, native process handling, and packaged runtime preparation
  are hardened.
- Release automation, FastDirect deployment, and benchmark reporting now reuse
  unchanged artifacts and compare model calls, cost, and final context with
  provider-correct accounting.

## v0.9.147 - 2026-08-21

- Long OpenAI sessions now keep their response chain and turn-state pin intact
  across reconnects, item reordering, and compaction, so the provider prefix
  cache survives a session instead of restarting mid-task.
- Session startup pre-warms the provider prefix and separates environment
  details from the shared instruction prefix, cutting cold starts and repeated
  upload of identical context.
- Tool-use rules read shorter with the same guarantees: routing clauses now
  disappear with the tools they name, and shell results are classified by the
  runner that produced them.
- Desktop tool cards and result summaries are localized, and the context gauge
  reports the post-compaction estimate instead of the discarded prefix.
- Benchmark runs gain fast route presets and a grok CLI reference adapter, so
  reference numbers come from the same containers and verifier.

## v0.9.146 - 2026-08-21

- Mobile web conversations now keep touch scrolling, streaming Markdown
  measurement, tab swipes, compact composer controls, and responsive overlays
  stable across native gestures, rotation, and small-screen layouts.
- Sessions can carry a full conversation into the currently selected model
  when it fits that model's context boundary, while context usage and inherited
  route details remain explicit.
- Transcript tool groups preserve their original calls, arguments, outputs, and
  completion state for detailed inspection, with localized image previews and
  clearer activity presentation.

## v0.9.145 - 2026-08-21

- Mobile web sessions now keep native viewport scale, pairing recovery, remote
  state projection, and transcript scrolling stable across touch gestures,
  streaming row measurements, app restores, and slow connections.
- Desktop panes, source-control refreshes, tool activity, command surfaces, and
  session state recover more consistently while preserving responsive layouts
  and clearer loading or interruption feedback.
- Agent tool routing now applies tighter argument guards, Git mutation policy,
  provider-prefix handling, evidence projection, and shell output recovery
  across the shared runtime and TUI.
- Release, benchmark, localization, and diagnostic tooling now validate their
  contracts with broader regression coverage and more compact runtime reports.

## v0.9.144 - 2026-08-21

- Desktop interaction now follows keyboard and pointer focus more reliably,
  improves mobile pane swipes and transcript/status presentation, and reports
  background shell task state with safer recovery behavior.
- Git diff panes reveal their own loading state immediately, coalesce
  overlapping refreshes, and render repository text without invoking configured
  external diff or textconv commands.
- Solo is now the default workflow, tool-use rules preserve evidence while
  batching work more tightly, and bounded read/grep windows reduce unnecessary
  context without hiding pagination.

## v0.9.143 - 2026-08-20

- Session execution now shares one supervised runtime worker instead of a
  process-shard pool. Background agents stay in-process, provider waits yield
  their local CPU admission slot, and machine-wide spawn limits and runtime
  health recovery remain enforced.
- Remote device approvals appear only while Settings → Connection is open,
  recover pending requests when that panel opens, and finish only after the
  browser proves its authenticated E2EE connection.

## v0.9.142 - 2026-08-20

- Linux desktop packaging validates the target architecture in the ABI
  prebuild directory that `node-pty` actually loads, while compiled Windows and
  macOS packages keep their `build/Release` validation path.

- Installed web apps resume one pending desktop approval across reloads, while
  the desktop replaces stale prompts, expires them with the relay request, and
  accepts each decision only after the service confirms it.
- FastDirect reuses fresh build targets, a persistent production renderer
  cache, prepared runtime output, and an extracted ASAR shell template. Live
  relay deploys independently fingerprint renderer/server changes and upload
  only verified renderer deltas before the atomic VPS swap.
- Inline code follows the surrounding prose font and size, leaving color as
  its only inline distinction while fenced code remains monospace.

## v0.9.141 - 2026-08-20

- Desktop task creation works under Electron 41 and Node 24: the agent shard
  router now copies immutable ESM session-manager exports into a writable
  facade before installing its remote-session overrides.

## v0.9.140 - 2026-08-20

- Studio deletes take effect on the first click: a finished run releases its
  grid slot as soon as its asset is indexed, so deleting that asset no longer
  revives the slot as a phantom "generating" tile. The gallery is no longer
  capped at 2,000 entries — an asset leaves the store only through an explicit
  delete — and a run that fails, starts without a job, or loses its runtime
  snapshot now reports that instead of spinning silently.
- The mobile tab switcher reads as a card grid and earns a filter field only
  once the list is long enough to need one, while phone chrome restates the
  composer discs, the status island, and panel sheets at touch proportions and
  brings hover-only controls within reach.
- An installed web app can pair itself: it opens a device-routed entry URL,
  asks that desktop for approval behind a two-digit code shown on both
  screens, and receives pairing material sealed to its own throwaway key.
  Paired browsers now register which push lanes they read, so a connected
  phone no longer pays for terminal, editor, and file traffic it never shows.
- The code-graph search server serves shared-pipe clients with per-connection
  response queues and client-scoped request ids, and exits on its own after an
  idle window so a force-killed owner stops leaving warm servers behind.
- Tool calls survive provider argument noise: an omitted optional base path
  resolves to the current Project instead of failing the call, task arguments
  are narrowed to the chosen action, and git output keeps its final progress
  frame and its trailing fatal line instead of burying the reason under redraw
  frames.
- The renderer loads one UI language catalog instead of eleven, settles the
  language before the first app module evaluates, and prefetches a surface
  chunk on selection; /inherit carries an existing conversation into a new
  session on the currently selected route.
- Third-party credit is carried by LICENSES and NOTICE alone.

## v0.9.139 - 2026-08-20

- Antigravity OAuth arrives as a provider: one Google login exposes Gemini 3.x
  and Claude through the Cloud Code Assist gateway, with login, token refresh,
  and endpoint failover following the existing OAuth provider shape.
- Agents now have exactly two states, a pinned model or off, and Web Search
  resolves the Main Model when its route is left unset.
- Paired browsers reach the desktop operation surface — project instructions,
  folder browsing and places, and the git contract — through one shared
  argument-validation module, while relay session state travels as
  client-scoped compact deltas inside binary E2EE frames.
- The web app now ships precompressed brotli and gzip assets, holds back
  background warmups and fonts on metered or slow links, resizes image
  attachments and dictation audio before upload, drops the pinned status
  island's live blur on phones, and paints the brand accent in Google blue.
- Windows runtime staging and asar packing survive repo lifecycle scripts and
  transient antivirus file locks, and the TUI status line computes its running
  shell count directly on the instant path.

## v0.9.138 - 2026-08-19

- Remote web sessions now use client-scoped subscriptions, binary E2EE frames,
  compact state/catalog deltas, terminal batching, and paint-latency probes,
  reducing transfer volume while preserving live recovery on slow links.
- Web transcript scrolling and composer input remain visually stable during
  concurrent remote snapshots, session switches, and mobile rendering.
- Runtime context, provider request recovery, background task notifications,
  and completion restoration are hardened across long-running sessions.

## v0.9.137 - 2026-08-19

- Remote reconnect recovery now refreshes session catalogs and mounted
  transcript lanes, and the update control leads the title-bar button group.

## v0.9.136 - 2026-08-19

- Retired Discord/Telegram messaging and channel-session plumbing are removed,
  while mobile system bars remain consistently black.

## v0.9.135 - 2026-08-18

- Desktop now preserves pane layouts, sidebar state, panel geometry, and
  composer drafts across reloads and FastDirect restarts, with expanded
  renderer regression coverage.
- Shell execution now hardens environment scrubbing, warm standby, background
  completion recovery, native process handling, and tool routing across
  interactive and headless sessions.
- Native spawn Linux releases are statically linked, graph search and recall
  reporting are hardened, and Terminal Bench routing and report tooling are
  updated.

## v0.9.134 - 2026-08-17

- Desktop now ships the selected brand mark, a unified model route editor with
  model parameters and persisted list order, and unpacks node-pty beside the
  packaged daemon.
- Session compaction is hard-locked by owner: agent sessions stay semantic,
  user sessions use recall-fasttrack. Settings no longer lists Core memories
  (they live on the project), and the Windows acceptance inventory matches.

- Provider and tool integrations now include OAuth lifecycle and token recovery
  across Anthropic, Cursor, Grok, and OpenAI, Grok-specific tool schema
  normalization, and decomposed search and grep path/pattern fan-out.
- Session orchestration and TUI workflows now enforce owner-session scoping,
  preserve completed handoff and background completion cards across restores,
  retain externalized queued prompts, and classify outcomes across command
  failures, tool errors, and benign misses.
- Desktop workspace navigation now preserves pane session titles during drag
  interactions, adds cold-start workspace restoration retries that prevent
  dropped tabs, and updates onboarding and capability configuration panels.

## v0.9.133 - 2026-08-16

- Provider-only evidence projection now aliases repeated typed file paths
  within mutation epochs, preserving exact tool envelopes and reconstructable
  paths while reducing cumulative context in long sessions.
- Git execution now shares one mutation policy across orchestration and
  evidence projection, serializes repository-wide writes against file edits,
  uses tree-owned native processes, and makes queued locks abortable.

## v0.9.132 - 2026-08-16

- Tool execution now exposes complete shell exit status, adds a dedicated Git
  surface, strengthens atomic patch creation and diagnostics, and improves
  search, list, code-graph, and native graph integrity under concurrent load.
- Session compaction, provider/image recovery, evidence tracking, shard health,
  and Lead runtime cleanup now preserve state across failures without masking
  degraded workers or triggering unnecessary fallback work.
- Desktop routing, agent activity, restored pane state, and streamed Markdown
  rendering now remain responsive and visually consistent across live and
  resumed conversations.

## v0.9.131 - 2026-08-14

- Release gates now run automatically with incremental path selection, desktop
  platform runtimes prepare ahead of packaging, native graph builds use a
  faster reproducible profile, and production web/relay deployment includes
  atomic rollback plus hash and health verification.
- Desktop release lanes now package as soon as their matching runtime is ready,
  graph compiler caches stay isolated between reproducibility builds, relay
  installs are lockfile-pinned, and release timing warns on 10% regressions.
- Agent cleanup no longer mistakes Lead pool projections for child workers, so
  disposing another runtime cannot close the active desktop conversation or
  discard an accepted follow-up message.

## v0.9.130 - 2026-08-14

- Provider and session recovery now classifies transient stream failures
  consistently, retries image-rejected turns without losing user intent, and
  preserves interruption, summary, and terminal outcome state across Gemini
  and OpenAI transports.
- Tool failures are persisted without test-trace pollution, shell policy avoids
  quoted-script false positives, and native search/read/list/stat paths share
  cancellable work while preserving fresh watcher invalidation and exact-file
  grep/glob behavior under load.
- Desktop Studio, usage, agent activity, pane layout, localization, and worker
  tag presentation now stay aligned across restored and live sessions.

## v0.9.129 - 2026-08-14

- Headless exec now runs a true solo surface by default: web search and
  memory tools stay off unless --web-search / --memory opt back in, shell
  child processes inherit an enforced no-egress proxy (loopback stays
  reachable), and the session environment line states network=offline so
  models never attempt web access.

## v0.9.128 - 2026-08-14

- Exploration tools now finish at the search round: grep spends its output
  budget on ranked source blocks (rare-branch matches first), find drops
  noise-only fuzzy results, and code_graph symbol outlines filter before
  capping and honor body requests.
- Agent guidance batches one best-routed call per unknown instead of
  speculative multi-tool fanout, cutting benchmark token use by a third with
  no pass-rate change.
- Session recovery and runtime resilience hardening across native search,
  shell contract, and read/list tooling.

## v0.9.127 - 2026-08-14

- Native binaries now have one canonical home in GitHub Releases: npm ships
  only the CLI, while CLI runs verify and cache assets on demand and Desktop
  builds embed the same verified platform assets.

## v0.9.126 - 2026-08-14

- Native search now handles the complete internal grep/find contract, preserves
  regex recovery errors, and overlaps first-turn search and code-graph warmup.

## v0.9.125 - 2026-08-13

- Shell and background-task execution now use one hash-pinned native process
  manager across Windows, Linux, and macOS, with no environment, local-build,
  file-registry, standby-shell, or Node process fallback.
- Native search, patch, download, media, recall, webhook, and session paths now
  enforce bounded resources, stricter ownership, and hardened transport and
  release-supply-chain checks.
- Memory runtime extraction now accepts verified in-archive links while still
  rejecting traversal, external links, and special tar entries.
- Desktop project, terminal, update, remote pairing, relay, and pane behavior
  now include the consolidated security, recovery, and responsive-layout fixes.

## v0.9.124 - 2026-08-12

- Desktop agent activity now groups every active session independently of the
  focused tab, while restored session panes prewarm correctly and existing
  sessions accept follow-up input without waiting for host acknowledgement.
- Desktop and daemon session transport now survives startup races, stale
  control sessions, transient socket loss, and in-place stream recovery while
  keeping remote ownership global across session focus changes.
- Git commit preferences now separate the visible example from AI
  instructions, serialize overlapping saves, and validate then correct
  Conventional Commit output before accepting it.
- Core memory now mirrors curated and generated context into an atomic,
  revision-guarded file so sessions can load scoped memory without cold-starting
  the memory runtime, with mutations refreshing the mirror.
- TUI transcript anchoring and Escape selection handling avoid visual jumps and
  accidental queue restoration, while Terminal-Bench refusal fallback follows
  the runtime termination reason even after streamed narration.

## v0.9.123 - 2026-08-12

- Desktop provider setup now recovers stale control sessions without exposing
  raw transport failures, and prompt history engages only from an empty draft.
- Path search avoids cold full-tree sweeps, coalesces watcher prewarms, and
  tightens native search deadlines, bulk concurrency, and process snapshots.
- Async shell timeout guidance now distinguishes unlimited background work from
  explicit kill deadlines.

## v0.9.122 - 2026-08-11

- Tool routing rules now centralize path conventions, remove duplicate batching
  guidance, and require read-only inspection only when evidence is at risk.
- Anthropic benchmark preflight now resolves provider imports correctly from
  isolated temporary harness snapshots.

## v0.9.121 - 2026-08-11

- Tool execution rules and shell diagnostics now distinguish conclusive path
  misses, trust verified envelopes, keep same-turn value checks, and surface
  command-not-found facts from stderr.
- Desktop transcript virtualization now pins native text-selection endpoints
  during drag autoscroll, while utility launchers align their icon and copy in
  content-sized rows.

## v0.9.120 - 2026-08-11

- Background shell tasks now retain their owner session and daemon after every
  view detaches, so idle eviction cannot cancel the task before its completion
  is delivered.

## v0.9.119 - 2026-08-11

- Native Graph and Token reproducibility builds now run on independent runners
  in parallel, while macOS Intel DMG and ZIP uploads overlap and abandon
  stalled transfers promptly.
- Desktop project navigation, utility surfaces, transcript focus, and vendored
  virtualization behavior are refined alongside tighter tool execution styles
  and filesystem process reuse.
- Discord and Telegram attachment handling preserves bounded media delivery
  and validates Telegram upload behavior directly.

## v0.9.118 - 2026-08-11

- Desktop consolidates Agents, Search, and Source Control in the utility dock,
  keeps Utilities selected while launching tools, and aligns warning versus
  failure treatment across restored and live tool cards.
- File listing and native search now coalesce concurrent enumeration, support
  cancellable persistent requests and process snapshots, and preserve bounded
  fallback behavior under heavy filesystem fan-out.
- Code-graph batching, PowerShell standby reuse, shell process-tree tracking,
  and cache invalidation are hardened against concurrent work and stale state.

## v0.9.117 - 2026-08-11

- Desktop prompt submission now supports immediate Enter queueing and precise
  Esc restoration of pending text and attachments, while transcript scrolling
  defers virtualizer corrections during active reader motion.
- Desktop Utilities now presents direct Studio, Terminal, and Explorer
  launchers with localized descriptions, while the activity rail uses the
  creative Utilities identity and refreshed usage presentation.
- Obsolete model-facing channel actions and their provider-dispatch plumbing
  are removed so the advertised tool catalog matches the runtime surface.
- Tool execution guidance tightens batched evidence and same-turn verification,
  while concurrent filesystem, graph, patch, and shell bursts gain bounded
  threadpool, spawn-lane, and reachability-pressure handling.

## v0.9.116 - 2026-08-11

- Terminal-Bench H5 round analysis adds rewarded task traces and aggregate
  round counts for the final high-effort comparison.

## v0.9.115 - 2026-08-11

- Terminal-Bench H4 round analysis records successful high-effort task probes
  and their retrieval, patch, and verification cadence.
- Tool execution guidance now treats task facts and proven checks as durable
  known state and keeps patch verification in the same execution turn.

## v0.9.114 - 2026-08-11

- Guessed tool identities are now verified before dependent calls, with an H3
  Terminal-Bench round analysis recording the resulting retrieval patterns.

## v0.9.113 - 2026-08-11

- Tool guidance now batches distinct evidence samples and avoids redundant
  deferred-tool or project activation, with Terminal-Bench round analysis
  capturing remaining serial-probe patterns.

## v0.9.112 - 2026-08-11

- Desktop utility, activity, transcript, settings, and repository surfaces are
  simplified around focused feature configuration and compact regressions.
- Provider recovery, shell/list diagnostics, and release verification are
  consolidated into smaller ship-critical suites without weakening their
  transport, asset, or packaging contracts.

## v0.9.111 - 2026-08-11

- Repository navigation now uses the direct built-in tool surface without a
  separate explorer agent, reducing routing overhead and legacy configuration.
- OpenAI WebSocket retry decisions preserve current auth, throttling, and
  cancellation errors, while session transport recovery and completion
  deduplication are hardened.
- Tool batching, graph fan-out, progress reporting, and desktop transcript,
  settings, and utility-dock behavior are streamlined with focused regressions.
- Terminal-Bench 2.1 profiles, resumable runs, immutable harness snapshots, and
  cost accounting are tightened for reproducible native comparisons.

## v0.9.110 - 2026-08-11

- Provider transports now bound Anthropic non-stream stalls, distinguish
  retryable transport failures from model refusals, preserve OpenAI reasoning
  continuity on recovery, and prewarm compatible WebSocket sessions.
- Patch, list, and shell tools recover unique path or context mismatches in one
  call while retaining ambiguity, symlink, and destructive-command safeguards.
- Session-title completion and Markdown source fallback handling are more
  resilient, with focused provider, renderer, tool, and routing regressions.
- Terminal-Bench 2.1 diagnostics, fair native baselines, usage accounting, and
  reproducible reasoning-replay experiments are expanded.

## v0.9.109 - 2026-08-10

- Shell commands that complete with a non-zero exit are treated as command
  results rather than tool failures, with consistent runtime and TUI status.
- Tool routing, explorer limits, output-style contracts, and their regression
  suites are tightened to avoid redundant work while preserving concise
  user-facing reports.
- Compact patch roots now establish both the write boundary and relative path
  coordinate frame, including clearer recovery guidance.

## v0.9.108 - 2026-08-10

- Compact patch parsing accepts legacy Begin/End wrappers around compact
  sections while leaving canonical V4A input unchanged.

## v0.9.107 - 2026-08-10

- Non-interactive automation and benchmark sessions explicitly use implicit
  approval context, while interactive workflows keep their user approval gate.

## v0.9.106 - 2026-08-10

- MCP clients, tool discovery, instructions, execution, deferred refresh, and
  teardown are isolated by runtime scope so same-named servers cannot leak
  across concurrent sessions or standalone agents.

## v0.9.105 - 2026-08-10

- Remote access is web-app only: the retired Capacitor/Android package,
  APK download routes, native-shell hooks, and mobile release version wiring
  are removed, while relay deployment gains an explicit renderer staging step.
- Tool calls now normalize current-project inputs to compact relative paths,
  reject mismatched or redundant scopes consistently, and preserve parity
  across shell, patch, graph, explore, and built-in tool contracts.
- Context reporting separates provider-visible usage from compaction pressure
  and configured reserve, while Anthropic adaptive thinking leaves its display
  mode to the API unless an operator explicitly overrides it.
- New-task drafts keep their own project tab when selecting or registering a
  project, and successful session Fast changes seed the next matching draft
  without replacing a different model choice.

## v0.9.104 - 2026-08-09

- Tool routing now locates unknown repository coordinates once, assigns each
  evidence facet to one dedicated tool, batches only independent calls, and
  keeps text edits and verification behind the patch execution barrier.
- Directory inspection exposes dotfiles and file metadata without Shell
  exploration, while delegation-free workflows omit the unused Lead brief and
  use a smaller, capability-aligned tool surface.

## v0.9.103 - 2026-08-08

- Desktop navigation, composer, Studio, settings, and transcript surfaces now
  share a tighter responsive layout, with stronger virtual-scroll following,
  local-file handling, and expanded DOM regression coverage.
- The remote renderer ships as an installable web app with a stable manifest,
  icon, and network-only service worker, while the relay serves those assets
  with the required manifest and service-worker content types.
- Solo execution no longer carries obsolete debugger, scheduler-task, or
  webhook-handler agent definitions and removes their stale routing/cache
  protocol, keeping built-in services separate from editable custom agents.
- Hosted Codex image generation explicitly selects the image tool for supported
  models, with focused request-body coverage.

## v0.9.102 - 2026-08-08

- Maintenance version bump; no functional changes over v0.9.101.

## v0.9.101 - 2026-08-08

- Escape now recalls queued, still-unprocessed messages into the composer
  before anything else — queue order first — so a mid-turn Esc edits the
  waiting follow-up instead of interrupting the turn; a second press still
  cancels.
- Workflows are pure working-style definitions: packs no longer carry an
  agent roster. Every defined agent (built-in and custom) is available to any
  delegating workflow, Solo stays delegation-free via `delegation: none`, and
  deleting a custom agent removes it from every surface at once, including
  spawn-by-name.
- Settings → General gained independent Web search, Explorer, and Memory
  toggles; Memory now gates the memory/recall tools plus core-memory
  injection, while background memory cycles moved to Context as their own
  switch.
- Headless role runs and bench sessions start with explorer, web search, and
  memory off (classic surface) and opt back in per run via flags or
  MIXDOG_FEATURE_* variables.
- The shared tool policy drops the mandatory post-edit verification round,
  takes the cheapest sufficient evidence per lookup, and defines explore as a
  plain source search over source trees and files with one concrete target per
  query.

## v0.9.100 - 2026-08-07

- Context command styling no longer depends on opening Settings first or
  collides with Monaco's global context class, and transcript reattachment no
  longer rolls back a small reader wheel movement.
- Desktop packagers now restore npm downloads with a dependency-only cache key,
  so release version stamps do not cold-start every platform installation.
- Hidden drafts are treated as resumable work rather than published releases,
  preventing failed releases from consuming an extra patch version.

## v0.9.99 - 2026-08-07

- Desktop transcript typography now separates content, operational status, and
  metadata into a steadier hierarchy, while Fast uses a compact stateful icon.
- Explorer retrieval now fans out every concrete locator facet once, preserves
  returned paths verbatim, and stops bounded recovery instead of returning a
  weak or reconstructed anchor.
- Synchronous model-catalog reads no longer launch an implicit global network
  request. Session warmup remains the single owner of remote catalog I/O, so
  provider-injected transports stay hermetic on a cold installation.
- The isolated release lane now prepares one verified native code-graph runtime
  explicitly instead of depending on an ambient binary left by an earlier job.
- Intel macOS release assets use bounded, file-by-file HTTP/1.1 uploads with
  remote completion checks and retries, preventing one stalled CLI transfer
  from holding the entire release indefinitely.
- Unpublished same-version release recovery now folds its accumulated notes
  into that version before publishing instead of leaving shipped work marked
  as Unreleased.

## v0.9.98 - 2026-08-07

- Remote browser pairing now establishes an authenticated end-to-end encrypted
  channel before any session state, terminal data, or RPC payload can cross the
  relay; unencrypted media lanes remain closed.
- Desktop attachments preserve file identity and metadata through the session
  boundary, with bounded image/PDF extraction and shared media normalization
  for provider inputs.
- Desktop onboarding and related settings copy are localized across every
  shipped language, while IME composition, virtual transcript following, and
  fast-mode controls behave consistently in long-running panes.
- Session recovery, pending-message delivery, provider catalog caching, title
  generation, worktree snapshots, and bounded runtime metrics are tightened
  around the unified session service.
- Release validation is split into parallel lanes, desktop compilation overlaps
  the gates, prepared runtimes are cached, and platform packages upload to one
  hidden draft before atomic publication. Renderer-only dependencies are no
  longer duplicated in the desktop archive, cutting the Windows installer by
  roughly one third.

## v0.9.97 - 2026-08-07

- Session protocol 1 now carries an explicit compatibility index, allowing
  newer clients to reject older daemons while older clients can attach through
  the supported compatibility surface without parallel engine/backend stacks.
- Desktop, terminal, channel, OAuth, and memory flows now share the unified
  machine-wide session daemon; obsolete engine/backend transports, fallbacks,
  and compatibility shims have been removed from the development line.
- Session ownership and tool workload gates now coordinate parallel shell,
  patch, read, code-graph, memory, and channel work with fair admission,
  lower duplicate I/O, and stronger cancellation/recovery coverage.
- Desktop multi-pane focus, tab dragging, review state, notifications, provider
  naming, updater diagnostics, and developer update packaging have been
  tightened, with expanded renderer and session-transport regression tests.
- Terminal-Bench reproduction commands and cost validation now point to the
  exact archived run and fail clearly when a requested trial set is absent.

## v0.9.96 - 2026-08-07

- Release discipline now requires every app package to be pre-bumped when the
  engine wire protocol changes, keeps workspace versions synchronized, and
  publishes that pending identity without an accidental second increment.
- Development and installed surfaces continue to share the existing data and
  authentication store; protocol/version discipline prevents same-version
  daemon skew without hiding credentials behind a new profile.
- Release validation now gates platform packaging and removes a duplicate
  code-graph run, avoiding five expensive package jobs when a focused gate fails.
- Desktop protocol conflicts now explain the update/close-and-reopen recovery
  path instead of surfacing a raw session transport exception.
- The unified protocol-1 daemon removes the duplicate desktop session host,
  restores daemon reconnect/resync behavior, and preserves completed tool work
  across timeout and cancellation boundaries.

## v0.9.95 - 2026-08-06

- A machine-global process owns every live session, and the terminal TUI plus
  every desktop window attach as views over a 127.0.0.1 HTTP+SSE transport, so
  there is no owner/viewer role to negotiate between surfaces.
- Submitted prompts can no longer be lost between surfaces. A daemon view's
  submit keeps its synchronous answer but is retried until the engine takes it
  (and re-delivered after a daemon restart), a live-share submit is
  acknowledged by the owner and falls back to the durable spool when it is
  refused or unacknowledged, and the queue drops a re-delivered submission id
  instead of posting the message twice.
- Cross-client editing: resuming a session another view already holds adopts
  that live engine instead of loading a second copy, engine frames fan out to
  every view, and an engine only ends with its LAST viewer — so a terminal and
  a desktop window can drive one session turn by turn.

## v0.9.94 - 2026-08-05

- Desktop tab strip shrinks tabs together toward the active/inactive floors
  with every tab visible instead of scrolling, and touch shells collapse to a
  title + count switcher list.
- Streaming markdown heals the live tail (unclosed `**`, `` ` ``, `~~`) and
  scopes the fenced-code geometry lock to its own chunk, so headings, lists,
  and bold format while the model is still typing.
- Turn review moved into the scrolled timeline (turn diffs ride the
  thread), ending the composer-stack shift on session entry; warn-tone
  notices now use the amber status pair instead of the neutral one.
- Native caption band is transparent so the DOM titlebar and dialog scrims
  dim it directly; the ◀ ▶ pane-cycle pair is retired (Alt+Left/Right keeps
  the focus cycle) and project dialogs hold the titlebar dim claim.
- Desktop UI capture drives New task and Settings through Ctrl+N / Ctrl+,,
  pins the capture language, and asserts the 360px narrow settings layout.
- TUI transcript window and jitter harness refinements, plus desktop
  session-selection race probes.

## v0.9.93 - 2026-08-04

- Dependency audit to zero across core and desktop: `npm audit fix` for
  fast-uri, ip-address, hono/@hono/node-server, root undici, and
  brace-expansion; discord.js nested undici override raised to 6.28.0;
  desktop `dompurify` override `^3.4.12` clears the Monaco XSS batch.
- README feature audit: desktop workbench section, memory subsystem detail,
  QR relay pairing, quiet-hours cron and local Whisper transcription,
  parallel pane sessions, onboarding wizard.
- Discord: removed the last registered slash command (`/stop`); startup still
  clears stale global/guild command sets.
- Terminal-Bench 2.1: corrected results, replacement comparison charts, and
  reproduction/verification scripts.
- CI: Deploy is now the single release entry point (token supply chain folded
  in, tag-push side doors removed) with a changelog release gate.
- Unified package versions at 0.9.92 (mobile/relay aligned) and squashed the
  repository history to a clean root.

## v0.9.92 - 2026-08-02

- Baseline release: npm package, desktop installers, and native supply-chain
  assets (runtime, patch, graph, token, voice runtime).
