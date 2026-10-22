# Security

This document describes what the tool is allowed to touch, how that is enforced, how releases are
built and can be checked, how it was reviewed, and what was actually found and fixed.

This document describes the version this source tree builds, the one its
`.codex-plugin/plugin.json` names. Historical differences below name the release they apply to.
Unreleased source changes do not change any published release's bytes.

From v0.6.11 this tree builds two editions. Everything below describes the standard edition, and
holds for the advanced edition too unless a passage names it: the advanced edition's capabilities
are each off until a person turns one on, through the local bridge the Dashboard uses, and
[The advanced edition](#the-advanced-edition) says what each does, once it is on, beyond what the
rest of this page promises - and what its measurement harness does when a person runs it.

## Reporting

If you find a security issue, please open an issue on this repository.

This project operates no service of its own - no server, no endpoint, no telemetry - so there is no
vendor backend to notify. The only service the code this project ships contacts is GitHub
(github.com, and the GitHub storage hosts it redirects release downloads to), when setup downloads
a release and when you press *Check for updates* - which from v0.6.11 also reads this repository's
list of releases at api.github.com - or *Install another version...*, which reads that whole list
there, and, from v0.6.5, raw.githubusercontent.com, when you ask for
the compatibility data refresh. The Codex processes it starts talk to OpenAI with your
existing sign-in, as Codex does (see *No network code in the recovery runtime* below). A finding in GitHub or in Codex itself
belongs to that vendor's own reporting process, not here.

## What it touches

**Reads**, read-only for everything that is not its own:

- Codex's SQLite state (thread metadata, turn history, the queue), opened with `mode=ro`,
  `PRAGMA query_only=ON` and `PRAGMA trusted_schema=OFF`. SQLite takes its normal shared read
  locks while it reads.
- The conversation's rollout JSONL file, opened read-only: its first line, to confirm it is a
  desktop-app conversation, and, for a usage limit only, up to 8 MiB just before the failure,
  parsed in memory to find the reset time. That part of the file is conversation content.
  Only the reset time and the name of the limit it belongs to, taken from the rate-limit snapshot,
  are kept. Everything else is discarded, and nothing else from it is stored, logged or sent.
- Only when you press *Rescan and reconcile*, and only for a waiting recovery whose conversation
  Codex's history has not caught up with, that conversation's whole rollout file, up to 32 MiB (a
  larger one is not read), a line at a time, parsed in memory and dropped, to see whether a message
  of yours that carries no marker of this tool's follows the failed turn's end. That is conversation
  content too; only the yes-or-no answer is kept. It also lists the file names under the
  `sessions` folder, opening none, to follow a conversation Codex split across files.
- To prove its own message arrived, it has SQLite search that conversation's user messages and
  queued messages for this tool's marker. Only rows containing the marker come back.
- The recorded error of a failed turn. Its structured error type decides the category; only when a
  failure carries no structured error at all is its message matched against a short fixed list of
  transport failures. Either way, only the category name is kept.
- Its own state and settings.
- Windows process and Restart Manager information needed to identify the desktop app and its engine.

No prompt, assistant or tool content is kept in its state or written to its main log, apart from
the conversation title Codex shows, which may be derived from your first message: notifications
display it, and Windows keeps them in its notification history.

**Writes** while running:

- Files in its own `config/` and `logs/` directories, including the copy of the state file it
  takes before the first watcher of a new version upgrades the schema, and before
  `downgrade-state` rewrites it (`state.vN-backup-*.sqlite`), kept for forensics. From v0.6.5
  that includes two compatibility files, each with one writer: `config/compatibility.json`, the
  watcher's report, written atomically under the lock the watcher already holds; and
  `config/compat-cache.json`, the Codex compatibility data a person asked for, written only by the
  validator (`controlcli compat-import`) and only after a document passed it. From v0.6.8 it also
  holds `config/failure-seen.json`, one time - when a person last saw a failed recovery - which the
  watcher, the popup and the window write through a temporary file under one named lock, and which
  decides nothing but whether the icon is red. From v0.6.9 `logs/codex-start.log` holds one line
  each time Codex starts the plugin's MCP server and that server considers starting the watcher:
  what Windows wrapped the server in and what was decided, in fixed words, with no path in it.
- Nothing, from the MCP server, since v0.6.9 measured what would happen: Codex runs each plugin's
  MCP server in a job object that ends what that server starts, so the server starts no watcher and
  writes one line saying so. Nothing else in the standard edition starts a process from inside
  Codex. In the advanced edition, *start with Codex*, once a person turns it on, is the one
  exception: the server then starts the watcher, through WMI where Codex's job would end it.
- One continuation message to one exact thread, through the official `codex queue` CLI. Its
  text is this product's message in the language and style you chose or, from v0.6.3, the
  Custom message you wrote in the Dashboard (see *The Custom message is written in the
  Dashboard, and nowhere else* below). In the advanced edition, the marker-free continuation and
  the goal continuation, each once a person turns it on, go through Codex's app server instead.
- When that message has to be withdrawn, `thread/queue/delete` requests to the official Codex App
  Server for that exact queued item, repeated if the withdrawal cannot be confirmed.
- The notifications it raises, which Windows keeps in its notification history. From v0.6.5 a
  notification can instead be drawn as the product's own card beside the notification area - two
  windows of its own that never take the focus - followed, once the card has been seen, by the same
  toast raised silently into that history.
- When you switch **Run at Windows sign-in** on or off in the window, its single `Run`
  value is written or removed.
- Only when you ask for it, one diagnostics JSON file at a path you choose, from **Export
  diagnostics...** in the window or `auto_resume.py diagnostics`. It holds versions, settings,
  every record's state, reason and the checks it is waiting on, the content-free journal (up to
  2,000 entries) and the last 300 lines of each log; conversation and interruption ids become
  aliases valid only inside that one file, and file-system paths, the Windows user name and
  anything shaped like an e-mail address are replaced. It refuses to overwrite an existing file,
  and nothing sends it. `errors.log` carries exception text this product did not write: that is
  redacted the same way rather than filtered, and the file says so at the top.

The Codex processes it starts (`codex app-server`, `codex queue`) may also update Codex's own logs
and caches, as any Codex process does.

**Writes** at install time, for the current user only and never system-wide: a Start Menu
shortcut, the sign-in autostart value unless you decline it, the notification sender identity
Windows requires before it will draw a toast at all, and the handler for the notification
button's own URL scheme, and, from v0.6.16, the entry in Windows' Add or remove programs: one per-user key
under `HKCU\Software\Microsoft\Windows\CurrentVersion\Uninstall` (`CodexAutoResume`; the other edition's adds its
word), naming this version and folder and the command that removes it, with a copy of the installer's own
uninstall, `uninstall\install.ps1`, kept in the installation for that command to name. Through the `codex plugin`
CLI it also registers a local plugin
marketplace and this plugin in your Codex configuration, and asks Codex to refresh
marketplaces. v0.5.7 and earlier releases run that refresh with no name, so Codex refreshes
every Git marketplace you have configured. From v0.6.0, it names this product's own marketplace
and refreshes only that one. Uninstalling removes all of these, under the ownership checks
described below.

**Writes** while updating or uninstalling, on this PC only, none of it sent anywhere. An update that asks an open
Dashboard to close has that window write its page and position to `config\reopen-after-update-<process id>.txt`,
which the installer reads once to open the new version where it was and deletes. The uninstall that Settings >
Apps starts copies the Dashboard program into a new folder of its own in the temporary folder,
`%TEMP%\CodexAutoResume-Uninstall-<random>`, so that the installation can be deleted while the window shows it;
the folder is removed once the copy has ended.

**Never reads**: `auth.json`, tokens, cookies, authorization headers, or process memory. The Codex
processes it starts use Codex's own stored sign-in; this tool never sees it.

