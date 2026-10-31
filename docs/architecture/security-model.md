# Security model

This guide elaborates on `AGENTS.md`. If anything here conflicts with `AGENTS.md`, `AGENTS.md` wins.

Oarlock runs shells, reads and writes files, and sends data to AI providers. The security model is defense-in-depth: no single guard is enough, so every boundary validates input before acting on it.

## Boundaries

The main trust boundaries are:

1. **IPC boundary** - commands registered in `src-tauri/src/lib.rs`, gated by `src-tauri/capabilities/default.json`.
2. **File-system boundary** - every file command, PTY and shell spawn, git and the AI tools go through the workspace authorization registry; AI tools also go through `src/modules/ai/lib/security.ts`.
3. **Network boundary** - AI HTTP proxy in `src-tauri/src/modules/net.rs` with SSRF and DNS-rebinding defenses.
4. **Secret-storage boundary** - keys live in the macOS Keychain or Windows Credential Manager, or in a user-only file in the Linux app data directory; they never go in `localStorage`.
5. **Terminal escape-sequence boundary** - OSC sequences are parsed and acted on, but never blindly trusted to mutate state.
6. **MCP boundary** - MCP servers are programs and services the user added; their tools ask before every call unless the user trusts the server, and what they return is untrusted input (see below).

## Secret-path deny-list

`src/modules/ai/lib/security.ts` refuses reads and writes of obvious secret paths. This applies **on both read and write**, also while "Allow AI tools to access all folders" is on (it consults no setting), and must never be bypassed.

Blocked categories include:

- Files: `.env*`, `*.pem`, `*.key`, `*.p12`, `id_rsa*`, `known_hosts`, `credentials`, `service-account*.json`, and similar.
- Directories: `~/.ssh`, `~/.gnupg`, `~/.aws`, `~/.kube`, `~/.config/gh`, `~/.git`, system dirs (`/etc`, `/proc`, `/sys`), and Windows credential stores.
- System write prefixes: `/etc/`, `/var/db/`, `/usr/bin/`, `/applications/`, `/windows/`, `/program files/`, etc.
- Home persistence points (write only, directly under a home root such as `/Users/<name>`, `/home/<name>`, `/var/home/<name>`, `/root` or `C:\Users\<name>`): shell rc and login files (`.zshrc`, `.bashrc`, `.profile`, ...), `.gitconfig`, `~/.config/{fish,autostart,systemd/user,environment.d}`, `~/Library/LaunchAgents`, PowerShell profile folders and the Windows Startup folder. They run code later as the user, outside any approval; the same names elsewhere (a dotfiles repo) stay writable. This is defense in depth: an approved shell command can still write them.

The comparison surface normalizes paths: backslashes to forward slashes, strips Windows drive letters, strips NTFS alternate data streams, strips trailing dots/spaces, lowercases, and collapses duplicate slashes. Protected directories are matched as exact path or descendant, not raw substring.

`checkReadableCanonical` and `checkWritableCanonical` also canonicalize the path and re-check the resolved form so a symlink at an innocent path pointing into `~/.ssh` is caught. A path that cannot be resolved is let through only when it does not exist (the OS's not-found error, `isNotFoundError`); any other failure (outside the authorized folders, no permission, a link loop) refuses, since the read or write would follow links the recheck never saw.

## Workspace authorization registry

`WorkspaceRegistry` (`src-tauri/src/modules/workspace.rs`) tracks the folders that file commands, PTY spawn, git commands, and AI tools are allowed to operate in.

- `workspace_authorize` adds a root, or with `opened` lets the file commands reach a folder the user browses or the folder a file they open is really in (`authorize_opened`; nothing is added when an authorized folder already covers it).
- `authorize_spawn_cwd` rejects a spawn cwd outside an authorized root.
- `authorize_user_spawn_cwd` registers the user's chosen cwd as a new root instead of rejecting it.
- The registry is bootstrapped with the launch directory and the user's home directory (`bootstrap_registry`).
- A launch (arguments, a later launch handed over by `tauri-plugin-single-instance`, macOS Open With) authorizes its folder and the folder each of its files is in before a window opens them (`second_launch::authorize_launch`). Only the user's own processes reach a running Oarlock (the session D-Bus on Linux, a window message on Windows, a socket in `/tmp` the user owns on macOS), and those could start Oarlock with the same arguments anyway.

### File commands

Every Tauri command that reads, writes, lists, stats, searches or watches a path the page sends is refused outside the authorized folders, unless its caller's "access all folders" switch is on (below). The check is on the real path, through one of four gates:

- `authorized_existing`: the path, links followed and `..` resolved, lies in an authorized folder (`fs_read_file`, `fs_read_dir`, `list_subdirs`, `fs_stat`, `fs_canonicalize`, `fs_host_path` for WSL, the roots of `fs_search`, `fs_list_files`, `fs_grep`, `fs_grep_interactive` and `fs_glob`, `fs_open_default`, `lsp_resolve_root`).
- `authorized_write_target`: `fs_write_file` writes through a link only to an authorized file, a dangling link is an error, a new file needs an authorized folder.
- `authorized_new`: `fs_create_file` and `fs_create_dir` need the nearest existing ancestor authorized and plain names below it, so neither a link nor `..` leads out. File creation uses an exclusive native create, so an occupied leaf (including a dangling symlink) is refused rather than followed or truncated. Nested folder creation builds the parent chain, then creates the requested leaf exclusively; concurrent calls cannot both claim that leaf.
- `authorized_entry`: `fs_rename`, `fs_delete` and the sources of `fs_copy` act on the entry itself (a link, not what it points to) in an authorized folder; `..` and an authorized folder itself are refused. `fs_move` and `fs_delete_batch` also keep both ends under the explorer's authorized root.

A missing path outside reads as outside, so a refusal never says whether something exists there, and relative paths are refused. A WSL path is judged by its host path (the `\\wsl.localhost` share or the drive of `/mnt/<drive>`). `fs_watch_add` drops folders and files outside; `lsp_resolve_root` only looks into authorized folders, for markers that are plain names. Searches walk without following links, so a link inside a root never leads a search out.

The page authorizes only what the user chose (`src/modules/workspace/authorize.ts`): a file opened from the explorer, its search, the content search, a terminal link, LSP navigation or the New File dialog (its real folder); a folder expanded in the explorer; files dropped or pasted into the explorer (their folders, as host paths); the roots, terminal folders and open files of the spaces a window restores. Explorer items dropped on the AI composer are the exception: they authorize nothing, a dropped file is read through the AI tools' own checks (deny-list, `origin: "ai"`) and a dropped folder is only named in the prompt (`src/modules/ai/lib/pathAttachment.ts`, `composerDrop.ts`). It never authorizes a path a terminal program or an AI reply named on its own, so the AI tools (`read_file`, `list_directory`, `grep`, `glob`, writes) are refused outside the authorized folders, and `oarlock open` from a terminal already requires an authorized file. Path completion in the block input lists only authorized folders.

A terminal's folder is authorized as a root, which keeps the explorer and Source Control following `cd` anywhere. The folder comes from OSC 7, which is terminal output: `cat` of a crafted file can print one naming any folder, even `/`. So the page hands each report to `pty_authorize_cwd` with the terminal's id (only the window that opened the terminal may ask), and on Linux and macOS the backend authorizes it only when its real path is exactly the folder the OS reports for the shell (`/proc/<pid>/cwd`; `proc_pidinfo` with `PROC_PIDVNODEPATHINFO`) or for the leader of the terminal's foreground process group (a nested local shell, such as `bash` started from zsh, reports its own folder), both canonical and checked to still be the folder the process is in (a deleted folder never matches). The report follows the `cd`, so the shell is already there; one that a fast second `cd` overtook authorizes nothing, and the next report is checked. A report that does not match changes nothing in the page either (`TerminalCwdReports`): not the tab's folder, the explorer or Source Control, the folder a restart or a new tab starts in, or the terminal folders a restored window authorizes, since each of those would authorize it later. One check runs at a time per terminal and a burst keeps its latest report. A remote shell's report (over `ssh`) names no local process's folder, so the tab keeps the local folder `ssh` runs in. Windows cannot read another process's folder cheaply, so there (a WSL pane included) the report is authorized and taken as before.

One limit remains: `workspace_authorize` is itself a command the page can call, so the registry contains what the app's own flows do, not a fully compromised page. The same holds for the two settings below: they are plain switches in Settings, so the page can turn them on (`workspace_set_all_folders`).

### Access to all folders

Settings, General, Folder access has two switches, both off by default and labelled "At your own risk": **Allow the app to access all folders** and **Allow AI tools to access all folders**. They are independent: each widens one side and never the other.

- The backend initializes both gates from native preferences and updates them only after a successful preference commit (`modules/preferences.rs`). Windows cannot set these gates independently; `src/modules/workspace/allFolders.ts` is a UI mirror. Failed initial reads leave access denied and preserve the settings file for recovery.
- A command that both sides use takes an `origin` (`Origin`, `app` or `ai`): `fs_read_file`, `fs_write_file`, `fs_canonicalize`, `fs_create_dir`, `fs_read_dir`, `fs_grep`, `fs_glob`, `shell_run_command` (its cwd), `shell_session_open`, `shell_session_run` and `shell_bg_spawn`. A call that leaves it out is the app's. The AI tools' wrappers (`src/modules/ai/lib/native.ts`) send `ai` on every file and shell call, so the agent never gets the app's access, and a test checks that each command they tag takes the parameter (otherwise the tag would be dropped silently). Every other file command is the app's alone.
- The command takes its gates once (`registry.gates(origin)`): the authorized folders, or every folder while that origin's switch is on. The gates still require an absolute path judged on its real path, plain names for new entries and below an explorer root, and still read a missing path as outside while closed. Turning a switch off refuses the next command.
- A switch authorizes nothing: no root is added, so the other side, the asset protocol's grants, git, language servers (`lsp_resolve_root`, spawn cwd), terminal folders (`pty_authorize_cwd`) and `oarlock open` keep the authorized folders (`registry.authorized_gates()`, `is_authorized`). The page still authorizes what the user opens, as with the switches off, so turning one off leaves what the user chose reachable.
- The app's switch covers the explorer (listing, create, rename, move, delete, copy), editor open and save (and the external formatter's cwd), previews, the file finder and content search, file watching, path completion in block terminals and Open in Default App, whose question before running a program stays. Watches set up while it was on keep reporting changes until released.
- The AI tools' switch covers `read_file`, `list_directory`, `grep`, `glob`, `write_file`, `edit`, `multi_edit`, `create_directory`, plan mode's Apply and the agent shell's cwd. The deny-list and tool approval (Ask, Auto-approve) are unchanged, and the composer shows an "All folders" chip while it is on. Settings shows a persistent indicator in its header while either is on.

This is the allow side of the file-system boundary. Any new command that takes a path must pass it through one of these gates.

New File, New Folder, conditional editor saves and `fs_write_file` acquire an
operation-scoped directory capability (`fs/destination.rs`, `cap-std`). The
actual directory handle's path is authorized before any staging bytes or
missing parent directories are created. Creation, staging, publication and
cleanup use that capability, so replacing a parent path cannot redirect them.
Nested folder creation acquires and validates each parent before proceeding.
Regular-file comparison checks the opened file's actual path before reading;
symlinks to another entry and nonregular files are refused. Existing-file saves
publish with a relative atomic rename and apply permissions before publication;
new-file saves publish with an atomic no-clobber hard link. Filesystems lacking
that operation report a save failure, never fall back to an unsafe copy.
Handles and staging files live only for the operation; there is no idle watch,
cache or IPC request. These handles bind directory objects, not permanent path
reservations: another process can still rename an acquired directory. Detected
moves fail, and operations racing a move remain bound to the acquired object.
Conditional saves retain their final file-identity/change-stamp recheck, which
is not a filesystem compare-and-swap against unrelated programs.