**Never opens for writing**: a Codex database, rollout or configuration file. If a Codex database
uses SQLite's write-ahead log, SQLite may still update the shared-memory index file (`-shm`) beside
it while reading. Codex's state changes when the product asks official Codex interfaces to act:
`codex queue` (add one message), `thread/queue/delete` (withdraw that same message), and
`codex plugin` / `codex plugin marketplace` at install and uninstall (register, refresh or remove
this product's plugin and marketplace). The advanced edition asks for more, each only while
the capability that uses it is on, and only the methods that capability declares (the advanced package's
`codex/protocol.py`): adding one message to a queue with no marker, setting a goal the usage limit paused
active again, resuming, starting and interrupting a turn, compacting a conversation, reading the list of models and
putting a conversation's model back, reading usage and spending a reset credit. *Stop near a limit* also stops a
running turn through the Codex app's own channel, the `\\.\pipe\codex-ipc` pipe. Its measurement harness, when
a person runs a measurement by hand, asks for more whether or not any capability is on - among
them `thread/goal/set`, `thread/queue/add` with words this product wrote, and `turn/start` (see
*The measurement harness* under [The advanced edition](#the-advanced-edition)).

## Enforced properties

- **No network code in the recovery runtime.** No file under `src/` or `scripts/*.py` - nor, in
  the advanced edition, under its package's `advanced/src/` - imports a networking module, and a
  test fails if one gains an import of a networking module, so the
  watcher opens no connection of its own. That is a property of the code, checked by that test,
  not a sandbox. The advanced edition's compatibility report reaches GitHub only by starting gh, the
  GitHub CLI the person installed, when they ask in the Dashboard (*The compatibility report*, under
  [The advanced edition](#the-advanced-edition)). The traffic we know the product causes comes from elsewhere:
  - The Codex processes it starts ask OpenAI for your current usage (`account/rateLimits/read`)
    while a recovery is due. Codex identifies this tool to OpenAI by the client name and version
    the tool gives it: `codex_auto_resume` and `0.1` in v0.5.7; from v0.6.0, `codex_auto_resume`
    and the product's real version from the plugin manifest. These processes may also make
    Codex's own background requests (for example refreshing your sign-in), as any Codex process
    does. The resumed turn itself runs in your Codex desktop app, under your own Codex settings,
    and goes to OpenAI like any turn you start.
  - Setup: `scripts/bootstrap.ps1` downloads the release from GitHub over HTTPS and verifies it
    before anything in it runs. The installer then asks Codex to refresh marketplaces. In v0.5.7
    and earlier releases it names none, so Codex refreshes every Git marketplace you have
    configured, fetching from their hosts. From v0.6.0, it names this product's own marketplace;
    for the local marketplace it registers that is a no-op, and Codex fetches only if an earlier
    GitHub registration of that name is still in place.
  - When you use this plugin's tools, or ask Codex to run its commands, inside a conversation,
    what they return (status, pending recoveries with their conversation ids, and for the
    commands, local paths that include your Windows user name) becomes part of that
    conversation, which Codex sends to OpenAI like any tool output. `get_status` also says
    whether you have set an engine path (`codex_exe`), never the path itself, and in v0.5.7 it carried the install path, which contains
    your Windows user name; from v0.6.0, it no longer includes the install path. From v0.6.5 it
    also carries the Codex compatibility summary, as codes only - no version string, no path, no
    free text, and not what other people report about that version.

  There is no telemetry, and no update check runs unless you press the button for it: from
  v0.6.0 *Check for updates* makes one HEAD request to this repository's `releases/latest`
  page and reads the version out of the address it redirects to, never out of the page,
  which is not transferred. A redirect that leaves this exact owner and repository is
  refused, and the version is rebuilt from its three numbers before it can reach a download
  URL. This tool sends nothing to its developer; there is no
  service of the developer's to send it to.

  From v0.6.11 the same press asks one more question once github.com has answered, because
  `releases/latest` never names a pre-release: one unauthenticated `GET` to GitHub's list of this
  repository's ten newest releases
  (`api.github.com/repos/songyb111-gachon/codex-auto-resume-windows/releases?per_page=10`), with no
  redirect followed and nothing about the machine in it. It is the one body the update check
  parses, and it is read for one thing: the newest published pre-release - not a draft, tagged
  `vMAJOR.MINOR.PATCH-alpha` or `-beta` with a stage's number - that is newer than both the version
  installed and the newest release. A list that cannot be read, is over 2 MiB, is not a list or
  has not arrived within the time the check has left - a deadline for the whole request, not only
  for its first byte - offers nothing and changes nothing else in the answer. What it finds is only
  offered, and only where there is no release to offer first, in a question whose default button is
  *Not now*: a pre-release is installed only when you say yes, and the yes asks both questions
  again, so a release published while the question was open is reported instead and nothing is
  downloaded. It is installed only while the list still names it as published and it is newer than
  the newest release, only over an older version, in the edition you have and with your state
  kept, and - since no pre-release is ever pinned - verified against the `.sha256` published beside
  it, the trust-on-first-use case `docs/PLUGIN.md` describes. The watcher, the panel and the MCP tools
  never install one.

  *Install another version...* on the same page is the bootstrap too (`-Versions`, then `-Pick`),
  started by the window only when a person presses the button and again when they confirm a row;
  building its dialog starts nothing, so the window audit never asks GitHub. It reads the whole list
  of releases from a second api.github.com address on the same path - thirty to a page, at most five
  pages, the page number the one thing put in, each page under the same size, redirect and host
  checks and a deadline inside one budget - and any page that fails lists nothing, as does a fifth
  page as full as the rest, which more may follow. A picked version
  never reaches a URL as typed: it is rebuilt from its integers by the version rule, the row must
  still be offered exactly as it was shown when the list is read again, and `-Force` is required for
  an older version or the other edition and refused for anything else, so a stray `-Force` never
  widens a pick. The archive is downloaded, checked against its pin or its published `.sha256`,
  tested and unpacked as every install's is, and only then is the install lock
  (`Local\CodexAutoResume.Install`) taken; a lock held elsewhere installs nothing. For a version that
  reads an older state, the installed version's own `downgrade-state --to 3 --stop-watcher` then asks
  the watcher to stop and waits a minute at most - it is never killed, and a watcher that has not
  stopped gets nothing installed and the state left as it was, though the request stands and it may
  stop later, with nothing to start it again - converts the state in one transaction after a copy, and
  answers on one closed line that must agree with its exit code. A conversion that fails starts the
  installed watcher again and installs nothing. Only then does the archive's installer run, with the
  edition change passed to it only on a change and only to installers that know editions. While it
  runs, the window greys every action button, the header's Start watcher included, so the window
  cannot start the current watcher between the conversion and the installer. Nor does reading the
  state put it back meanwhile: while an installation holds its lock, the window, the panel, Codex's
  tools and the command line - a notification's Cancel, a status from Codex's skill, an installer's
  own setup - read an older state as an older watcher's and never upgrade it; only a watcher, at its
  start, does. A window or an MCP server left open from before the pick leaves it as it is after the
  lock too, once the older version's installer has replaced the files it runs from. Nor can the control
  layer start the current watcher meanwhile: while an installation holds its lock, the bridge's
  `start-watcher`, which the window's Start watcher sends, and Codex's `start_watcher` tool refuse
  (`start_failed`) and start nothing, as the start with Codex always has. The bootstrap's only
  registry access is a read of the two policy keys' value names: while any policy value an older
  version would stop applying is there - every one but `DisablePowerAction`, which holds back what no
  older version has - or a key cannot be read, no version before v0.6.11-beta is offered.

  No compatibility refresh runs unless you ask for it either. From v0.6.5 the Codex
  compatibility data refresh happens at exactly two moments: *Refresh compatibility data* on the
  Diagnostics page (`scripts/bootstrap.ps1 -Compatibility`), and a *Check for updates* that
  github.com answered, whether or not an update exists - and even then only while enough of the
  check's time is left, so it never makes the update answer late or changes it. It is the
  bootstrap again, never the watcher, and no MCP tool can start it. It makes one HTTPS `GET` to
  one constant URL - this repository's `src/codex_auto_resume/data/codex_compat.json` on `main`,
  at raw.githubusercontent.com - with no query string and nothing about the machine in it; a
  download that ends on any other host is refused, and one over 256 KiB is refused before the
  validator is started. The body goes to a temporary file the bootstrap deletes afterwards, and is
  never parsed or run by PowerShell: it is handed to this installation's own Python validator,
  which is described under *Compatibility data can only restrict* below.
- **No shell, and no values in script text.** No Python code uses `shell=True`, `os.system`, `eval`
  or `exec`, and every Python subprocess gets an argument list. Windows PowerShell runs the
  installer, the uninstaller and the plugin's setup script; the Python runtime uses it to list
  ChatGPT and Codex processes (a fixed script) and raise notifications, and at setup to create the
  Start Menu shortcut. The last two receive their values - toast text, shortcut paths - as
  environment variables read by a constant script (`src/codex_auto_resume/pwsh.py`). PowerShell
  does not parse an environment variable's value as code, so no character in a conversation title
  or a folder name can change what runs. The Python runtime starts PowerShell by its full path under
  `%SystemRoot%\System32`, and `Install.cmd` and `Uninstall.cmd` call both `chcp` and PowerShell the
  same way, so a program of the same name sitting beside them is not run instead. The two small
  Windows programs start the bundled Python with a command line quoted by the `CommandLineToArgvW`
  rules.
- **Its own code, found by path.** This is new in v0.6.0. The skill tells Codex (an instruction, not a check) to run the setup script by its
  absolute path inside the plugin, not as a relative `scripts/bootstrap.ps1`, which would resolve
  against the user's project and could run a script of the same name from it. The sign-in launcher
  starts the installed application; its fallback, for installations older than the application
  directory, searches Codex's plugin cache only under this product's own marketplace
  (`codex-auto-resume-windows`), and the only other copy it will start is the one recorded when
  setup ran. If neither qualifies, the launcher logs that no engine was found and starts nothing.
  In v0.5.7 the skill gives the relative path, and the fallback accepts a same-named plugin from
  any marketplace in the cache.
- **Exact thread only.** Thread ids must be canonical UUIDs. `--last` is never used.
- **No secrets in logs or state.** Engine events are logged from a fixed message table, with
  untrusted values masked unless they are hex or digits. Prompt text, error text and account
  identifiers are discarded at parse time. From the usage response, only numeric usage windows,
  reset times and the limit bucket's name are kept; from an error, only its category.
  A few lines outside the table record local facts: the main log records the state directory's
  path, which contains your Windows user name, and the engine's version string - in v0.6.4 and
  earlier only for an engine this tool was not verified against, from v0.6.5 for every engine,
  beside the Compatibility Registry's codes for it. Tracebacks go only to a separate error log
  (`errors.log`), and the main log records the exception class name only.
- **Fail closed.** Unknown loaded state, unknown usage, an unavailable probe, a corrupted state file
  or, from v0.6.5, a compatibility evaluation that could not run results in waiting or refusing,
  never in sending.
- **No duplicate resume.** The interruption is durably reserved (SQLite, `synchronous=FULL`,
  `BEGIN IMMEDIATE`) before any external process can accept a message. If the result of a send is
  ambiguous, the record enters `submission_unknown` and is never resent. The watcher keeps checking
  it for 24 hours, and if the message turns out to have arrived it is matched to the exact turn
  it started and follows that turn to its outcome. (`resumed`, the name v0.5 wrote on delivery,
  is kept so old rows stay valid and is never written now.)
- **Observe only sends nothing, twice over.** From v0.6.11 Observe only is refused by the watcher on
  the setting and by the claim itself on the state's own switch, which the setting is written into, so
  either one alone stops a send the other has not heard of yet. What a conversation seen for the first
  time gets and which projects may resume only ever hold an interruption for a person when it is
  detected, and a project that cannot be read is held; a project is only a digest, it narrows what
  may be sent and never names a conversation, whose identity stays its exact UUID.
- **The waits and the guards only hold back.** From v0.6.11 the Custom retry waits are picked from
  closed lists, the second to fifth starting at the engine's own 15-minute floor, which with the five
  continuations a day stays a constant of the engine, not a setting; jitter and a named Retry-After only
  lengthen a wait, and the time ceiling only stops a task sooner. The task-changed guard reads a
  folder's `.git/HEAD` as a file - git is never started - and never a share path, and keeps only a
  digest; the context-cost guard reads one number of Codex's, and only where it is a numeric column.
  A guard's hold is a hold like any other: the claim and the last look before the send refuse it, and
  only Let it continue, bound to the exact record, lets it go. Each is off by default.
- **An administrator's policy keys only hold back.** From v0.6.11 seven values under
  `Software\Policies\CodexAutoResume`, in `HKEY_LOCAL_MACHINE` or `HKEY_CURRENT_USER`, are read and
  never written - `startup.py` is still the only code that writes the registry - and applied after the
  settings are read, never to the file: they can pause recovery, force Observe only, turn off the update
  check or the status file, lower the attempts' ceiling, add quiet hours and, from v0.6.12, turn the power action off, and nothing else. Both
  places' restrictions hold, a malformed value is ignored, one that is there and cannot be read holds the
  most it could, and a write that would loosen one is refused.
  `DisableAutoResume` is written into the state as a Pause before every check and refused by the engine
  on the key as well. They are what a cooperating installation obeys, not a lock: the program is the
  person's own, in their own folder, and a copy run from a source checkout reads none.
- **Path confinement.** Owned directories are rejected if they are links, or if they resolve outside the
  configured home. The resolve-based check also catches NTFS junctions, which `is_symlink()` does not.
- **No contention with the app's thread lock.** There is no byte-lock API anywhere in the adapter.
  Loaded state is determined purely from the Restart Manager inventory, so the tool never takes
  the app's own thread writer lock. Reading Codex's databases uses SQLite's normal shared read locks.
- **Least privilege.** No administrator rights are required. Optional autostart writes a single value
  under the current user's `Run` key. No service, no scheduled task, nothing system-wide. From
  v0.6.11 **Keep this PC awake while a task waits**, off by default, is the watcher's own request to
  Windows (`SetThreadExecutionState`), which it takes back when nothing waits, after the hours chosen
  (with Unlimited, not while a task waits), on a pause and when it stops, and which Windows ends with
  the watcher; no power setting is changed, and nothing wakes a sleeping PC. The memory guard (from
  v0.6.11, off by default) stops the watcher itself, between two checks, through the same stop a
  person asks for; it leaves with an exit code
  of its own that the sign-in launcher never starts again, and the standard edition has no
  supervisor or other process that would. A status file for other tools (off by default) is a file
  in the watcher's own `config\`, written whole: no port is opened and nothing listens.
- **The power action asks Windows, and starts nothing.** From v0.6.12, off by default and turned
  on only in the Dashboard, the watcher can put the PC to sleep, hibernate it or shut it down once
  every usage-limit recovery has ended. It is the watcher's own call of `SetSuspendState`, or of
  `ExitWindowsEx` with `EWX_POWEROFF` and no `EWX_FORCE` or `EWX_FORCEIFHUNG`, so every program may
  refuse a shut down and Windows then does not shut down. Before the call it enables
  `SeShutdownPrivilege` on its own token - a privilege a standard user holds, not administrator
  rights - and disables it again if the call fails; an account without that privilege is offered
  nothing. `powrprof.dll` and `wtsapi32.dll` are loaded from System32 only
  (`LOAD_LIBRARY_SEARCH_SYSTEM32`), since neither is a KnownDLL. No process, scheduled task or
  service is started (`shutdown.exe` and `rundll32` are never used), no Windows setting is changed -
  Hibernate is never turned on and `powercfg` is never run - wake timers stay as Windows has them,
  and it never shuts down while another person's session is signed in or disconnected. The batch is
  written as done before Windows is asked, so a refusal is never retried. MCP, the icon and a notice
  can only turn it off or stop one batch, named by an opaque id that every batch end replaces; an
  administrator's `DisablePowerAction` holds it - one turned on before does nothing while the value is
  set. The code refuses to act whenever `unittest` is
  loaded, so no test can make a real call.
- **Named objects planted by a less-trusted process are refused.** This is new in v0.6.0. The watcher's single-instance mutex, its stop event and the wake event the control layer signals to make it look now have
  predictable names in the session namespace, where a process running at Low integrity may create
  objects. If any of them already exists with an integrity label below Medium (the level an ordinary
  user's programs run at), the watcher refuses it and logs `named_object_squatted`. A planted
  mutex makes the watcher refuse to run and status read unknown; uninstall treats that unknown as
  it treats any other, and aborts before removing anything. A planted stop event makes the watcher
  refuse to start, so status reads not running. This covers an object a lower-integrity process
  creates first. It does not cover a lower-integrity process that opens the running watcher's
  mutex and takes it when the watcher exits: that mutex carries the watcher's own Medium label, so
  it is not refused, and status reports a running watcher when none is, as in v0.5.7. In v0.5.7 a
  planted mutex makes status report a watcher running when none is, and a planted, signalled stop
  event makes a real watcher quit on start, logging only an ordinary stop request - nothing that
  points to the planted event. From v0.6.11 the watcher's icon makes one more, the demo event that
  Diagnostics' **Show me what happens** signals, and refuses a planted one the same way; a signal on it
  can do nothing but draw one card of made-up words whose buttons do nothing, which is never a
  Windows notification and reaches neither the recovery state nor the engine. From v0.6.20 an object
  that already exists is refused as well when its owner is another account - one at the same
  integrity, such as a sandbox account commands may run under in this session - and not the
  computer's administrators or Windows itself, which only more rights can make owners.
- **Tools that turn recovery back up request approval through MCP annotations.** This is new in v0.6.0. The plugin's MCP tools that can turn recovery back on or
  up, or change its settings - `resume_auto_recovery`, `enable_conversation_recovery`,
  `reset_recovery_budget`, `start_watcher`, `update_settings`, `restore_default_settings` and,
  from v0.6.11, `release_hold` - are annotated `destructiveHint: true`, and so are `cancel_recovery`
  and `clear_recovery_history`.
  This requests approval; actual prompt behavior depends on Codex and its approval settings,
  and has not been observed for this release. `pause_auto_recovery`,
  `disable_conversation_recovery`, `retry_now` and `postpone_recovery` are not: pausing and
  switching one conversation off never add automation, `retry_now` only moves an already-registered
  attempt earlier, with every check still applied, and a postponement only ever makes one record
  later. Taking a person's own postponement away again (**Don't postpone**, v0.6.11) brings a send
  nearer, so it is no MCP tool at all: only the Dashboard and the notification-area popup offer it,
  bound to the exact record and conversation, and it goes back no further than what the schedule says
  without that postponement - never past an objection window, a retry's wait or a usage reset. The two switches do not cost the same, though. Pausing withdraws a
  continuation already waiting in Codex's queue, and a withdrawal the watcher can confirm puts that
  recovery back in its waiting state with its attempt returned, so resuming picks it up again; only
  a withdrawal that cannot be confirmed becomes `submission_unknown`, and only a pause over a
  submission that was already uncertain ends as `failed`. Switching one conversation off cancels
  every recovery it has waiting, and a cancelled recovery is final: switching that conversation
  back on does not revive it, and giving attempts back refuses it. The prompt is Codex's to show:
  this product can only mark its tools, and Codex's approval settings decide whether a prompt
  appears. `update_settings` offers and accepts only the settings a person can change in the
  window, not the engine path (`codex_exe`) or the detection look-back, and `get_status` does not
  include the install path. From v0.6.3 `update_settings` also leaves out the text of the Custom message, while the
  settings `get_status` carries include it, read-only: Codex can read it there and cannot change it (see
  the next item). In v0.5.7 only `restore_default_settings` and `cancel_recovery` are
  marked; `set_auto_recovery`, `reset_recovery_budget`, `start_watcher` and `update_settings`,
  which there also offers the engine path, have no destructive annotation requesting approval,
  and a pause-withdrawn recovery there is cancelled outright. The advanced edition adds three
  tools - `list_advanced_capabilities`, `disarm_advanced_capability` and `disarm_all_advanced` -
  that list its capabilities or turn them off. They carry no destructive annotation, because they
  only ever do less, and no tool turns a capability on (`advanced/tests/test_advanced_surfaces.py`).
- **The Custom message is written in the Dashboard, and nowhere else.** New in v0.6.3. It is
  the one piece of text a person writes that this product then sends by itself, into that
  person's conversations, at every interruption it covers, while nobody is watching. So it is
  written only through the local control layer the Dashboard uses, and never through
  the plugin's MCP tools: `update_settings` leaves the text fields out of its schema and
  refuses them by name when a client sends them anyway. From v0.6.11 the same holds for a message
  for one conversation (`custom_message_by_thread`), written from its task's row in the Dashboard:
  checked by the same validator, at most 50 conversations, no MCP tool writes it and
  `update_settings` refuses it. A prompt-injected model that could
  write it would turn one injected instruction into a standing one, delivered at every future
  interruption. What Codex may still set - the continuation language, the style and the
  Custom mode - only chooses among texts this product ships or the person wrote. The new
  `preview_recovery_message` tool is annotated `readOnlyHint: true`, saves nothing and sends
  nothing; it accepts a language and style to preview with, and refuses Custom text. The
  placeholders a message may use are a whitelist - `{reason}`, `{category}`, `{attempt}`,
  `{max_attempts}` and `{reset_time}`, values this product counted or was told by Codex - so
  a placeholder nobody has thought of yet is refused by default, and the ones that would put
  the prompt, the reply, the conversation title, a path, the Windows account name, the raw
  error, an account, an e-mail address, a credential or a token into the message are refused
  by name, saying why. A message is at most 2,000 characters, and it is stored and sent
  exactly as typed or refused; it is never trimmed or rewritten. The same check runs when the
  settings file is read, so text put into `config/settings.json` by other means that fails it
  is treated as not set, and the next message in the fallback is sent instead. Nothing about
  the text can change what is recovered: it is built only after the classifier has found the
  interruption recoverable and every gate has passed, it is attached only to a recoverable
  kind of interruption, and it cannot skip a check or choose a different conversation.
- **A notification button can cancel one recovery or open one page, and nothing else.** The
  `codex-auto-resume:` handler accepts exactly three requests. `cancel` names one interruption
  by its opaque id, which has to match a real record, and can only stop a recovery. `open`,
  new in v0.6.3 for the **Open Dashboard** button, names one page from a fixed list -
  Overview, Pending, History, Statistics, Diagnostics or Settings - and opens it. It changes no
  state and cannot cause a send, so a page that knows the scheme can at worst open a window.
  The third, from v0.6.12, stops the power action for one batch, named by that batch's opaque id, which every batch
end replaces; it can only turn the action off. Anything else is logged as unsupported and ignored. From v0.6.5 the notification card's
  buttons are the toast's buttons, as data, and a press is handled inside the watcher rather than
  through the handler - parsed by the same three parsers, with the same three outcomes: one exact
  interruption cancelled through the control layer, one of the window's own pages opened, or one batch's power
  action stopped. The
  card imports nothing that can send, and the tests hold it to that. From v0.6.11 the needs-you
  notice, off by default, has one button, **Open Dashboard**, at the Settings page: no cancel, and
  no setting is written from a notification - which kinds are told is chosen on that page. What it
  keeps to be told once is a table nothing that decides a send reads, and it never becomes a record.
  The notice that tasks fell due during a long sleep (from v0.6.11, off by default) also has one
  button, **Open Dashboard**, at Pending: no cancel, since it is about several tasks, each of which
  is let continue or cancelled there on its own row. The memory guard's two notices (from v0.6.11,
  off by default) are about the watcher, not a task: each has one button, **Open Dashboard**, at
  Diagnostics or at the Overview.
- **Front ends ask; the watcher alone sends.** New in v0.6.3. The **Auto-resume** switch
  beside each task, on the Pending page and in the notification-area popup, carries the exact
  interruption id and conversation id of the row it was drawn in. When the click arrives, the
  control layer reads the record again and refuses one that no longer exists, has finished,
  or belongs to a different conversation, and a refused click changes nothing - so a list that
  re-sorted between drawing and clicking cannot turn a click on one task into a change to
  another. What it changes is that conversation's switch, which is policy: it sends
  nothing, and turning it on leaves every gate to run. The popup runs inside the watcher
  process, on the notification-area icon's thread, and is a front end like the Dashboard: it
  asks the control layer only for what its rows and menus offer - the pending list, the status, the global
  switch and the per-task switch, postponing a task and taking that back, letting a held task continue, a
  conversation's or a project's rule, and, in the icon's menu, turning the power action off - and imports nothing that can put a continuation into
  Codex. **Cancel all** on the Pending page cancels every pending recovery one exact record
  at a time. Cancelling is the only action offered in bulk, because it can only reduce what
  the tool does; there is deliberately no bulk retry. The advanced edition has one exception: a
  measurement a person runs by hand is carried out by the bridge process itself, not the
  watcher, and some measurements put words into the conversation they are pointed at (*The
  measurement harness*, below).
- **Compatibility data can only restrict.** New in v0.6.5. The Codex Compatibility Registry's
  data ships in the release and can be refreshed from this repository on request (above), so data
  from outside the release reaches a decision the watcher makes - and it is built so that it can
  only make that decision more careful. A failed local check always wins: nothing a document says
  turns it into anything that sends. A document can mark a capability incompatible, for an
  exact Codex version or a range, and then the watcher sends nothing while that data is in force;
  it can mark one verified, or from v0.6.7 checked, only for an exact version, citing an evidence
  file, and only where the local checks already pass - which changes the word shown and not what
  is sent. A local check that fails on a version the data checked or verified reads as failed
  here, since the cause is then most likely this computer rather than that version, and it
  still sends nothing, exactly as incompatible does. A check that could not run stays unknown
  whatever the data claims, and unknown sends nothing. The validator,
  `controlcli compat-import`, is the only writer of `config/compat-cache.json`: it refuses whole a
  document of an unknown format, a malformed or oversized one, one with a duplicate key or a
  number that is not finite, a range that tries to grant trust, one that says it needs a signature
  (the slot is reserved and nothing verifies one yet), one older than the data already in force or
  than the bundled data, one dated more than a day ahead of this computer's clock, and one meant
  for a newer version of this product; a refusal leaves the cache exactly as it was. The cache is validated again on every
  read. Refreshed data past its expiry, or dated ahead of a clock that was set back, keeps its
  restrictions and loses its trust, so no clock can lift a restriction. Every reason that reaches
  a person or a model is a code from a closed list, never text from a document. The watcher's report,
  `config/compatibility.json`, is bound to the Codex executable it describes by a digest of its
  path and its size and time, and every reader refuses one that is damaged, too old or about a
  binary that has since changed. The MCP server can read a summary of it, as codes only, and cannot
  refresh or import anything. And a failing evaluation fails closed: the gate reads unknown, and
  nothing is sent on the strength of a check that did not run.
- **What others report decides nothing.** New in v0.6.10. The Diagnostics page shows, beside the
  Codex version, how many of the reports other people filed for that exact version saw it work,
  fail or neither. Nothing can prove such a report was not written by hand, so it is built to
  inform and never to decide. Its counts are a file of their own that ships with each release,
  `src/codex_auto_resume/data/reported.json`, beside the compatibility data and never inside it,
  and no request fetches it. One module reads it (`compat/reported.py`), with a reader of its own:
  a size cap checked before parsing, the registry's decoder (a duplicate key, a number that is not
  finite or too deep a structure refused), exact keys, and counts that must add up. Only the view
  a person reads imports that module; the engine, the watcher's loop, the gates, the registry's
  standing, permits, evaluator and cache, the popup and the tray never do, and
  `tests/test_reported_isolation.py` holds that by structure and by behaviour - a thousand reports
  that a version worked leave one with no evidence of its own *compatible*, a thousand that it
  failed leave a verified one verified, and neither moves a permit or what the watcher writes. A
  damaged file reads as *could not be read* and can never refuse the registry. The MCP summary
  never carries the counts. And the compatibility data cannot rest on someone else's report: the
  validator refuses a claim whose evidence is under `docs/evidence/community/`, in any spelling
  Windows would still open as that folder.
- **A report's pull request is judged by `main`'s check, as data.** New in v0.6.10.
  `.github/workflows/community-report.yml` runs on `pull_request_target`, so its definition is
  always `main`'s and a fork cannot rewrite the check it is judged by. It never runs the head: it
  checks out the base commit with no token left on disk, holds `contents: read` and no secret,
  installs nothing, keeps no cache or artifact, runs for at most five minutes, and reads the
  head's commits with git plumbing only (`build/community_check.py`) - nothing in them is checked
  out, merged or run. A contributor's pull request, from a branch whose name starts with
  `compat-report/`, may add one new file, at
  `docs/evidence/community/<their GitHub login>/codex-cli-<its own version>.json`, of at most 1 MB
  known before it is read, that the report reader (`build/community_report.py`) accepts, and that
  is not a copy of a filed report; anything else is refused. The report's own levels and verdict
  are recomputed from what it measured, and only ever lowered. `tests/test_workflow_privilege.py`
  and `tests/test_community_check.py` hold each rule.
- **A report that passes is filed by `main`'s code, as data.** This is the repository's own
  machinery rather than the product's, and works from the day it is on `main`.
  `.github/workflows/community-file.yml` files what the check accepted with no step by the
  maintainer, in two jobs, so that nothing a stranger sends can reach its write access. The first,
  `plan`, holds no write access at all: a read-only token is given only to the steps that ask
  GitHub's list and read endpoints and run nothing else, and the steps that run Python
  (`build/community_file.py`) have no token. It fetches each pull request's commits anonymously,
  with no file over 1 MB brought over, judges them again with the same check against `main` as it
  is then, builds this project's own regeneration of the report - never the sender's bytes - and
  runs the tests that read what a filing writes on the tree that would become `main`. Its whole
  answer is a git bundle and a few lines of text, kept for a day. The second, `write`, starts on a
  fresh runner, runs no Python and no repository code, uses git and gh by absolute path with no
  configuration of the runner's and no hooks, and trusts nothing it is handed: it re-derives every
  commit from git and refuses one that adds more than one report, changes a filed one, touches any
  path but that report and the index, README and counts every filing rewrites, names a folder
  Windows keeps for a device, or carries a message other than the filer's own. GitHub's hash for
  every blob and tree it uploads has to equal the one tested, and `main` moves only forward and only
  from the exact commit the plan was made on, so a race is lost rather than won wrongly. dev takes
  the same files only when that cannot touch anything else on it. What a sender is told is fixed
  text, with no mention, link or markup. The limits a maintainer used to apply - account age, one
  open report per account, reports per account and per Codex version per week, a budget of Codex
  versions the project's data does not name - are counted from `main`'s own history and keyed by
  numeric account id, which a rename does not change. The repository variable `COMMUNITY_AUTOFILE`
  pauses it on anything but unset or `on`, `COMMUNITY_BLOCKED` refuses an account, and cancelling a
  running job stops it at once. A pull request whose comment the survey's page of recent comments
  misses is read on its own before anything is decided about it, so none is told twice. `tests/test_workflow_privilege.py` and `tests/test_community_file.py`
  hold each of these, the second by running the write step itself against a stand-in for GitHub.

## The advanced edition

New in v0.6.11. The advanced edition is the standard edition plus capabilities that each depart,
on purpose, from at least one of the standards the standard edition keeps, and each one's
statement - what it does, what the standard edition does instead, which standards it departs
from, what can go wrong and how to stop it - names them. While none is on and no measurement is
being run, everything above holds for it as written. Once one is on, everything above still holds
except what that capability's paragraph under *What each does* says; and while a person runs a
measurement, it does what *The measurement harness* says.

The standards are the project's own list, kept by the owner and published in
[STANDARDS.md](STANDARDS.md), each with how it is held and the tests that hold it. Where this
section names one by its id it also says in a few words what that standard is, as each
capability's statement does. [EDITIONS.md](EDITIONS.md) describes the two editions, and each
capability, in plain words.

**How the two editions are kept apart.**

- **The standard archive holds none of the advanced code.** It is built from a list of trees that
  does not name `advanced/`, and `build/edition_audit.py` proves the rest from the two archives'
  and the two setup programs' own bytes in every release build, before anything is kept: no
  advanced path, file, name or marker in any entry of the standard ones, the standard archive
  built again from `git archive` with `advanced/` deleted is the same file, and every standard
  entry is in the advanced archive unchanged (`tests/test_edition_audit.py`,
  `tests/test_edition_build.py`).
- **An installation updates within its edition.** An update, and a pre-release the update check
  offers, fetch the installed edition's archive. A bootstrap or installer that meets the other
  edition refuses before anything is moved, unless the change was asked for and confirmed, and a
  change of edition is a reinstall that keeps settings and pending recoveries
  (`tests/test_edition_bootstrap.py`, `tests/test_edition_installer.py`).
- **Its state is its own.** Which capability is on, what each has spent and what it did are kept
  in `config/advanced/advanced.sqlite`, in closed words, ids and numbers. Nothing of it is written
  into the standard edition's state or settings, and no secret is kept in it.

**Who turns a capability on, and what turns it off.**

- **Only the Dashboard's bridge turns one on.** Every capability starts off, and entering the
  edition turns every one off. A capability is turned on, or set to watch first, one at a time - or
  turned on together with what it needs, in one confirmation that shows every statement involved - and
  only by a request on the local bridge the Dashboard uses (`controlcli serve`), which must still
  carry what the person has just been shown: the statement revision they read, the generation the
  list was read at - so that nothing turned off since is undone by a request that had not seen it -
  the warnings shown, and, for on, the Codex version shown. Every other surface may only turn
  capabilities off, and no MCP tool turns one on, whatever a client sends
  (`advanced/tests/test_advanced_arming.py`, `advanced/tests/test_advanced_surfaces.py`). The
  Dashboard's **Advanced features** page is what makes that request, sending exactly what it showed
  (`advanced/tests/test_advanced_page_arming.py`). Like every request on that bridge, it is open to
  anything running as you; what cannot make it is a model through the plugin's MCP tools. A
  capability watched first journals what it would have done and does nothing, and nothing moves it
  from watched to on but a request of this kind.
- **A warning is confirmed, never refused.** A measurement its route rests on that failed or was
  never made for the Codex in force, a compatibility grade of Failed here, Incompatible or Unknown,
  or a Codex version not yet known is shown in its statement as a warning, and turning it on
  confirms each warning shown. What still refuses is an administrator's policy: three values under
  `Software\Policies\CodexAutoResume`, in `HKEY_LOCAL_MACHINE` or `HKEY_CURRENT_USER`, read and
  never written - `ForbidAdvanced` (nothing may be on or watched), `AllowedCapabilities` (only the
  ids listed may be) and `ForceShadow` (watched, never on). Both places count, together they are
  the stricter, and a value or a key that cannot be understood reads as the strictest. Like the
  standard edition's policy keys, they are what a cooperating installation obeys, not a lock.
- **What turns one off by itself.** A new revision of its statement; a warning the person did not
  confirm that says what it stands on went wrong - its compatibility failed here or is
  incompatible, a local check failed, or a measurement its route rests on failed; one of its hooks
  raising; a send it paid for becoming `submission_unknown`; and, for one that is on, a new Codex
  version. Whatever turned it off, a person can turn it on again over the same bridge, with its
  statement as it reads then.
- **Pause and consent come first.** A capability answers only where core asks it, after core's own
  checks: a paused watcher asks no capability anything, a conversation switched off or a cancelled
  record is never put to one, and a pause that commits after the last look before a send still
  stops a capability's send or route at the launch guard (`tests/test_plug_points.py`). Every gate a
  send passes, the durable claim and the last look before the send stay core's.
- **Ceilings.** Each capability has its own sends a day and in one conversation, spent when the
  claim is made, before anything is asked of Codex. Over them stands one ceiling for every
  capability together, 12 an hour, which a person may lower over the same bridge and never raise, and
  every claim still counts against core's own caps for the conversation.

**What each does, once it is on.**

- **Start with Codex, through WMI.** It departs from C4 (nothing happens on its own, and nothing at
  start) and F6 (the processes the product starts are a fixed list, and a route through WMI is not
  on it). When Codex starts the plugin's MCP server, and recovery is not paused, no watcher runs, no
  installation is in progress and this installation's launcher is there, the server starts the
  watcher. Where Codex's job would end what the server starts, it asks WMI to
  (`Win32_Process.Create`): one constant PowerShell script, run by PowerShell's full System32 path
  with the command line in an environment variable, windowless. The watcher's parent is then WMI's
  own host, outside Codex's job, so closing Codex does not end it. The command line is core's, built
  from this installation's own launcher; the route never starts a second watcher, sends nothing and
  claims nothing.
- **The marker-free continuation.** It departs from A2 (one channel only, `codex queue`), A4 (every
  continuation carries its marker, and counts as delivered only when the marker is found), B3
  (Codex's state changes only through `codex queue`, `thread/queue/delete` and the plugin commands)
  and B4 (the app server is asked only for usage and to withdraw a queued message). The
  continuation's words go without the marker, added to the conversation's queue through `codex
  app-server --stdio`'s `thread/queue/add` under a client id derived from the interruption, and
  delivery is proven by that id alone. A send it cannot prove - the app server refuses, does not
  answer, or the item never shows - is held as `submission_unknown`, never sent again, and turns the
  capability off. At most 24 a day, and 5 in one conversation.
- **The compatibility report.** It departs from B11 (gh reads the person's GitHub sign-in on the
  product's behalf), C1 and C2 (network work, by delegation, from a second shipped file), C3 (GitHub
  addresses beyond the two lists of releases), C8 (the person's GitHub identity and gh's User-Agent),
  D1 (the report's counts go to the project), E8 (a gh that hangs, or outlives the Dashboard's
  service, is ended), F3 (a file saved where the person chooses) and F6 (gh is not a listed process).
  It is an action: core never asks it anything, and it sends nothing to Codex. Writing reads this PC's
  records read-only, as codex-compat-reporter does, and saving never writes over a file. Only while it
  is on, and recovery is not paused, does it start gh: the gh.exe first in an absolute folder on PATH
  that is not the current one or the installation's - so whatever gh.exe is there is trusted - by its
  full path, with an argument list and no shell, without GH_HOST or GH_REPO, prompts off, every API
  call naming `--hostname github.com` and every pull request `--repo github.com/<the project>`; each
  gh is started suspended and windowless in a job object that ends it when the Dashboard's service
  ends, and one that has not answered in two minutes is ended alone. The file goes to gh on its
  standard input. A send writes only after the word `send`, typed exactly, for the SHA-256 and the
  writes the person was shown, which it reads again from GitHub first; before every write it looks
  again at the capability, an administrator's policy and the pause, and stops with what it wrote. One
  check or send runs at a time for an installation, across processes, under a named mutex of the
  user's. A send that ended part way is told by the next check, from what is on GitHub: the
  report's branch left on the fork with no pull request open. No MCP tool reaches any of it
  (`advanced/tests/test_advanced_report.py`, `advanced/tests/test_advanced_report_github.py`).
- **The goal continuation.** It departs from 0.5 (a goal's state is never changed), A2, A11 (nothing
  is done for a conversation the app does not hold), B3 and B4. For a usage limit only. Where the
  app does not hold the conversation and the limit paused its goal, it sets that existing goal
  active again through `thread/goal/set` - the thread and the status alone: no goal is created, and
  its words are never read or written - so that Codex carries the goal on when the app next opens
  the conversation. The set is made only while core's own look, made again once the session is up,
  still finds the conversation not held. While that goal is active, the standard continuation is
  held back, for at most ten minutes. Where the app holds the conversation it acts only if
  measurement M2b passed for the Codex in force, setting the goal active and then adding the
  continuation with `thread/queue/add`; anywhere else the standard route stands. Which goal a
  conversation has, its status and when it changed are read from Codex's goals database, opened
  read-only - while the capability is watched as well as while it is on. At most 12 a day, and 3 in
  one conversation.

Those four are the first. The others each have a statement in [EDITIONS.md](EDITIONS.md), which the Dashboard shows
before a person turns one on, and the ones that add to what this page lists are: *Check for updates once a week*
(unattended requests to GitHub, where C4, C5 and C7 allow only a pressed button), *Open Codex on a notice* (starts
`explorer.exe` with a `codex:` link and reads, never writes, the handler Windows has registered for such links), *Stop
near a limit* (stops a running turn through the Codex app's own pipe), *Run a conversation here while Codex is
closed*, *Compact a full conversation, then continue* and *Use Codex's default model when one is at capacity* (resume,
start, interrupt and, for the last two, compact or change a conversation's model, through an app server of their own),
*Use a reset credit at the limit you pick* (reads usage on a schedule and spends one reset credit) and *Usage meter*
and *Send your own message when a limit resets* (read usage on a schedule).

Each capability's session with the app server is started as core starts its own, with the same
arguments and environment. It may call only the methods that capability declares
(the advanced package's `codex/protocol.py`), and never calls a sign-in, token or attestation
method. It answers the approval, permission, input and elicitation requests Codex may make of it -
seven methods - with the refusal Codex's own schema gives each (a table in the same file), and
every other request, a token
refresh, an attestation or a tool call among them, with an error. The advanced edition adds no
network code: its package imports no networking module either (`tests/test_privacy_claims.py`). The
compatibility report reaches GitHub only through gh, above.

**The measurement harness.** The advanced edition's archive also carries `measure` (the advanced
package's `measure.py`), with which the owner finds out whether a
capability's route can work on a given Codex. It is not a capability: nothing turns it on, and it
runs whether or not any capability is on - once for each request, when a person sends
`measure <id>` over the same bridge, with a conversation id where they give one. No MCP tool
reaches it, and the window offers it nowhere. Each measurement opens a `codex app-server --stdio`
session of its own, limited to the requests the harness declares it may make (in the same
`codex/protocol.py`) and answering Codex's requests as a capability's session does, and some of
those methods change Codex's state or start work in the conversation named:

- M2 and M2b set the conversation's existing goal active (`thread/goal/set`).
- M2b and M7 add a message this product wrote to its queue (`thread/queue/add`) - *Reply with the
  single word: ok.* and `/compact` - which the Codex app runs as a turn once it takes it; M3 adds
  an empty one.
- M6 resumes the conversation in its own session and starts one model turn there (`thread/resume`,
  `turn/start`), asking Codex to run `whoami` under the strictest approval policy and a read-only
  sandbox. It declines every approval it is asked for, interrupts the turn if it has not ended
  within three minutes (`turn/interrupt`), and unsubscribes.
- MW starts two throwaway processes of its own - a helper inside a job built the way Codex builds
  its plugins' jobs, and a heartbeat the helper asks WMI to start - and ends both.
- M1, M4, M5, MH and MA only read: the loaded conversations, a queue, the hooks, the account's
  state (`account/read`, of which the record keeps only that it was read).
- MP1 only reads too - the Codex home's list of MCP servers (`mcpServerStatus/list`), asking for this
  product's server by its name first and for every server only where Codex knows it by another
  name - but Codex starts each server it lists, as the app does when it starts. Starting this
  product's installed server runs that server's own start step: a line in the installation's
  `logs/codex-start.log`, and, where Start with Codex is on and no watcher runs, the watcher
  started. Run it with the watcher running. MP2 and MP3 open no session: they are what a person
  sees in the Codex app.

Without a conversation id, the calls carry a placeholder id that is no one's. A record is written
only into a source checkout's `docs/evidence/live/`, and holds booleans, counts and closed words
(`evidence.py`). An installed copy has no such folder, so there the record is refused - but only
after the calls were made. Run a measurement only on a throwaway conversation.

## Destructive-operation safety

**Nothing is destroyed that this installation cannot prove it owns, with two exceptions at install
time.** The rule covers files, directories, processes and registrations, when installing and when
uninstalling, because "it has the right name" was never evidence for any of them. The two exceptions
are things installing replaces by name, both described under *Installing*: this product's own
per-user registrations, which exist once per user, and the Codex marketplace name it registers
under.

- **Installing.** The install path destroys things too: it sweeps set-aside copies, moves
  `app/` and `runtime/` out of the way, and deletes what it moved. From v0.6.0, it writes a small
  JSON journal at the installation root before the first move, naming every tree it is about to
  move and the `*.old-*` name it will use - written to a temporary name and moved over the real
  one, so a crash during the write leaves either the previous journal or none. The next run reads
  it before it sweeps anything: it puts back a tree whose target is missing, and checks both ends
  of every move against the installation it has already proved is its own. The two files that
  belong at the installation root are copied there by name rather than by wildcard, so nothing
  else a payload happens to carry reaches the home - including a file named like this product's
  own provenance marker. It cannot ask the question the uninstaller asks, because the first
  install happens into a directory that is not ours yet. So it asks the other half: is anything
  of ours here? A directory already holding `app`, `runtime`, `config`, `logs` or a set-aside
  copy, with no proof any of it is ours, is refused and nothing in it is touched. A directory
  holding none of them has nothing to destroy, and is marked as ours *before* the first file is
  written - never afterwards, because a marker written after the fact would authorise the
  deletions backwards. Two things are replaced by name. The notification identity, the Start Menu
  shortcut and the URL handler exist once per user, so installing writes this installation's
  values over whatever is registered under those names - in practice, another copy of this
  product that did not register for sign-in. The sign-in value is not replaced: if it belongs to
  another installation, setup stops before writing any of the per-user entries above and says so.
  By then the installer has already copied the files and registered the Codex plugin and
  marketplace, including the repointing described next. And if the marketplace name
  `codex-auto-resume-windows` is already registered from a different source, installing removes
  that registration and registers the name again, pointing at this installation, without checking
  what the old source was.
- **Upgrading.** Before replacing its files, an upgrade asks a running watcher to stop through its
  stop event - the same request `stop` and uninstall make - and waits up to a minute. It never
  kills the watcher: one stopped mid-submission would leave that recovery unable to prove whether
  it was sent. If the watcher is still running after the wait, the upgrade completes and says that
  the previous version is still running and how to replace it. The only processes an install
  stops by force are this plugin's own MCP launchers, identified by path as on uninstall, when
  they hold the plugin's files open and Codex cannot update the plugin; Codex starts a fresh one
  when it needs it.
- **Uninstalling: directories.** The installation root has to be one we created: it carries our
  provenance marker (`.owned-by-codex-auto-resume`), or its `config/` does, or its `runtime.json`
  names that very directory. The root can be pointed anywhere by `CODEX_AUTO_RESUME_PLUGIN_HOME`,
  so a directory that merely contains folders called `app`, `runtime`, `config` and `logs` is
  refused and nothing in it is touched. Every path deleted is then re-checked against the
  *canonical* root, with junctions and symlinks resolved, so a link inside the installation
  cannot redirect a recursive delete out of it. Inside an owned directory, only our own file
  names are removed.
- **Uninstalling: processes.** The MCP launcher is stopped only when its executable resolves
  inside this installation or inside this plugin's own Codex cache directory. Another program
  running under the same filename is left alone, and a process whose path cannot be read is
  skipped: not being able to tell is not permission to kill.
- **Uninstalling: Codex configuration.** The plugin and its marketplace are removed only while
  they still point at this installation, which is read from `codex plugin list --json` and
  `codex plugin marketplace list --json`. If you have repointed that marketplace name at a fork
  of your own, uninstalling this product leaves your configuration exactly where it is and says
  so. If Codex refuses a removal, that is reported as a refusal, never as a removal.
- **Uninstalling: registry and Start Menu.** The sign-in entry, the notification identity, the
  Start Menu shortcut, the `codex-auto-resume:` handler and the Add or remove programs entry are per-user singletons that a second
  installation would overwrite, so each is removed only when it still belongs to the
  installation being removed.

Uninstall first asks a running watcher to stop through its stop event. If a watcher is still
running, or if it cannot verify whether one is running, uninstall aborts before removing anything
at all — registrations included. The proof of ownership is deleted after the last step that can
still stop the run, so an interrupted uninstall can be run again. Uninstall never deletes ChatGPT or
Codex files itself: it asks the `codex` CLI to unregister this plugin and its marketplace, only
while they still point at this installation, and Codex removes its own cached copy of the plugin.
User repositories and parent directories are never deleted.

## Release integrity

Releases are built and published by GitHub Actions (`.github/workflows/release.yml`) from the
tagged commit, not from a developer's working tree.

Archives v0.5.0 through v0.5.7 were built by the earlier single-job
workflow, which referenced its actions by floating tags and produced executables that were not
reproducible. The two-job split, the pinned actions, the reproducible executables and the
version resource described below are new in v0.6.0.

- **Two jobs, split by privilege.** From v0.6.0. `build` runs the repository's code - the tests
  and the build scripts - with a read-only token that is not left on disk. `publish` holds the
  rights to create the release and attest it, runs no script from the repository - only the steps
  written in the workflow itself (it does not check the repository out) - and runs only on a tag
  push. A manual run builds and verifies whatever ref it names and never reaches `publish`.
- **Pinned actions.** From v0.6.0. Every GitHub Action the workflows use is pinned to a full
  commit SHA, with the release it corresponds to in a comment, and a test enforces it. Dependabot
  proposes updates as pull requests for a person to review; nothing in the repository merges them
  automatically.
- **A published version is not replaced by the workflow.** From v0.6.0, `publish` refuses a
  version that already has assets, so a correction needs a new version; the earlier single-job
  workflow refused the same way from v0.5.4 on. These are not GitHub "immutable releases": that
  repository setting is not enabled, so the rule is this workflow's rather than a platform
  guarantee, and a person with write access to the repository could still change a release's
  assets by hand. The digest an install is checked against is therefore kept as a commit on
  `main` rather than as a release asset; the next item says what that does and does not catch.
- **What an install is checked against.** The plugin's setup script verifies the archive's
  SHA-256 against the digest pinned for that version in `scripts/release.json` - the copy that
  came with the plugin from `main`, where the pin is committed after the archive is published. It
  is a commit on `main`, not a release asset. A replaced asset no longer matches it unless the pin
  is changed too, and that change is a new commit on `main`, visible in its history unless that
  history is rewritten; the pin lives in the same repository, under the same write access. For a
  version with no pin yet - between publication and the pin commit - the script falls back to the
  `.sha256` published beside the archive and says so; that file shows the download is intact,
  not where it came from. A file passed with `-ArchivePath` is checked only against a pinned
  digest; if the version has none, its SHA-256 is compared with nothing, and the script says so.
  Every archive from v0.5.4 on also carries a GitHub build provenance attestation, which ties it
  to the workflow run and the commit that built it.
- **Two editions, one attestation.** From v0.6.11 a release publishes each edition's archive
  (`CodexAutoResume-vX.Y.Z-win-x64.zip`, `CodexAutoResume-Advanced-vX.Y.Z-win-x64.zip`) and each
  one's setup program (`CodexAutoResume-Setup-vX.Y.Z.exe`,
  `CodexAutoResume-Advanced-Setup-vX.Y.Z.exe`), each with its `.sha256`, and one attestation names
  all four as its subjects (`tests/test_workflow_privilege.py`). `scripts/release.json` pins the
  standard archive's digest under `sha256` and the advanced archive's under `advanced`, each version
  in both in the same commit on `main`, and each edition's bootstrap checks its own archive against
  its own pin. A setup program has no pin of its own: it carries its edition's archive byte for
  byte, and `build/make_setup.py --check` shows that from the published files.
- **Reproducible executables.** From v0.6.0. The in-box C# compiler stamps every build with the
  time and a random module id (MVID). `build/normalize_pe.py` fixes the PE timestamp and derives
  the MVID from the module's content, so the two executables depend only on their source and the
  compiler build (which the build log records), and the release build compiles them twice and
  refuses to publish if the two builds differ. Text files are checked out with CRLF everywhere
  (`.gitattributes`), because their line endings are part of the archive's bytes. Two full builds
  from fresh clones on one machine, with the same compiler, Python and zlib, produced
  byte-identical archives. For v0.6.0, the archive GitHub's runner published and a rebuild on another Windows machine had the same SHA-256 - a
  same-toolchain match, since the two used the same compiler build ([VERIFY.md](VERIFY.md)); two different
  compiler builds have never been compared.
- **Version resource.** From v0.6.0. Both executables carry a Windows version resource -
  product, publisher, file and product version - generated from the plugin manifest, so a file's
  Properties name what it is. That is a label, not a signature: it says nothing about who built
  the file.

## Code signing

Nothing this project builds is Authenticode-signed - the two executables, the setup programs,
`Install.cmd`, `Uninstall.cmd` and the PowerShell scripts. The bundled Python interpreter keeps the signatures it
was published with: the Python Software Foundation's on `pythonw.exe`, `python.exe` and the Python
DLLs, and Microsoft's on the two Visual C++ runtime DLLs.

- What the sign-in entry starts is the bundled `pythonw.exe`, which carries the Python Software
  Foundation's signature.
- The two small executables - the settings window and the MCP launcher - are unsigned, and with
  Smart App Control on, Windows may block them. On the manual route SmartScreen may warn, because a
  ZIP downloaded in a browser and extracted with Explorer passes the mark of the web on to its
  files. A `.cmd` file cannot carry an embedded Authenticode signature.

Without a signature on this project's own files, what establishes that a file is the one this
repository published is the checking described under *Release integrity* and below.

## Verifying a release

If you download the archive yourself, verify it before extracting it. In PowerShell:

```powershell
(Get-FileHash .\CodexAutoResume-vX.Y.Z-win-x64.zip -Algorithm SHA256).Hash
```

Compare the result, ignoring case, with the `.sha256` file published beside the archive, and with
the digest pinned for that version in
[`scripts/release.json`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/scripts/release.json)
on the `main` branch. The pin reaches you by a different channel - a commit on `main`, not a
release asset - so it is the comparison that does not rest on the release page alone. It is still
in the same repository; a change to it is a new commit on `main`, visible in its history unless
that history is rewritten. v0.5.0 and v0.5.1 have no pin, and a version published very recently
may not be pinned yet. For v0.5.4 and later, you can also check the build provenance with
the GitHub CLI:

```powershell
gh attestation verify .\CodexAutoResume-vX.Y.Z-win-x64.zip `
    --repo songyb111-gachon/codex-auto-resume-windows `
    --signer-workflow songyb111-gachon/codex-auto-resume-windows/.github/workflows/release.yml `
    --source-ref refs/tags/vX.Y.Z
```

The advanced edition's archive, from v0.6.11, is checked the same way, under its own name
(`CodexAutoResume-Advanced-vX.Y.Z-win-x64.zip`) and against its own pin, under `advanced` in the
same file; so is each setup program, against its `.sha256` and the attestation.

`Install.cmd` checks nothing about the archive it came in; this step is the check. The plugin route
does the SHA-256 comparison itself, except for a file passed with `-ArchivePath` for a version with
no pin, as described under *Release integrity*.
[`docs/VERIFY.md`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/docs/VERIFY.md)
goes through each step, what the plugin route checks for you, and how to rebuild a release and
compare. Archives up to and including v0.5.7 were not built reproducibly, so a rebuild of those tags
is not expected to match them byte for byte.

## Review process

Three adversarial review rounds. Each round ran several independent reviewers across different
dimensions, and every finding was then given to three further independent agents whose task was to
*refute* it. Only findings that survived refutation were treated as real.

| Round | Scope | Confirmed | Rejected |
|---|---|---:|---:|
| 1 | detector, store, Windows adapter, scheduler | 12 | 6 |
| 2 | CLI, app, config, logging, autostart | 3 | 0 |
| 3 | final audit across 9 dimensions | 8 | 3 |

Empirical verification beyond review:

- **Mutation testing.** Around twenty safety guards were deliberately broken to confirm the test suite
  catches it. Three survivors exposed real gaps, all in uninstall safety, and regression tests were added.
- **Crash-window matrix.** The process was killed at four points around sending. After restart, every
  case sent at most once.
- **Cross-process race.** Four processes raced to reserve the same interruption, eight times, with
  exactly one winner each time.

A later review took in the installer, the plugin's skill and MCP tools, the Windows named
objects and the release workflow as well as the runtime, and its findings were checked again by
a second, independent pass. What held up is in the last two lists below. The PowerShell fix is
tested by running the original payload through the real interpreter (`tests/test_pwsh.py`), and
the named-object check, which is new in v0.6.0, was measured against a real low-integrity
process.

## Notable issues found and fixed

- **The loaded-state probe could acquire the app's own exclusive writer lock** when the byte range was
  momentarily free, which could make the app's own lock attempt fail with a lock violation. The locking
  code was removed entirely.
- **Autostart could point at the wrong state.** With a home configured by environment variable, the
  registered command omitted it, so the autostarted watcher would use a different state database and a
  different single-instance mutex, allowing a second watcher and silently resuming nothing.
- **Uninstall could delete same-named files it never created.** Fixed with the provenance marker.
- **Uninstall treated an unverifiable watcher probe as "not running".** Now fails closed.
- **NTFS junctions bypassed directory confinement**, because `is_symlink()` does not detect them.
- **A transient engine probe failure at logon terminated the watcher** for the whole session.
- **Two inherited bugs made the prototype non-functional**: detection results were rejected by the store,
  so nothing was ever registered or resumed, and the entry point swallowed all exit codes.

From the later review, fixed in v0.5.7:

- **A folder or conversation name could run PowerShell.** Toast text and shortcut paths were
  written into the script as single-quoted strings, escaping only the ASCII apostrophe. PowerShell
  also treats U+2018, U+2019, U+201A and U+201B as single quotes, so a name containing one ended the
  string and the rest ran as PowerShell under the user's account, silently. Every release from
  v0.4.0 through v0.5.6 was affected; the next release fixed it. Values now travel as environment
  variables to constant scripts.
- **An upgrade could leave the old watcher running.** Renaming `app/` under a live watcher succeeds,
  so the old code carried on from the renamed copy and a security fix could be installed but not in
  effect. The installer now asks it to stop, as described under *Upgrading*.
- **`Install.cmd` and `Uninstall.cmd` called `chcp` and PowerShell by bare name**, so `cmd.exe`
  would run a program of the same name sitting in the same folder - which, if that folder is
  Downloads, could be any earlier download. Both are now called by full path.

From the later review, fixed in v0.6.0 (v0.5.7 still has each of these):

- **The MCP tools let content in a conversation turn recovery back up without asking.**
  `set_auto_recovery` needed no approval in either direction, so a prompt-injected turn could
  undo the user's pause; `reset_recovery_budget` revived exhausted recoveries the same way; and
  `update_settings` offered the engine path. From v0.6.0, see *Tools that turn recovery back up
  request approval through MCP annotations*.
- **The installer refreshed every Git marketplace the user had configured**, because it ran
  `codex plugin marketplace upgrade` with no name - an action on other publishers' plugins, and
  a network fetch from their hosts. From v0.6.0 it names its own marketplace.
- **The sign-in launcher's fallback accepted a plugin of the same name from any marketplace** in
  Codex's plugin cache, and, for an installation with no application directory, could have run
  it at sign-in. From v0.6.0 it searches only this product's own marketplace, besides the copy
  recorded when setup ran.
- **The skill ran the setup script by a relative path**, which resolves against the user's
  project. From v0.6.0 it gives the absolute path inside the plugin.
- **A lower-integrity process could squat the watcher's mutex or stop event.** Creating the mutex
  first made status report a running watcher when none existed and kept the real one from
  starting; creating and signalling the stop event made a real watcher quit on start, logging
  only an ordinary stop request - nothing that points to the planted event. From v0.6.0 such
  objects are refused and logged. This covers an object a lower-integrity process creates first.
  It does not cover a lower-integrity process that opens the running watcher's mutex and takes it
  when the watcher exits: that mutex carries the watcher's own Medium label, so it is not
  refused, and status reports a running watcher, as in v0.5.7.
- **The release workflow's dry run was not one.** A manual run against a tag could publish, and a
  manual run against any ref ran that ref's code holding a write token left in `.git/config`. On
  v0.6.0 the workflow is split into the two jobs described under *Release integrity*.
- **An interrupted install was destroyed by the run that came next.** The old `app\` and
  `runtime\` are moved aside before the new ones are copied in, and the first thing the next run
  does is delete every `*.old-*` directory it finds - so a power cut between the two left the
  only complete copy under exactly that name, and the recovery attempt was what destroyed the
  installation. From v0.6.0 a journal written before the first move tells the next run what to
  put back, as described under *Installing*.
- **Whatever sat at the payload root was copied into the installation home.** It was a wildcard
  copy, so a stray file in a release landed in the home under whatever name it carried,
  including the two this product reads as proof that the home is its own
  (`.owned-by-codex-auto-resume`, `runtime.json`). From v0.6.0 the two files that belong there
  are copied by name, and a payload missing either fails the install before anything is moved.
- **An upgrade switched automatic recovery back on, and put back a sign-in start that had been
  removed.** Plain `setup` runs the engine's `enable`, so upgrading over an installation whose
  owner had paused recovery turned it back on silently, under the name of an update. From v0.6.0
  the installer, and Repair in the window, run setup with `--keep-state` whenever the program
  directory is already there: the pause is left alone, and the sign-in entry is re-registered
  only where the one registered is already this installation's.

Found while planning v0.6.5, fixed in v0.6.5 (v0.6.4 still has each of these):

- **Text sent as a switch's value turned the switch on.** The window's bridge read the
  `enabled` value of its switch commands with a plain truth test, so any non-empty string counted
  as on: `{"enabled": "false"}` switched automatic recovery on, and for Run at Windows sign-in
  wrote this product's value under the current user's `Run` key; a request with no value switched
  them off. The settings window always sends a real `true` or `false`, so its own switches were
  never affected; a request made some other way could be. Anything but a boolean is now refused,
  with the control layer's own code, before the control layer is asked.
- **A settings value of the wrong type was accepted whenever it equalled the default.** An update
  was compared with what it coerced to, and coercion answers a value it does not like with the
  field's default - so `{"reduce_motion": 0}` and `{"notifications": 1}` were accepted while
  `{"notifications": 0}` was refused. The type the settings schema publishes is now checked
  first, for every field, and a wrong one is refused whatever it equals.
- **The release job checked fewer entries than an installed bootstrap requires of an update.**
  It did not check `.codex-plugin/plugin.json`, `scripts/plugin_setup.py` or the icon at the
  payload's root, so an archive missing one could have been published and then refused by every
  installed copy. It now checks everything the bootstrap requires, and tests hold the two lists to
  each other in both directions and to what published bootstraps require.

## Residual risks

- The blocking usage bucket cannot always be identified from history with certainty, so live
availability is re-checked immediately before sending. This reduces but does not eliminate the
uncertainty.
- The tool no longer requires an exact engine version. An unrecognised build is
accepted when the `codex queue` interface probe passes, which means a Codex update can change
*semantics* without the probe noticing. This is mitigated rather than eliminated: every send is
still proven afterwards by the per-interruption marker in that exact thread, an unproven send
is never recorded as a recovery, and `status`/`doctor`/the log state clearly when the engine is
unverified.
- Unloaded threads are not resumed at all; this is a documented product limitation,
not a security control.
- If withdrawing its own queued message cannot be confirmed, the record
becomes `submission_unknown` and the message may stay in Codex's queue, where it may be
delivered if the conversation is opened later. The tool never sends it again.
- A
lower-integrity process that holds the watcher's mutex or stop event name keeps recovery from
running while it holds it, in v0.5.7 and in v0.6.0 alike. From v0.6.0, a planted
mutex makes status read unknown and a planted stop event makes the watcher refuse to start, so
status reads not running; both are logged as `named_object_squatted`. This covers an object a
lower-integrity process creates first. It does not cover a lower-integrity process that opens
the running watcher's mutex and takes it when the watcher exits: that mutex carries the
watcher's own Medium label, so it is not refused, and status reports a running watcher, as in
v0.5.7. In v0.5.7 a planted mutex makes status report a running watcher and the real one exit
as a duplicate, and a planted, signalled stop event makes a real watcher quit on start, logging
only an ordinary stop request - nothing that points to the planted event.
- Content in a
conversation can pause recovery without a prompt, in v0.5.7 (through `set_auto_recovery`) and
in v0.6.0 (through `pause_auto_recovery`) alike. Pausing withdraws a continuation already
waiting in Codex's queue. From v0.6.0 a withdrawal that can be confirmed returns that recovery
to waiting with its attempt returned, so resuming picks it up; only a withdrawal that cannot be
confirmed (`submission_unknown`), or a pause over an already uncertain submission (`failed`),
is final. In v0.5.7 the recovery is cancelled for good and resuming does not bring it back.
Either way the message is never sent twice.
- From v0.6.0, content in a conversation can also
switch recovery off for one conversation without a prompt, through
`disable_conversation_recovery` - and that one is not reversible. It cancels every recovery
that conversation has waiting, switching the conversation back on does not revive them, and
giving attempts back refuses a cancelled recovery. What it costs is unfinished work left
unresumed, never a message sent twice.
- Whether Codex shows an approval prompt for the tools
marked destructive is up to Codex's approval settings, not this product.
- Nothing this project
builds is Authenticode-signed (the two executables, the setup programs, `Install.cmd`,
`Uninstall.cmd` and the PowerShell scripts); the bundled Python interpreter keeps the signatures
it was published with: the Python Software Foundation's on `pythonw.exe`, `python.exe` and the
Python DLLs, and
Microsoft's on the two Visual C++ runtime DLLs. Releases are not GitHub-immutable. Trust in a
download rests on the pinned digest and the provenance attestation (*Release integrity*,
*Verifying a release*).
- Archives v0.5.0 through v0.5.7 were built by
the earlier single-job workflow with floating action tags and executables that are not
reproducible. For v0.6.0 a rebuild on another Windows machine reproduced, byte for byte, the archive GitHub's runner published,
with the same compiler build ([VERIFY.md](VERIFY.md)); two different compiler builds have never been compared.
- A Custom message is sent as written, and
Codex reads it as your own words. The checks above decide which values it may contain and
that it cannot change what is recovered; they do not judge what it asks Codex to do. Any
program running under your Windows account can also edit `config/settings.json`, as it can
your other files; the placeholder and length checks still apply to what it writes.
- The Codex
compatibility data a refresh fetches is not signed. It comes over HTTPS from this repository's
`main` branch, so anyone who can change that branch can change what the next refresh on every
machine receives. What such data could do is bounded by the rules under *Compatibility data can
only restrict*: at worst it marks a Codex build incompatible and recovery stops for that build
until the data changes again - unfinished work left unresumed, never a message sent that the
local checks would refuse. A document that requires a signature is refused whole until something
verifies one. Any program running under your Windows account can also write
`config/compat-cache.json`; it is validated on every read, and the same rules apply to it.
- What
other people report can be made up. The check a report's pull request runs refuses one that could
not have been measured - a setup that could not have written it, times the machine could not have
recorded, a copy of a filed report - but nothing proves that a plausible report was measured, so
the counts beside a version are only as honest as the people who sent them. They are shown as
other people's reports and change nothing: no state, no check and nothing sent moves with them. -
In the advanced edition, a capability a person turned on does, by design, what the standard edition
refuses. A watcher started with Codex through WMI outlives Codex. A marker-free continuation is
proven delivered only by the client id it was queued under, which Codex keeps on the message; that
`thread/queue/add` takes such an id and delivers the words as plain text was measured once, on one
Codex version (M7), and no marker-free continuation has yet been followed to its turn on a real
Codex. A goal set active is left for Codex itself to carry on, under Codex's own settings, when
the app next opens the conversation. M2 found that the app does not take such a goal up while it
holds the conversation, and saw the goal live again once the app loaded the conversation - which
its record, holding only the failing verdict, does not keep - and nobody has yet followed Codex
carrying such a goal on by itself. Turning the capability off leaves a goal it already set active
as it is. Each rests on a measurement of one Codex version, and a failed
or missing one is a warning the person confirmed rather than a refusal. The policy keys that can
forbid them are what a cooperating installation obeys, not a lock. And a measurement run by hand
makes its calls into the conversation it names from an installed copy as from a source checkout;
only its record is refused where there is no `docs/evidence/live/`.
- A version picked with *Install another version...* that reads an older state has the state
converted before its installer runs. Between the two, reading the state no longer upgrades it - not
through the window, the panel, Codex's tools or the command line - nor does a window or an MCP server
left open after the pick, once the older version's files have replaced the ones it runs from; the
control layer starts no watcher - the window's Start watcher, the bridge's `start-watcher` and
Codex's `start_watcher` tool all wait for the install lock - but a watcher started outside it, from
the command line as an installer's own setup does, would still bring the state back to the current
schema; the older watcher would then refuse that state and send nothing. That fails closed, but
recovery stays off until the installation is repaired. An older
installer can also fail after the conversion: the state then stays converted, which sends less and
never more, and the copy taken first is kept for forensics, not restored.