## Settings store

Ordinary preferences, MCP settings and custom AI endpoints have native owners; their files and the legacy preferences migration source cannot be opened by the page through the store plugin. Other page data, including snippets, todos, agents, custom themes and spaces, uses JSON stores through `tauri-plugin-store` (`store:default`). The plugin joins the path the page gives it to the app data folder, so an absolute path or `..` would read or write JSON anywhere, and it has no option to stop that. `src-tauri/src/modules/store_scope.rs` registers the plugin inside a thin wrapper that forwards every hook unchanged (stores, resource ids, the `store://change` events that keep windows in sync, file names) and refuses, before the plugin sees them, the two commands that name a file (`load`, `get_store`) unless the name is a plain file name: ASCII letters, digits, `-`, `_` and inner dots, no separator, drive, `..`, leading or trailing dot, or Windows device name (`CON`, `NUL.json`). The only nested name allowed is an extra window's own spaces store, `windows/<label>/oarlock-spaces.json`, from that window alone. Every other store command takes the resource id of a store opened that way. A test lists every store the page opens (each `STORE_PATH` in `src/`) and checks that each is allowed. The backend's own stores (`StoreExt`) are not affected.

## Asset protocol scope

Asset URLs (`asset://localhost/...`, `http(s)://asset.localhost/...` on Windows) let a webview load a file from disk without IPC. `tauri.conf.json` allows nothing (`assetProtocol.scope` is `[]`, and a test keeps it so); `src-tauri/src/modules/asset_scope.rs` grants at runtime:

- every root the workspace registry authorizes, recursively, through `WorkspaceRegistry::watch_roots` (roots authorized before the app existed are replayed). The editor's media and PDF previews and the Markdown preview's images load from there. A WSL root is registered by its host path (the `\\wsl.localhost` share or the drive of a `/mnt/<drive>` path), which is also what `fs_host_path` maps a WSL file to for its URL. A root inside one already granted adds nothing, unless the way down passes a dot folder the wildcard skips.
- each installed font face `system_font_faces` returns, as a single file, for the terminal's font features.

Tauri canonicalizes every requested path before matching, so a link pointing out of a granted root is refused. The configured scope sets `requireLiteralLeadingDot`, so on every platform the wildcards never enter names starting with a dot and a granted home folder does not serve `~/.ssh` (Tauri's default does this only on Unix, which on Windows would serve `C:\Users\<me>\.ssh`). Never widen the configured scope (no `**`); grant what a feature needs where it needs it.

A runtime grant can never be taken back, so "Allow the app to access all folders" grants nothing here. While it is on, previews load through the backend's own `oarlock-asset` scheme instead (`src-tauri/src/modules/asset_all_folders.rs`; `workspaceAssetUrl` picks the scheme from the setting this window last sent). It asks the setting on every request: it serves what the asset protocol would, and while the switch is on any file whose real path has no name starting with a dot (the rule `requireLiteralLeadingDot` applies below a granted root, here from the filesystem root), so `~/.ssh`, `.env` and `.git` stay out. Links are judged by their target, a missing file outside reads as refused, only GET and HEAD with single byte ranges (at most 1000 KiB a response) are answered, responses are `no-store` and name only the app's origin, and a request carrying any other `Origin` is refused. Like the asset protocol, any frame can load from it (a page in the preview pane can show, but not read, such a file while the switch is on). The moment the switch is off it serves no more than the asset protocol, and previews switch back to `asset:` URLs.

## Opening files in their default app

`fs_open_default` (`src-tauri/src/modules/fs/file.rs`) hands the OS only an existing file whose canonical path lies in an authorized workspace, so a link pointing out of the workspace is refused. The OS's default handler can run code, so the command classifies the canonical path first (`fs/launch.rs`, a pure function per OS: Windows extensions such as `.exe`, `.bat`, `.ps1`, `.js`, `.lnk`, `.reg`, an alternate data stream; on macOS and Linux the execute bit, Mach-O or ELF headers, bundles, Terminal scripts, launchers, installers and packages; Windows programs everywhere, since Wine may run them). The lists err toward asking. For a program the backend shows the OS's own dialog (`fs/run_prompt.rs`: a warning naming the file and saying it runs as a program, Cancel and Run, attached to the calling window) and opens the file only on Run; otherwise it answers `cancelled`. Return presses Cancel on every platform, so running takes a deliberate click on Run (or moving the focus to it first), and Escape or closing the dialog cancels: on macOS an `NSAlert` sheet whose first, accented button is Cancel with Return as its key (Run has none; Escape, which `NSAlert` would give only to a Cancel button that is not the default, is caught while the sheet is up and presses Cancel, and the keyboard-navigation focus starts on Cancel); on Windows `TaskDialogIndirect` with Run and Cancel and Cancel the default, focused button; on Linux a `GtkMessageDialog` transient for the window with Cancel the default response and focused. tauri-plugin-dialog cannot choose the default button (through rfd its first button is the default on macOS and Windows, and GTK gets none), and handing it the labels in the other order is unsafe, because it reports a dialog closed any other way as its second button. Only an explicit Run runs: any other answer, a dialog that never showed or one destroyed with its window is a Cancel. The page has no way to approve: the command takes no confirmation, the webview holds no permission for message dialogs, and the answer arrives from the OS. Only one such question shows at a time, the dialog is awaited without blocking the main thread, and the file is checked again after the answer. A link named like a document is judged by its target.

## AI tool approval flow

In `src/modules/ai/tools/tools.ts`:

- `TOOL_GATES` classifies every tool (`none`, `approvable`, `approvable-outside-plan`, `always`); the record is exhaustive, so a new tool cannot ship unclassified. Each run's `toolApproval` is built from it and the conversation's approval mode (`buildToolApproval`, read on every call); sub-agents get Ask mode's fixed `TOOL_APPROVAL`.
- Read-only tools (`read_file`, `list_directory`, `grep`, `glob`) auto-execute after passing the deny-list.
- In Ask mode (the default), mutating tools (`write_file`, `edit`, `multi_edit`, `create_directory`, `bash_run`, `bash_background`) and the coding-agent tools (`spawn_coding_agent`, `send_to_agent`) are `user-approval`. The AI SDK pauses and surfaces a `tool-approval-request` part rendered as a confirmation card.
- Auto-approve, a per-conversation opt-in shown by an always-visible composer chip, runs file and shell tools without the card. It only drops the card: `execute` still refuses protected paths and the command deny-list, plan mode keeps shell commands asking, and the coding-agent tools, which no deny-list covers, ask in every mode.
- Plan mode queues file mutations instead; Apply re-checks each path against the deny-list where it writes.
- MCP tools (`mcp__<server>__<tool>`) have gates of their own (`mcpToolGate`): a server the user has not marked Trusted asks before every call, in every mode, Auto-approve included; a Trusted server's tools follow the conversation's mode as shell commands do (plan mode asks); a tool set to Always allow runs unasked and one set to Never allow is never offered. `mcpToolsWithGates` offers no MCP tool without its gate, and nothing a server says about a tool (its annotations, such as `readOnlyHint`) is an input to a gate. Sub-agents never get MCP tools.
- `use_skill` and `read_skill_file` never ask: they read only inside the folders of the conversation's usable skills (see Skills and project trust).
- `edit` / `multi_edit` enforce a read-before-edit invariant: the model must have read the file earlier in the session.

Auto-send after approval uses `lastAssistantMessageIsCompleteWithApprovalResponses`.

## Skills and project trust

Skills (`src-tauri/src/modules/skills/`, `src/modules/skills/`) are folders with a `SKILL.md`: instructions the model follows, with optional reference files and scripts. They come from Oarlock's own skills folder (the app config folder's `skills/`), `~/.claude/skills`, and an open project's `.claude/skills` and `.oarlock/skills`.

- **Their text is untrusted input.** The system prompt lists each enabled skill's name and description and says a skill's text never overrides the instructions, the safety rules or the approval mode; `use_skill` returns the instructions with the same note. Nothing a skill says changes `TOOL_GATES`.
- **Reads are confined to the skill.** `use_skill` and `read_skill_file` go through `skills_load` and `skills_read_file`, never the file commands: the backend resolves the skill by its id among the skills the conversation may use (valid, on, trusted, not overridden), takes a relative path of plain names (no `..`, no root, no drive), and reads only a regular file whose real path is inside the skill's real folder, so a link leading out is refused. Text only, 1 MiB per file. The secret-path deny-list still applies (`read_skill_file` checks it first). These reads need no approval and are not limited by the authorized folders or the AI's "all folders" switch: a skill folder is not part of the workspace, and only skill folders can be read this way.
- **Scripts run through the shell tools.** A skill's script is a `bash_run` or `bash_background` command like any other: it asks in Ask mode, runs in Auto-approve outside plan mode, and the command deny-list applies. It runs with the user's rights and is not limited to the authorized folders, which Settings > Skills says plainly. `allowed-tools` in a skill's frontmatter is ignored (Settings shows a note).
- **Project content needs the user's trust.** `project_trust.rs` keeps one record per project folder (by its real path, in `project-trust.json` in the app data folder): for each item the project provides (`AGENTS.md`, `.claude/skills`, `.oarlock/skills`, `.mcp.json`), allowed or declined, with the SHA-256 of the item's tree (every entry's relative path and kind, each file's content and each link's target; links never followed; over 10,000 entries or 64 MiB it cannot be reviewed and is never used). A file's digest is reused only while the file keeps the size, modification time, change time and identity (inode on Unix) it had when it was read, and only when it had been left alone for three seconds by then, so a same-length edit is always read again: one made within a filesystem's timestamp granularity (two seconds on FAT), or one that restores the old modification time (an archive extracted over it, `cp -p`), which no program can do to the change time. Files are opened without waiting, so a pipe in a project item cannot hold a hash up. A project's skills are listed, loaded and read only while the record allows the item with its current hash, checked on every call; a change asks again, unless Oarlock made it itself (below). A decision is stored only for the hash the user was shown (`project_trust_decide` re-hashes and refuses a stale answer). Every skill folder of a project item must really be inside that item, so the hash covers everything the skills hold; a link out is an invalid skill. The prompt (`ProjectTrustPrompt`, loaded only when needed) lists what each item provides (`AGENTS.md`'s size, line count and first lines, skills, or each MCP server's command and URL); Settings > Skills decides and forgets a project's `AGENTS.md` and its skill items and lists every decision, Settings > MCP decides and forgets its `.mcp.json`. A project opened at the home folder does not offer `~/.claude/skills` as a project item.
- **Project instructions.** A project's `AGENTS.md` is the system prompt's project section on every AI run, so it is an item of the same trust (`ItemKind::AgentsMd`, `project_memory.rs`), hashed by the file's content (SHA-256). Its inspector reads the file in chunks (any size, never held whole) and shows the size, the line count and the first eight lines as plain text (control, bidirectional and zero-width characters removed, 160 characters a line); not UTF-8 text, containing a NUL byte, not a regular file or a link out of the project: listed as not usable and never sent; empty or blank: nothing to ask. There is no size limit: the model gets the whole allowed file, and the prompt shows its size before the user allows it. The page never reads it for the model: `project_memory_read` reads the file once in the backend and returns its text only for the calling window's open project (the run's workspace root must resolve to that project), only when the AI's file tools reach its real path (the workspace registry's gates for origin `ai`, as `read_file` would), and only when the record allows the hash of exactly the bytes read, so there is no gap between the check and the read. A file larger than the run's model could take (its context at four characters a token and four bytes a character) is hashed in chunks and only its size is returned, and the run fails saying it does not fit. Anything else (undecided, declined, changed, revoked, missing, refused) means the run has no project memory and goes on; the page keeps no copy, so a decision or a change takes effect on the next run.
- **Oarlock's own edits keep the answer, for every item.** The editor's save (and autosave and Overwrite), the explorer's New File and New Folder, and the AI's file tools (`write_file`, `edit`, `multi_edit`, `create_directory`, plan mode's Apply, `/init`), each approved by the user or run under Auto-approve, go through `fs_write_file`, `fs_create_file` and `fs_create_dir`, which run the change through `project_trust::keeping_trust`, one path for every kind of item. When the change's real target lands in an item of a project a window has open (an `AGENTS.md` or `.mcp.json` written or created at the item's real path, so a link inside the project counts; any file or folder made inside `.claude/skills` or `.oarlock/skills`, including the folder itself), it reads what the item held right before the change from its bytes (a file item streamed, a folder item's whole tree, never a digest kept from earlier, so a stale cached hash can never be recorded), makes the change, and records as allowed the item as that reading plus the bytes written leave it: what anyone else wrote meanwhile is not in that hash, so it still asks. It does so only if the record allowed the previous content, or the item held nothing (absent, blank, a `.mcp.json` declaring no server, a skills folder holding only folders); the record is checked again under the trust store's lock, so a decision withdrawn during the change holds, and such changes are serialized. Declined content, content that changed outside Oarlock since the decision, content that could not be read or reviewed (too large, a link out of the project), and files already in a skills folder that no decision covered (a script with no `SKILL.md` yet, so nothing was asked) are never carried over. Content Oarlock itself wrote that cannot be used (a half-typed `.mcp.json`, an `AGENTS.md` holding a NUL byte) is recorded like any other, so the next save keeps the answer; it is never used, whatever the record says. Every other change asks again: git, another editor, a shell command (the agent's included), an MCP server, a coding agent, and the explorer's rename, move, copy, paste or delete. No command lets the page mark content allowed without the prompt. For `.mcp.json` this keeps only the file's answer: a server's Trusted switch and its tools' Always allow choices are kept in the page with the hash of that server's own entry and lapse when the entry changes, whoever changed it, since they decide whether its tools run unasked and an edited command must not inherit them.
- **Installing.** Git installs clone through the app's git runner (`run_git`, 120 s) with only the `https` and `ssh` transports (`protocol.allow=never` plus each allowed one; `file://`, `ext::`, plain `http://` and `git://`, local paths and a user name or token in an https address are refused before git runs), shallow, into a staging folder inside Oarlock's skills folder. Zip installs open a file the user picks in the system dialog the backend shows (the page never names the zip): at most 64 MiB, 5,000 entries and 128 MiB extracted (counted while writing), entries must be plain relative names (no `..`, absolute paths or drives) and links or encrypted entries refuse the whole archive. Every skill found is validated (its `SKILL.md`, at most 2,000 files and 64 MiB, links only to files inside it) and only the ones the user then picks are moved into place by name, a replaced one going to the trash first. Deleting works only in Oarlock's folder, moves to the system trash (the user confirms a permanent delete when there is none) and removes only the link of a linked skill folder.
- **Editing.** Edit hands the `SKILL.md` to the app window in front (`skills_edit`), which first lets the file commands reach the skill's folder as when the user opens a file (`authorize_opened`), so the editor can read and save it wherever the folder is. Saving a project skill there is Oarlock's own edit and keeps the project's answer.

## SSRF and DNS rebinding defense

`src-tauri/src/modules/net.rs` proxies AI provider requests and local-model pings. Before connecting:

1. Resolve the hostname once (`resolve_and_classify`).
2. Classify every resolved IP as public, private, loopback, or blocked metadata (`net/ip.rs`). An IPv6 address that carries an IPv4 destination (`::ffff:a.b.c.d`, `::a.b.c.d`, NAT64 `64:ff9b::/96`, 6to4 `2002::/16`, Teredo) takes the class of the embedded IPv4, and anything outside global unicast `2000::/3` (unique-local, site-local, link-local, multicast, documentation) is never public. Redirect targets are classified the same way.
3. Block cloud metadata endpoints (`169.254.169.254`, `metadata.google.internal`, AWS IPv6 metadata, etc.).
4. Pin reqwest to the resolved IPs so a second DNS lookup cannot return a different address (DNS rebinding).

Local LLM endpoints are explicitly allowed because the user opted in by pointing Oarlock at them, but they are still classified and logged.

AI, MCP HTTP and preview-image requests also carry a native-issued page generation
(`net/page.rs`). Native retires the previous generation on navigation and removes
it on window destruction, cancelling registered requests under the same lock as
admission. Native delivers the replacement token only when the document finishes
loading; an old page cannot query a replacement through delayed IPC. Start, cancel
and credit commands require the current token and calling window. Frontend waits
are abortable and fail visibly after 30 seconds if initialization never arrives.
This prevents queued work from a retired page from registering; it does not make
already-dispatched network effects reversible or terminate an OS DNS resolver
thread that has already started.

Guarded native hostname resolution uses the system resolver, preserving system
hosts files, VPN and split-DNS configuration. A shared gate permits 8 active OS
lookups and 32 waiting callers; further calls fail with a busy error. Each DNS
caller has a 10-second deadline covering its queue wait and lookup. Cancellation
or timeout removes queued work, but a running OS lookup retains its slot until
it exits. This bounds retained resolver work without pretending it is forcibly
cancellable. IP literals bypass the resolver. No additional DNS cache or resolver
dependency is used; returned addresses still undergo classification and pinning.

Non-streaming native operations have total deadlines: 5 seconds for connection
probes, 20 seconds for preview images and 30 seconds per OAuth HTTP operation.
One deadline covers DNS queueing/resolution, redirects, headers and body reads;
probes finish at headers. Expiry drops the request future and response body,
while a running OS lookup retains its DNS permit until it exits. The separate
five-minute interactive sign-in allowance is unchanged. AI and MCP event streams
retain their streaming lifecycle rather than inheriting these total deadlines.

Endpoint Test probes also require the native page generation. They register before
starting DNS or HTTP work and share a separate eight-probe app-wide limit, with no
waiting queue. URL edits, retesting and card collapse/unmount cancel the exact
probe; native reload/close cleanup retires the page and cancels its probes.
Registration acknowledgment is separate from completion, allowing cancellation
that overtook admission to be repeated immediately after admission.

Automatic MCP OAuth metadata discovery uses its own eight-request app-wide gate
and page-generation ownership. Settings tracks at most 256 current candidates,
matching the native status-query limit, and starts at most eight at once. Cancelled
work retains its running slot until it settles. Page retirement, server edits or
disablement and sign-in/sign-out cancel the affected discovery; queued stale pages
cannot register. Native configuration validation rejects disabled or stale global
servers and revalidates project trust/entry identity before publishing metadata.
Publication and cancellation share the probe registry lock. Configuration updates
also cancel native discoveries independently of UI event delivery. Errors are
scoped to their configuration and offer explicit Retry. HTTP 5xx and 429 responses
fail discovery rather than being cached as absence; 404 keeps its absence behavior.
Interactive sign-in and token refresh remain separate from this automatic gate.

AI and MCP reserve their existing request slots and validate page ownership before
copying uploads out of the IPC buffer. Body-decoding failures release that slot.
This bounds the native handoff copies; it does not cap Tauri's incoming IPC buffers
or frontend request-body preparation before native admission.

The Markdown preview's remote images go through the same checks (`net/image.rs`): https only, public addresses only, and redirects are followed by hand so every hop is validated, classified and pinned again. The webview's CSP loads no remote images at all, because AI chat Markdown renders in the same webview and an image URL in a prompt-injected answer would send data out without a click; only the preview of a file the user opened asks the backend for its images.

Formulas and diagrams in that Markdown are untrusted too. KaTeX runs with `trust` off, so `\href`, `\url`, `\includegraphics` and the `\html*` extensions render as errors, never as links or markup. Mermaid runs at its strict security level with labels as SVG text, and a diagram's own `%%{init}%%` directive or front matter cannot turn HTML labels, DOMPurify settings, theme CSS or fonts back on (`MERMAID_SECURE_KEYS`); links are removed from its output so a click never navigates the webview, and an image shape's remote URL falls to the same CSP (`src/modules/markdown/mermaidRender.ts`, `mathPlugin.ts`).

## MCP servers

MCP servers (`src-tauri/src/modules/mcp/`, `src/modules/mcp/`) are programs and services the user adds in Settings. Settings says so in plain words: a local server is a program running with the user's rights, outside the folder limits Oarlock applies to its own file features and the agent's file tools, and a remote server receives whatever the agent sends it. The protections are about Oarlock's part:

- **Approval.** Every call of an untrusted server's tool asks, even in Auto-approve; trusting a server is an explicit switch per server, and per-tool Always allow and Never allow are explicit too (see the approval flow above). The approval card shows the server, the tool, its arguments and the server's annotations, labelled as the server's claims.
- **Untrusted results.** A result is capped (text 50,000 characters, at most four images within size limits, anything else a note), marked as external in the transcript, and the system prompt tells the model that MCP results are data, never instructions, and never change approvals. A server's instructions are passed on as the server's words. Tool descriptions and schemas are capped.
- **Processes.** A local server starts only from an app window, with the command the user configured, resolved through the user's shell environment (a relative command, such as `./serve.sh` or `bin/serve`, only in the server's own working folder or a project server's project folder, never in Oarlock's working folder or a home folder it merely defaults to); it leads its own process group (Unix) or job object (Windows), stops with its window (reload or close) and with the app, and its stderr goes to a bounded in-memory log. A message over 16 MiB stops it.
- **Network.** A remote server is reached only through the backend (`mcp_http_stream`): every request must stay within the origin the user configured, goes through the SSRF classification and DNS pinning of `net.rs`, may reach private or loopback addresses only when the configured host itself is local or private, and is never redirected by the backend; the client follows a redirect only within that origin, as a new checked request. A server cannot make Oarlock fetch another host (a legacy SSE server's endpoint on another origin is refused by the client and by the backend).
- **Secrets.** Environment variables and headers marked secret live in the keychain under the service `oarlock-mcp` (32 KiB each at most; see Secret storage for long values on Windows). Settings writes them (`mcp_secret_set`, only from the settings window); the backend reads them only when it starts the server or opens its session; no page can read them back, because `secrets_get` and `secrets_get_all` refuse that service. The configuration store holds only their names.
- **Sign-in (OAuth).** Remote servers that need it are signed in to by the backend (`mcp/oauth/`, the MCP authorization specification, revision 2026-07-28), so the page never holds a token:
  - A server is "sign in required" when a request without a token gets a 401 with a `Bearer` challenge, when its token is refused and cannot be refreshed (the backend marks that 401 with `x-oarlock-sign-in: required`, and the window's client then waits instead of reconnecting), or when it publishes protected resource metadata (Settings probes each enabled remote server once). A 403 with `insufficient_scope` asks to sign in again for the union of the granted and the requested scopes.
  - Only the settings window may sign in, cancel or sign out (`mcp_oauth_*`); app windows have no command that starts a sign-in or returns a token, and `mcp_oauth_status` returns state, issuer, scopes and expiry only (a test serializes a status built from tokens and checks no token is in it).
  - Discovery follows the specification: the `resource_metadata` URL of the server's challenge, else the RFC 9728 well-known URIs (path, then root); the metadata's `resource` must be the configured server's origin with a path the server's path is within (else it is not used); the first usable `authorization_servers` entry; its RFC 8414 / OpenID Connect metadata in the specified order, whose `issuer` must be the one asked for (a terminating slash aside) and which must list `S256` in `code_challenge_methods_supported`, or sign-in refuses. A server with no resource metadata falls back to its own origin as authorization server (earlier revisions).
  - Every sign-in request (metadata, registration, token, refresh) goes through `oauth/fetch.rs`: https only (plain http only to a loopback host, and only when the configured server is itself a plain-http loopback URL), no user info or fragment, never a metadata host, the `net.rs` classification and DNS pinning with private addresses only when the configured server's host is private, no redirects but same-origin ones on GETs (each checked again), 1 MiB responses, 30 s. The URLs are only those the metadata names; the browser URL is checked the same way before the opener plugin opens it.
  - The client is the one the user configured (client ID, an optional secret in the keychain as `<server>/oauth/client-secret`, scopes, a fixed callback port), else one registered dynamically (RFC 7591: a public native client, `token_endpoint_auth_method` `none`, `application_type` `native`) and kept per server with the issuer and redirect URI it was registered for; a later sign-in reuses it only for that issuer, binding its port again when it can. Client ID metadata documents are not used: they need an https document Oarlock would host.
  - The redirect is a one-shot listener on `127.0.0.1` (a free port, or the registered one) at `/callback` (RFC 8252). It answers only a GET to `/callback` whose `state` (32 random bytes, compared in constant time) is the one it waits for; anything else gets a short error page and is ignored, so a local page probing the port can neither end nor answer the sign-in. The response's `iss` is checked as RFC 9207 and the specification tabulate (a mismatch is refused and its `error` never shown); the code is exchanged with the PKCE verifier and the RFC 8707 `resource` (also sent on the authorization request and refreshes). The page the browser shows carries no code or token, escapes what it shows and forbids scripts. Sign-in ends after five minutes, on Cancel, or when another one starts.
  - Tokens and the registration live in the keychain under `oarlock-mcp` (`<server>/oauth/tokens`, `<server>/oauth/client`), split on Windows like every long value (see Secret storage); `secret_account` can never name them, so `mcp_secret_*` cannot touch them. Tokens are bound to the server URL they were obtained for (a changed URL does not get them; Settings also signs out when the URL changes or the server is removed). The backend adds `Authorization: Bearer` to that server's session requests only when its configuration sets no `Authorization` header of its own, replacing anything the page sent, marked sensitive. It refreshes the token a minute before it expires, and once on a 401 (one refresh at a time per server); a refused refresh deletes the tokens, any failure reports sign-in required. Token values never reach a log: the records' `Debug` output omits them and error messages carry only the OAuth `error` and `error_description`, cleaned and capped.
- **Import.** `mcp_import_scan` (settings window only) reads exactly the files Claude Desktop (`claude_desktop_config.json` in the platform configuration folder), Claude Code (`~/.claude.json`, user scope, streamed), Cursor (`~/.cursor/mcp.json`) and VS Code (`settings.json` `mcp.servers` and `mcp.json` in its `User` folder, JSON with comments) keep their servers in, and returns parsed entries only, never the files. A value that looks like a secret (by name or look: keys, tokens, passwords, credentials in URLs, long opaque strings) is withheld; `mcp_import_secrets` reads the entry again, checks its fingerprint is the one the user saw, and writes those values to the keychain under the new server's id. VS Code `${input:...}` values become secret values the user enters; `${env:NAME}`/`${NAME}` passed through under the same name are left to the shell environment; other variables are kept as written, with a note. Imported servers start disabled and untrusted, with `source` `imported:<app>`.
- **Project servers.** A project's `.mcp.json` (Claude Code's format) is an item of the shared project trust (`ItemKind::McpJson`, see Skills and project trust): its inspector lists each server's command line or URL and the environment variables it reads, hashed by content (over 1 MiB, invalid, or a link out of the project: never used). Its servers are listed (`mcp_project_servers`) only for the windows that have the project open, only while the user allows the file's current content, and never trusted automatically: the Trusted switch and Always allow choices are kept per server with the hash of that server's own entry and lapse when it changes (Off and Never allow hold). The backend starts them itself from the file (`mcp_project_spawn`, `mcp_project_http_open`), never from the page's copy, expanding `${VAR}` and `${VAR:-default}` from the shell environment (a variable that is not set stays as written and is logged), in the project's folder with `CLAUDE_PROJECT_DIR`; their values never pass through the page (but the expanded URL of a remote one, which the client connects to) and nothing is written to the keychain. Every message and request of a running project server checks again that its window still has the project open, that the user allows the file's current content, and that this content declares the server exactly as it started (the hash of its own entry); otherwise the server stops. An allowed edit elsewhere in the file (Oarlock's own edits keep the trust) leaves it running. A WSL project's local servers are not started.
- **Configuration.** `oarlock-mcp.json` is a plain-named store in the app data folder; a damaged entry is dropped, never started. Imported and project servers start untrusted.
- **Resources and prompts.** What the user attaches from a server (a resource under `@`) or runs (a prompt as `/<server>:<prompt>`) is the server's text: it travels in an `<mcp-resource>` or `<mcp-prompt>` block that names the server and tells the model it is the server's data, not the user's instructions, and that it never changes the rules or what needs approval; closing tags inside are escaped so it cannot end its block. Chips in the composer and the transcript name the server. A resource is capped like a file attachment (200 KB of text, images within provider limits, other binary content refused); a prompt over 200 KB of text is refused. Names, titles and descriptions a server lists are shown without control or bidi characters and capped, and an address with control characters or over 2,048 characters is not offered.
- **Sampling.** A server's `sampling/createMessage` never runs on its own: in every approval mode and for a Trusted server alike, it opens a dialog in the window whose client received it, showing the server, its messages and system prompt (editable), max tokens (capped at 8,192 whatever the server asks), its model preferences, and whether it asked for context, which Oarlock never includes. Only Approve runs it, with that request alone (no conversation, no tools, no Oarlock instructions) on the user's key, and the reply goes back only after a second approval of the text (editable). Deny or closing returns the spec's rejection. It is refused while the window has no composer to show it, while another request from the same server waits, and when it asks for tools, audio or images a provider refuses; it ends when the server cancels it or stops.
- **Elicitation.** A server's request for information (form mode) is shown in the chat with the server's name, its message as its words (no clickable links) and a warning not to enter passwords, keys or payment details; nothing is sent until the user submits, and Decline and Dismiss return the spec's actions. Values are checked against the schema first. Only the spec's flat primitive fields are supported; anything else is refused with the reason, URL mode is not offered (the SDK refuses it), one request per server waits at a time, and it ends when the server stops.

## Secret storage

API keys are stored via `secrets_*` commands (`src-tauri/src/modules/secrets.rs`):

- macOS: Keychain via `keyring-core`
- Windows: Credential Manager via `keyring-core`
- Linux: a JSON file in the app's local data dir with mode `0600` (atomic write to `.tmp` then rename, under the store's lock)

A value is at most 32 KiB; a longer one is refused with that limit in the error. Credential Manager holds at most 2,560 bytes of UTF-16 per item, so on Windows a longer value is split into a head item under the account (`\x01oarlock-chunks:<count>:<digest>:` and the value's start) and items `<account>:1` to `<account>:<count - 1>`; the Keychain and the Linux file hold any of these lengths and never split. A value that fits in one item is stored exactly as earlier releases stored it, so they read it after a downgrade. Reads join the chunks only when the digest (SHA-256) of the whole matches, so a lost or mixed chunk reads as not set, never as another value; a value that itself starts like a head is always written as one, so it cannot be misread. Writes put the chunks first and the head last and remove stale chunks; deletes remove every chunk. Pages cannot name a chunk account.

Service constant: `oarlock-ai`. Keys never touch disk outside the keychain/Linux secrets file, never go in `localStorage`, and never appear in logs. MCP secret values use the service `oarlock-mcp`, which the `secrets_*` commands refuse: only the backend reads them (see MCP servers above).

## Language server docs

Hover and completion docs come from the language server, which takes them from comments in the project and its dependencies. The LSP library renders them with `marked.parse` into `innerHTML`, so `src/modules/lsp/lib/safeMarkdown.ts` sets that shared `marked` instance's renderer when the LSP client loads: raw HTML in the docs is shown as text (no iframes, forms or styles), links keep only `http`, `https` and `mailto` targets and open in the browser through the opener plugin (`target="_blank"`), never in the app's window, and images become their alt text.

## OSC trust gating

The terminal parses OSC sequences from the PTY byte stream:

- **OSC 7** updates the tab cwd, only between commands and, on Linux and macOS, only once the backend has matched it to the folder the shell or its foreground job is in (see the registry above).
- **OSC 133 A/B/C/D** marks prompt/command boundaries.
- **OSC 777** is used by the agent detector to signal coding-agent state transitions.

The agent detector (`src-tauri/src/modules/pty/agent_detect.rs`) is armed by `OSC 133;C;<cmd>` or by a self-armed marker and emits `oarlock:agent-signal` events. It is driven **only by OSC sequences**, never by raw output, so a repainting TUI never flaps. The agent name a marker carries is untrusted: any name is shown, but only as plain text with control and bidi characters removed and at most 32 characters, with the generic icon unless it is exactly a known agent id. It never selects a command, path, hook file or icon file.

## macOS privacy controls

macOS privacy controls (TCC) sit below the registry: a folder the registry authorizes can still be refused by macOS, and TCC counts Oarlock and every program its terminals start as one app. Checking what Oarlock may reach never makes macOS ask: the status check (`mac_privacy.rs`) opens only files that Full Disk Access guards, which macOS refuses silently (`EPERM`) without that grant, and never the folders macOS asks about (Desktop, Documents, Downloads, iCloud Drive, removable and network volumes, other apps' containers). The page opens System Settings only at a pane the backend names (`SettingsPane`), never at a URL it supplies, so the opener's URL scope stays as it is.

## Invariants

- The deny-list in `security.ts` applies on both read and write. Never bypass it.
- New file-system-touching commands must pass every path the page sends through a registry gate (`authorized_existing`, `authorized_write_target`, `authorized_new`, `authorized_entry`).
- The page authorizes a path only for what the user chose, never for a path a terminal program or an AI reply named. A terminal's reported folder is authorized only by `pty_authorize_cwd`, which on Linux and macOS requires the OS to confirm the shell or its foreground job is there.
- The asset protocol's configured scope stays empty; files are granted at runtime (`asset_scope.rs`), never with `**`. Files outside the grants are served only by `oarlock-asset`, only while the app may access all folders, and never under a dot name.
- The "access all folders" switches widen only their own side: a command both use takes `origin`, the AI tools send `ai` on every file and shell call, a call without it is the app's, and neither switch authorizes a root.
- The page opens stores by plain names in the app data folder only (`store_scope.rs`); a new store gets a plain name.
- New network-facing commands must go through the `net.rs` proxy or reimplement the same classification and DNS pinning.
- New plugin APIs must be added to `src-tauri/capabilities/default.json`.
- Keys, tokens, and credentials stay in the keychain / Linux secrets file.
- An MCP tool is offered only with its gate; an untrusted server's tools ask in every mode, and server annotations never relax a gate. MCP requests stay within the configured server origin, and MCP secret values are read only by the backend.
- MCP OAuth runs in the backend: no command returns a token to a page, only Settings starts or ends a sign-in, sign-in requests reach only URLs the server's metadata names (https, checked and pinned), and a token is sent only to the server URL it was obtained for.
- A server's sampling and elicitation requests are answered only by the user, in every mode and for every server, trusted or not; a sampling result is returned only after the user approved both the request and the reply. Resource contents and prompt messages reach the model only inside their server-labelled blocks.
- Content a project provides (its skills, its `.mcp.json`) is used only while `project_trust` allows that item with its current content hash; untrusted project content never reaches the model and its servers never start.
- A skill's files are read only inside its real folder; a skill's text never changes approval.

## See also

- [`AGENTS.md`](../../AGENTS.md) - the architecture source of truth
- [`docs/README.md`](../README.md) - index of contributor guides
- [Two-process model](two-process-model.md) - IPC boundary and command catalog
- [AI subsystem](ai-subsystem.md) - tools, approval flow, and provider handling
