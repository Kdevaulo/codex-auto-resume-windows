# Contributing

Thanks for looking. This is a small, deliberately conservative tool, so the most useful
contributions are usually bug reports with a reproduction, and fixes that keep the safety
properties intact.

## Development environment

- Windows 10/11. The product is Windows-only, and so is most of the test suite.
- Python 3.12 or newer, standard library only. There are no third-party runtime dependencies
  and no build step for the Python side. What that promise covers is decided in one file,
  `scripts/python_support.json`: CI runs every non-live test on Python 3.12, 3.13 and 3.14 as
  blocking jobs, and on the 3.15 pre-release as an advisory one whose result is shown but does
  not block; releases are built with 3.13; and the archive bundles Python 3.13.15, so nobody
  installing a release needs a Python of their own. Adding a tested version never moves the
  bundled runtime. `tests/test_python_support.py` fails if the workflows, or the minimum this
  page and the README state, stop agreeing with that file.
- The ChatGPT/Codex desktop app, if you want to run anything beyond the unit tests.
- .NET Framework 4.8 (already on every supported Windows) to build the three C#
  programs — the window, the MCP launcher (`gui/McpLauncher.cs`) and the setup program (`build/setup/`, built by
  `build/make_setup.py`). The window is
  `gui/SettingsApp.cs` for the form and the Settings page and `gui/Dashboard.cs` for the
  navigation and the Overview, Pending, History, Statistics and Diagnostics pages; the soft
  controls both are drawn with are `gui/SoftTheme.cs` (the colours, sizes and motion),
  `gui/SoftDepth.cs` (the shadows), `gui/SoftLayout.cs` (what holds what), `gui/SoftFields.cs`
  (buttons, check boxes, choices and text), `gui/SoftCombo.cs` (the drop-down),
  `gui/SoftCallout.cs` (the callout, a notice set apart), `gui/SoftList.cs` and `gui/Marks.cs`
  (the status light); and `gui/Brand.cs` is the palette, generated. The compile list is
  `gui/window.sources` and only there — a new window source is added to that one file, and
  `build/make_gui.ps1` and every test read it.

Nothing here needs administrator rights.

## Running the tests

```bash
python -m unittest discover -s tests
```

Set `PYTHONPATH=src` first, or run from a checkout where `src` is importable.

The suite uses fakes and temporary directories. It never contacts the ChatGPT app, never
sends a message to a Codex conversation, and never writes to your real registry. The live
read-only checks stay skipped unless you set `CODEX_AR_LIVE=1` on Windows.

Other parts skip quietly when the tool they need is missing, so a green run is not always a
full run. The schema-migration and downgrade tests build their databases from the store
code of real tagged releases, so those tags have to be in the checkout (`git fetch --tags`;
a shallow clone has none, which is why CI checks out the full history).
`tests/test_mcp.py` needs Node to run the panel's own code, and `tests/test_reproducible.py`
and `tests/test_gui_json.py` need the in-box C# compiler.

What a green run does and does not establish is set out capability by capability in
[`docs/FEATURE_MATRIX.md`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/docs/FEATURE_MATRIX.md), and the checks
no suite can make - a real install, a real interruption, a real send - are the procedure in
[`docs/LIVE_ACCEPTANCE.md`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/docs/LIVE_ACCEPTANCE.md).

### In parts

The suite is long - a lane took 78 to 103 minutes on GitHub's runners in September 2026 - so CI runs
every lane in parts, one job each, and you can run it in parts on your own machine.
`scripts/test_parts.py` is the one place the suite is split. It deals the test files into N parts,
balanced by how long each file took in that lane when it was last measured (`tests/data/durations.json`),
and runs each part the way `unittest discover` runs the suite: the same files, loaded by discover itself,
in the same order, one fresh Python per suite.

```bash
python scripts/test_parts.py --parallel 8                   # all 8 parts at once: one summary, one exit code
python scripts/test_parts.py --part 3/8                     # only the third of 8 parts
python scripts/test_parts.py --lane advanced --parallel 8   # the advanced edition's lane
python scripts/test_parts.py                                # the whole suite: `unittest discover` itself
```

It sets `PYTHONPATH` and `CODEX_AR_EDITION` for the lane itself - `standard`, `advanced`, or
`release` (the two suites the release runs before it builds) - gives each part of a parallel run its
own `TEMP` and `TMP`, and starts every child with no console window. Parallel parts share the machine,
so the speed-up is what your processor has to spare. The window tests
contend for one desktop, and the longest file - `tests/test_gui_layout.py`, which lays out every page
in every language at five scalings - is a floor no number of parts goes below.

The parts together are exactly the tests `unittest discover` finds, each once, for every part count
the workflows use: `tests/test_split_runs.py` proves it. Whether a part's results are a whole run's
is a question about the tests themselves, and the runner answers it on your machine. Run with neither
`--part` nor `--parallel`, it runs `python -m unittest discover` itself, suite by suite, as CI ran the
suite before it was split, and records each test's outcome; `--compare` holds that to the parts, test
by test:

```bash
python scripts/test_parts.py --outcomes whole.json
python scripts/test_parts.py --parallel 8 --outcomes parts.json
python scripts/test_parts.py --compare whole.json parts.json
```

`--compare` prints every test id whose outcome differs and, for parts run at once, the part it ran in.
Parts run at once on one machine contend for it, which a whole run and CI's parts - a runner each -
never do: the window tests for one desktop, the probes' timeouts and the timing checks for one
processor. So a local `--parallel` run is not a whole run's result, and a slow probe or a late UI
Automation event can fail there and nowhere else. For each part with a difference, `--compare` prints
the command that runs it alone; hold that to the whole run:

```bash
python scripts/test_parts.py --part 2/8 --outcomes part-2.json
python scripts/test_parts.py --compare whole.json part-2.json   # only the files part 2 ran
```

What agrees there came from the parts running together: contention for the machine, or a name only one
process on it may hold - a mutex or event name, a port, a fixed path outside `TEMP` - which the failure
names, and which is worth making unique although CI never meets it. What still differs means two test
files share something in one interpreter - a fixed temporary path, the working directory, the
environment, a module global, a setting one of them changes and never puts back - and the fix is to make
them independent, never to keep them in one part.

The durations keep the parts even, and they refresh themselves. Each lane has a table of its own,
because one file can take one lane much longer than another. The figures in the repository are GitHub's
runners', where CI's parts run: every part the tests workflow (`.github/workflows/test.yml`) runs writes
what each of its files took with `--seconds` and keeps it as an artifact for 30 days. After every green
run on `dev`, `.github/workflows/durations.yml` reads that run's files with `--refresh-seconds`, and when
a new deal would make some lane's longest part shorter by at least 10 % and at least 3 minutes, it
commits the new table to `dev` and runs the tests there again. It writes only while `dev` is still the
commit it measured, and never to `main`. By hand - a run on another branch, or a gain too small for
the workflow - `--merge-seconds` takes a run's into the durations whatever the gain:

```bash
gh run download <run id> -p 'seconds-*' -D seconds
python scripts/test_parts.py --merge-seconds seconds
```

Each lane's seconds go into its own table, and the other tables are kept; where several jobs timed one
file in one lane, one for each Python, the merge takes their median. `--record-durations` does the same
from a run on your own machine, into the lane it ran, with your machine's times rather than the
runners'. A file a lane's table lacks is dealt by the figure for every lane, and a file never measured
at all round-robin after the measured ones. `--list --parts 8` shows the deal, and `--lane` another
lane's.

A failed run on `main` gets one more try: `.github/workflows/rerun-once.yml` reruns its failed jobs
once, on the first attempt only. A runner's hiccup then does not leave the README's badge saying
failing, and a fault that comes back fails the second attempt too and stays on the badge. It checks
nothing out and runs nothing of the repository's.

## Measuring the window

Speed is a claim like any other, and `build/measure_window.py` is how it is checked rather than
believed. It builds `gui/*.cs` into a scratch folder and walks the real window page by page and
section by section - `SettingsForm.LayoutAudit`, off screen, with no bridge and no timers - at two
languages and two scales, and prints the medians:

```bash
py build/measure_window.py
py build/measure_window.py --tree <another checkout>
```

Timings belong to a machine, so the suite asserts none of them; what it holds is the behaviour the
speed comes from, such as `tests/test_gui_v069_idle.py`, which fails if an unchanged snapshot makes
the window fill a list or rebuild the safety checks again. The v0.6.9 numbers are in that file's
header and in the changelog.

## Validating plugin metadata

The plugin manifest, the marketplace index and the MCP companion file are covered by
`tests/test_plugin.py`. Run the suite after touching any of them; it checks the manifest
against the fields Codex actually accepts, and it fails if the repository manifest starts
declaring an MCP server (see below).

## Building a release

This section describes the release process as it is from v0.6.0. The split of the release
workflow into build and publish jobs, the actions pinned to commits, Dependabot, the
reproducible executables, the CRLF checkout and the executables' version resources are new in
v0.6.0. Every archive from v0.5.0 through v0.5.7 was built by the earlier
single-job workflow, which referred to its actions by floating tags, and with executables that
cannot be reproduced.

```bash
powershell -ExecutionPolicy Bypass -File build/make_gui.ps1
python build/make_release.py
python build/make_release.py --edition advanced
python build/smoke_archive.py build/dist/CodexAutoResume-v<version>-win-x64.zip <version>
```

The first builds `CodexAutoResumeSettings.exe` and `codex-auto-resume-mcp.exe`, makes them
reproducible (below), and prints the compiler it used and each executable's SHA-256; it
needs `python` on `PATH` for that step. The second downloads the pinned embeddable Python
(checksum-verified), assembles the payload, and writes the ZIP and its SHA-256 into
`build/dist/`; with it comes each edition's setup program, `CodexAutoResume-Setup-v<version>.exe` and
`CodexAutoResume-Advanced-Setup-v<version>.exe`, with their `.sha256` files.

The third drives the archive's own bytes: it extracts the ZIP and runs the engine inside
it with the interpreter inside it, against a state directory that exists only for that run,
and reads the version resource off both executables. Nothing outside that directory is
touched - no registration, no watcher, and `plugin_setup.py` is never run, because a smoke
test that repoints the sign-in entry at a temporary folder and then deletes the folder has
broken the installation it was checking. Run it again on the **published** archive once the
release exists: "the build works" and "what people download works" are different sentences,
and only the second is a promise to anybody.

Releases are published by the tagged GitHub Actions workflow, not from a developer machine.
From v0.6.0 it has two jobs. `build` runs the repository's code - the tests and the build
scripts - with a read-only token that checkout does not leave on disk. `publish` holds the
rights to create the release and attest it, runs none of the repository's scripts or tests, and
runs only on a tag push. Every action the workflows use is pinned to a full commit SHA.
Dependabot proposes updates as pull requests; `.github/dependabot.yml` turns on no automatic
merging, and each one is meant to be reviewed and merged by a person. Nothing in the repository
checks its own settings on GitHub.

### Alpha, beta and the release

A version built in stages ships each finished stage as a pre-release while the next stage is
built, so one version can have more pre-releases than one `-alpha` and one `-beta`. The word a
pre-release carries says whether a person can notice what it brings:

- **`-alpha`, then `-alpha.2`, `-alpha.3`, and so on**, when it carries nothing a person can
  notice: refactoring, module splits, groundwork, stored-format or seam work, probes, internal
  tests.
- **`-beta`, then `-beta.2`, `-beta.3`, and so on**, when it carries something a person can
  notice: a new feature, or a change they can see or feel. Once a version has had a beta, every
  later pre-release of it is a `-beta.N`; it never goes back to an alpha.
- **No suffix** - the release - once every stage is done and live acceptance
  ([`docs/LIVE_ACCEPTANCE.md`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/docs/LIVE_ACCEPTANCE.md))
  has passed in both editions.

The plain word is its stage's first pre-release, so the second is `.2`: there is no `.0` or `.1`,
and the number is written in ASCII digits, from 2 to 999, with no leading zero. The words are in
lower case and nothing follows the number. They sort in the order they are made:
`X.Y.Z-alpha` < `X.Y.Z-alpha.2` < `X.Y.Z-beta` < `X.Y.Z-beta.2` < `X.Y.Z-beta.3` < `X.Y.Z`, the
numbers compared as numbers (`.9` before `.10`). Every place that reads this product's version
applies that one rule - the bootstrap, the settings window's build, the release workflow, the
check of the published bootstraps and the product itself - and `tests/test_version_rule.py` holds
them to it. The release workflow builds each such tag and publishes it as a pre-release that never
becomes the latest release; the executables' file version is `X.Y.Z.0` for every one of them, and
the product version beside it carries the whole name.

A bootstrap reads only the words and numbers of its own day: the ones published before the
numbered pre-releases read no number after `-alpha` or `-beta`, and cannot tell an installation at
one from none. They cannot be changed, so a pre-release whose version the newest published
bootstrap cannot read says so in its changelog entry, naming those copies
(`tests/test_legacy_bootstraps.py` fails until it does).

### Making the build reproducible

The build is designed so that, from a fresh clone, with the same build of the in-box
compiler and the same Python build, the same source produces the same archive, byte for
byte, and a rebuild of a tag can be compared with the published digest. How far that has
been verified is set out below. It applies only to a tag whose source contains
`build/normalize_pe.py`, and no release from v0.5.0 through v0.5.7 has one. What it
relies on:

- **The executables.** The in-box C# compiler has no `/deterministic` switch, and two builds
  of the same source differ, as measured, in exactly two fields: the COFF header's timestamp and the
  module's random MVID. `build/normalize_pe.py` sets the first to a constant and the second
  to a GUID derived from the module's own content, as Roslyn's `/deterministic` does for the
  MVID. It locates both by parsing the PE and CLI metadata, and refuses a file that fails
  its structural checks, for example one with a debug directory or a PE checksum. One
  construct adds a third varying value that no after-the-fact edit can fix: a string `switch`
  with enough cases makes the compiler emit a class named `<PrivateImplementationDetails>{GUID}`
  with a fresh random GUID (measured: six cases did, four did not). The normaliser refuses any
  executable that holds such a class, so the build fails on the machine that made it.
  `make_gui.ps1` runs it on both executables. The version resource they carry is
  generated from the manifest, so it depends on the source alone.
- **The archive.** `build/make_release.py` fixes the file order, the entry timestamps and
  the compression level, and writes no build-host path. The `zipfile` and `zlib` modules
  that write it still come from the Python that runs it, so for a comparison use the
  Python line the release workflow uses, 3.13, or at least the same zlib build: on
  Windows, Python 3.14 and later use zlib-ng, which can compress the same files to
  different bytes.
- **Line endings.** The archive packs source files, so their line endings are part of its
  bytes. `.gitattributes` checks every text file out with CRLF whatever the machine's
  `core.autocrlf` says; the repository still stores LF.
- **Checked, not assumed.** The release workflow builds the executables twice and refuses to
  continue if the digests differ, and `tests/test_reproducible.py` compiles a real program
  twice with the real compiler and holds the normaliser to the two-field claim. It also
  compiles a program with a long string `switch` and checks the normaliser refuses it, and
  holds the window's own source to having no such `switch`. That rule was learned from the
  first v0.6.3 release run, whose two builds differed and which published nothing.

How far that has been verified: two local builds, and a build from a separate clone,
produced identical executables; the archive writer reproduced a published archive byte
for byte from its entries with the same zlib (1.3.1). Whether GitHub's runner produces the
same bytes as a local build has not been verified. It depends on the build of the in-box
compiler, which is why `make_gui.ps1` prints it, and on the Python that writes the archive.

### Rebuilding a tag and comparing digests

For a tag whose source contains `build/normalize_pe.py`, start from a fresh clone, so
`.gitattributes` decides the line endings rather than an old checkout, and build with
Python 3.13:

```powershell
git clone --branch v<version> --depth 1 https://github.com/songyb111-gachon/codex-auto-resume-windows.git
cd codex-auto-resume-windows
powershell -ExecutionPolicy Bypass -File build/make_gui.ps1
python build/make_release.py
Get-Content .\build\dist\CodexAutoResume-v<version>-win-x64.zip.sha256
```

Compare the digest with the published `.sha256` and with the version's entry in
[`scripts/release.json` on `main`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/scripts/release.json).
If they differ, compare the `compiler` line and the two executable digests `make_gui.ps1`
printed with the same lines in the release run's log, while GitHub still retains that log,
and compare the files inside the two archives;
[`docs/VERIFY.md`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/docs/VERIFY.md)
has a snippet that does that without extracting either. If every file matches and the
archive digest still differs, look at the Python and zlib that wrote the archive. A tag
whose source has no `build/normalize_pe.py` predates all of this - that is every release
from v0.5.0 through v0.5.7 - and its executables will not match.

### After a release is published: pin its digest

The Codex plugin installs the release by downloading it, so it needs to know what the
archive should hash to. `scripts/release.json` maps a version to that digest, and a version
has no entry there until its archive exists (the v0.5.2 to v0.5.4 tags carried a `null`
placeholder, which the bootstrap treats the same as no entry; v0.5.0 and v0.5.1, published
before the table existed, have none at all). The archive contains `release.json`
itself, so it cannot carry its own digest, and the pin is taken from the published file
rather than from a local rebuild because it has to describe the bytes people download - and
a runner build matching a local one is the part that has not been verified. Absent and
`null` mean the same thing to the bootstrap, so there is no placeholder to add before
tagging and none to find afterwards: publishing adds the key.

So, once the release is up:

1. Download the published `CodexAutoResume-v<version>-win-x64.zip`.
2. `Get-FileHash <zip> -Algorithm SHA256` — and check it against the published `.sha256`.
3. Put that digest in `scripts/release.json` under the version - under `sha256` for the standard archive, and
   under the `advanced` table's `sha256` for the advanced one - and commit.

A planned pre-release - a suffixed tag such as `v0.6.9-alpha` - is not pinned at all. The
table's keys are releases, `releases/latest` never answers with a pre-release, and the check that
a tagged version carries a pin is told about it by the `prerelease` list in `scripts/release.json`
instead. From v0.6.11 the update check can offer a newer pre-release, and installs it only on a
person's yes, against the `.sha256` published beside it - the weaker case below, said as such. That list may name the version under
development and nothing else, so the next bump has to remove the entry
(`tests/test_convergence.py` fails until it does).

Until that commit exists, the plugin verifies against the published `.sha256` sidecar
instead and says so when it runs. That is weaker — the sidecar comes from the same origin
as the archive — so it is worth closing rather than leaving. The commit does not reach the
plugin copy an install registers: that copy carries the archive's own `release.json`, so
for its own version it keeps falling back to the sidecar (or, with `-ArchivePath`, to no
comparison) and says so.

### Do not change a published version

`v0.5.4` is meant to name one archive, with one SHA-256, for as long as the release exists.
There is no supported way to change the bytes behind a published version, and the release
workflow, since v0.5.4, refuses to try: publishing stops if the version already has
assets.

This is not tidiness. The plugin's bootstrap pins a version's digest and refuses anything
else, so replacing a published archive either breaks every install of that version or -
worse - succeeds with bytes the pinned digest does not describe. Two people installing
"v0.5.4" a month apart have to get the same thing.

So a correction gets a new version. If a published archive turns out to be wrong, bump the
version, tag, and publish that; the mistaken release stays as a record of what was actually
released, which is the point of a release.

That refusal is the workflow's rule, not GitHub's. The releases from v0.5.0 through v0.5.7
are not GitHub "immutable releases" - a repository setting; GitHub reports each of them as
not immutable - so someone with write access could still replace an asset by hand. What
would show it is the digest pinned on `main`, and the build provenance attestation checked
against the release workflow and the tag, which is why
[`docs/VERIFY.md`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/docs/VERIFY.md)
tells users to check both.

The manual dispatch still exists. From v0.6.0 it is a dry run: point it at any ref and it
builds, tests and verifies with a read-only token, then keeps the archive as a workflow
artifact. The publish job runs only on a tag push, so a dispatch of the main-branch workflow
cannot create or change a release. That is new in v0.6.0. In the earlier single-job workflow,
which built every archive from v0.5.0 through v0.5.7, a dispatch ran with the workflow's write
permissions. In its v0.5.2 and v0.5.3 versions, a dispatch given a tag rebuilt that tag and
replaced the release's assets (`--clobber`). Those copies of the workflow remain at those tags,
and someone with write access can still dispatch them. Dispatched on its own tag, such a copy
first tries to create that version's release, which fails because the release exists, so it
reaches the replace step only when run from a branch that holds it. In its v0.5.0 to v0.5.3
versions, a dispatch started on a tag with no release yet could also create that release (in
v0.5.2 and v0.5.3, from a build of the ref named in its `tag` input), with no attestation. In
its versions from v0.5.4 on, a dispatch started on a tag, while that version had no assets yet,
could publish and attest a build of any ref whose `plugin.json` declared that tag's version;
the attestation records which event started the run.

> Actions → **release** → Run workflow → optionally set **ref**.

### Changing anything visual

Colours, the icon and the generated files that carry them are covered in
[`docs/BRAND.md`](https://github.com/songyb111-gachon/codex-auto-resume-windows/blob/main/docs/BRAND.md).
The short version: the palette lives in `src/codex_auto_resume/brand/`, `gui/Brand.cs`
and `assets/brand/icon.svg` are generated from it, and `tests/test_brand.py` regenerates
both and compares. Do not write a colour literal into the window or the panel stylesheet.
`tests/test_gui_theme.py` refuses one - a literal, a named colour, or a light brand colour
drawn directly - in every hand-written source of the window: the `[settings]`, `[dashboard]`
and `[controls]` groups of `gui/window.sources`, so a file added to a group is covered without
an edit. The test that catches sizes written in raw pixels (`tests/test_brand.py`) reads the
`[settings]` half only, so a raw pixel size written in the Dashboard's files is on you. Other
tests do read those: every Paint handler must sit on a buffered control, every class that
draws itself must be double-buffered, and the long-lived bridge's command line is executed for
real.

## The MCP declaration is added at build time

The repository manifest declares only `skills`. The release build adds `mcpServers` to the
copy it packs beside the bundled interpreter. That split is deliberate: the MCP server runs
on the interpreter that ships in the release archive, so declaring it in the repository would
make a marketplace install from GitHub register a command that is not there. Please do not
"fix" that by moving the declaration into the manifest — the build refuses to run if both
declare it.

## Translations

The interface speaks sixteen languages, and every word of it - the Dashboard, the popup and
menu, notifications, the panel in Codex and the continuation message - comes from a catalog:
`src/codex_auto_resume/locales/<locale>.json`, one per language. Two more catalogs, Arabic and
Hebrew, are complete and held: nothing offers them until every surface mirrors right to left
(`l10n.HELD`), and every rule below holds for them as for the rest. English (`en.json`) is the
source. Every other catalog is a translation of it, and at runtime English fills in any key a
translation has not reached yet. A new sentence a user will read is a new key in `en.json`.

A translation is only as current as the English it was made from, so `build/l10n.py` records,
key by key, a digest of that English in `build/l10n/<locale>.basis.json`:

```bash
python build/l10n.py status                 # missing, stale and extra keys, per language
python build/l10n.py export ja > work.json  # only the keys that need a translator
python build/l10n.py import ja work.json    # merge, validate, record the basis
python build/l10n.py mark ja KEY [KEY ...]  # reviewed: still right for the new English
python build/l10n.py prune ja               # drop keys English no longer has
python build/l10n.py check                  # exit 1 if anything is incomplete
```

So adding an English string, or changing one, is not finished until every catalog has caught
up: the key is missing or stale in every other catalog, and `tests/test_l10n.py` fails until each
has been translated and imported, or marked as reviewed. An import that loses or invents a
placeholder is refused. Nothing here reaches the network, and a test holds the localization
modules and this tool to that.

A catalog is also held to how it is drawn. `tests/test_glyph_coverage.py` looks every character
of every catalog up in the faces each surface draws with - Segoe UI and the faces Windows links
to it, and the panel's type stack - and `tests/test_words_fit.py` lays the popup and the
notification card out with every string of every language at every scale, so a new script or a
long word is found before a person sees a box or a cut line. A letter drawn from a linked face is
not a box but is still a word in two faces, so `tests/test_typeface.py` holds every surface to one
face per language: where Windows' interface font lacks one of a language's letters - Vietnamese on
a Korean Windows - that language is set in Segoe UI on the Dashboard, the popup, the card and the
panel alike (`win/typeface.py`). Right to left, the popup, the card
and the panel mirror already (`tests/test_right_to_left.py`); the Dashboard window does not yet,
and that is what keeps Arabic and Hebrew held.

## Branches and languages

Three branches carry the documents three ways:

- **`dev`** holds every document in both languages: `X.md` and its Korean sibling `X.ko.md`,
  written and reviewed in the same commit. Work happens here, and every Korean check runs here.
- **`main`** is English only. It is the repository's front page, the branch the plugin
  installs from and the one releases are tagged on. It receives dev by a *promotion*, never a
  fast-forward: `python scripts/promote.py to-main --title "..."` merges dev, deletes every
  `*.ko.md`, and names the dev commit in a `Korean-sources:` trailer. What main receives on its
  own - the compatibility data, published by pull request - goes back with
  `python scripts/promote.py into-dev`, which keeps dev's Korean documents exactly as they were.
- **`ko`** is generated from `main`, by `.github/workflows/sync-ko.yml`, every time main's
  tests pass - and it is force-updated: main's code, with the Korean sources of the dev commit
  main was promoted from written over the English pages. A pull request against `ko` cannot be
  merged and an edit made there is lost at the next sync, so please do not spend an evening on
  one. The sync tests the tree in four parts at once before publishing it, and
  `.github/workflows/ko-watch.yml` fails a scheduled run when ko is still behind main six hours
  after main moved - a stalled sync used to read only as "cancelled".

CI holds the split: on a push to `main` no `*.ko.md` may exist, and on a push to `dev` every
mapped one must (`tests/languages.py`, `tests/test_korean.py`), so dev cannot quietly skip its
Korean checks and main cannot grow a Korean file back. And dev is tested as main will hold it:
`test.yml`'s `main-tree` job takes every `*.ko.md` off dev's tree, as a promotion does, and runs the
release's suite on what is left, so a test that reads a Korean page without asking `tests/languages.py`
whether this checkout holds one fails on dev - not on main, or in the release.

`ko` was an independent fork until v0.5.5, with its own copy of the engine, the installer,
the workflows and the tests. It ended up three releases behind while still telling Korean
readers that the tool made no network request and that installing meant downloading a
release archive. That is what a second copy of a codebase does when somebody has to
remember to merge it.

So the code on `ko` is main's code, and the only difference is the language of the
documents. To change something there:

- **code, installer, workflows, tests** — change them on `dev`; they reach `main` at the
  next promotion and `ko` at the sync after it.
- **Korean prose** — change the `.ko.md` file on `dev`, beside its English page.
  `scripts/ko_branch.json` maps each one to the English page it replaces. What stays English is listed there too, with the
  reason: the licence, because a translated licence is a second licence, and the Codex
  skill, because it instructs Codex rather than a person.

`python scripts/ko_sync.py --check` on dev shows what a sync would do without writing anything.
Adding a Korean page means adding the file and its mapping entry in the same commit;
`tests/test_korean.py` fails if a Korean page exists that nothing maps.

The mapping also records which English revision each translation was made from. Change an
English document and the suite fails naming both files, because a translation that goes
stale quietly is how `ko` spent three releases describing a tool that no longer existed.
Update the Korean, then record it:

```bash
python scripts/ko_sync.py --reviewed README.md
```

Nothing here is machine-translated. A person decides what the Korean says; the digest only
records that somebody did.

## Screenshots

`python build/make_screenshots.py` renders the whole set from the working tree - every Dashboard page, the Codex
panel, the popup and the notification card, in English and Korean, and some of them also in Japanese,
Simplified Chinese and German - into
`assets/` with copies in `docs/images/`. The motion pictures, the social preview and the Advanced page's stills
have generators of their own: `build/make_motion.py`, `build/make_social.py` and `build/advanced_shots.py`. Nothing is captured by hand and nothing is edited
afterwards. A whole regeneration is two steps, in this order, both from PowerShell - launched
from a POSIX shell such as Git Bash, headless Edge exits at once and prints nothing:

```
python build/make_screenshots.py
python build/make_screenshots.py --breathe
```

**A picture of a light that moves, moves.** Every surface's status light is animated in its
pictures as it moves in the product, as an APNG whose first frame is what a viewer without
animation shows. Each surface declares its lights - where each is, its radius, its state and the
ground it stands on - and the manifest keeps them under `lights`: the popup and the notification
card are drawn moving by their own renderers in the first step, and the window and the panel are
captured still, at the first moment of the breath, so the second step draws every light they
declare over the capture, on its own ground, for exactly one cycle. It refuses a capture whose
light does not stand where it says or on the ground it names, rather than paint a box of the wrong
colour. Forgetting the second step leaves the window's and the panel's pictures still, and the
suite says so.

**Each design is pictured too.** Besides the set above, the Dashboard's Overview, the panel, the
popup and the notification card are drawn in each Design other than Soft - Classic and Plain - in
English and the light theme, as `docs/images/design-<design>-<surface>.png`.
They are documentation only and never copied into `assets/`.

**Only what moved is drawn, side by side.** Both steps first hold the manifest against the working
tree and draw only the pictures whose inputs moved, whose files are not the bytes the manifest
records, or - for the window - that were captured at another display scaling; the rest are kept as
they are. A change to the generator itself draws everything, and so does `--all`
(`python build/make_screenshots.py --all`, `python build/make_screenshots.py --breathe --all`). What
is drawn is drawn side by side, each job - one language's window pages, one panel, one popup - in a
process of its own: the windows' jobs all at once, and the others half the processors at a time and
never more than eight (`--jobs N` says how many). Stopping a run - Ctrl+C, or a job the run cannot
read - ends every job it started and starts no other, and a job ended so closes its windows with it;
a run killed outright takes its jobs with it too, since they run in a Windows job of the run's.
The window is photographed as soon as it says that the page it opened on is drawn from the bridge's
answers and holds still, rather than a fixed fifteen seconds after it started:
`build/capture_window.ps1` hands it the name of an event to set, through a variable only the capture
sets, and still waits no longer than those fifteen seconds; a window still busy then is photographed
once it answers, as before, and the picture is the same. A capture is given up only thirty minutes
after its window started: it was five, and a machine whose processors were all taken by other work
outran that with windows that were only slow. One window is on screen at a time unless
`--windows N` asks for more (`python build/make_screenshots.py --windows 2`): a window spends most
of its start drawing text through parts of Windows every process shares, a dozen started together
each took two minutes, and a session once crashed while several windows were being captured at
once. Each is photographed with PrintWindow, which draws a window whatever
covers it, and one at a time from the moment its caption is painted inactive to the moment it is
closed. None of them takes the foreground - a new window otherwise does once nobody has typed for a
while, and the foreground window's caption comes out active - and a picture whose caption is active
all the same is taken again, and after five tries not kept.

It needs Windows, Microsoft Edge (it is what renders the panel), and
`build/CodexAutoResumeSettings.exe` already built — run
`powershell -ExecutionPolicy Bypass -File build/make_gui.ps1` first. The first run also
downloads the pinned embeddable Python into `build/cache/`.

They are pinned to light. The product follows the reader's Windows and Codex themes at
runtime; the pictures do not, so that a gallery looks like one product and a build on a
machine in dark mode produces the same bytes as a build on one in light mode. Since v0.6.6 that
holds for the notification card as well, which until then was pictured in both themes. The Design
is pinned the same way: every picture is Soft's but the designs' own.

`assets/screenshots.json` records a digest of every input each image was rendered from.
The window is recorded in two halves. One is the files it is compiled from — every source
`gui/window.sources` compiles (one `<window sources>` input), its DPI manifest, the plugin manifest, the icon, and the capture and
build scripts; `WINDOW_INPUTS` in `build/make_screenshots.py` is that list. The other is what
the bridge tells it: the generator asks the bridge the window's own questions against a
scratch installation, with the clock, the paths and the machine's answers pinned, and records
a hash of the replies (`<bridge envelope:*>`). The panel is recorded as its rendered markup,
and the popup as the view it draws plus a digest of the code that draws it, pooled by
definition name across the popup's modules and the palette's, and across what those import by
name from the rest of the package, wherever it is defined. So moving code from one module
to another leaves the manifest alone, while a change to anything a picture shows — a word, a
row, a figure, a status, a colour — does not. Change one and `tests/test_screenshots.py`
fails telling you to re-run the generator. It is the mechanism that stops a screenshot
describing a version of the product that no longer exists.

To see what a `<bridge envelope:*>` entry is made of, run this from the repository root; it
prints the questions and the replies the digest is taken over:

```
python -X utf8 -c "import sys; sys.path.insert(0, 'build'); import make_screenshots as m; print(m.bridge_envelope('en'))"
```

**The notification card is rendered, not photographed.** The generator draws it off-screen
the way `tests/test_notice_card.py` does — a `notice_window.Card` with no windows, painted by
the popup's renderer, with its floating shadow over the theme's canvas — from the notice the
watcher's own builder makes for the sample's usage limit, with the reset time read on a clock
pinned to UTC. `<card render:*>` records what it says and a digest of the code that draws it,
pooled the way the popup's is, across the card's modules, the package they move into and the
popup's renderer and palette. To make only those pictures and their manifest entries, which
needs neither Edge nor the window:

```
python build/make_screenshots.py --cards
```

Windows' own notification, which appears instead wherever a card must not, is not pictured. The
shell draws it in the machine's theme, so a capture cannot be pinned, and the one this
repository carried until v0.6.5 had fallen behind the product — no Open Dashboard button, the
old identifier line — before anything noticed. If you photograph one for an issue, never
photograph a real conversation: it shows the conversation's identifier, and a screenshot of a
real one publishes it permanently.

**Every surface is pictured from one set of records.** The window's sample records
(`seed_window_state`) are written once, at the moment the popup and the panel are drawn at, and read
back the way each surface reads them: the popup's rows and the panel's rows are the window's two
waiting recoveries, with the same names, states and times, and the panel's page is told that moment
and reads clock times in UTC, as the card does. The window itself is seeded again when it is
photographed, with the same offsets, because the bridge behind it runs on the real clock, and it is
told, through a variable only the generator sets, to print that moment as the popup's and the
panel's, in UTC: every date and time of day it prints, such as History's, is moved by as much. So a
countdown, a chip, a count and a time of day say the same on all four pictures, a run on another day
draws History again byte for byte, and its times do not depend on the PC's time zone; until
v0.6.12-alpha History printed the day the pictures were drawn.

**To audit the look, draw both themes side by side.** The committed pictures are the light theme's
only. For a change to how the product looks, draw contact sheets of the window's Overview and
Pending pages, the top of the panel, the popup and the card, in the light and the dark theme, every
surface at the scale the window is captured at:

```
python build/make_screenshots.py --audit <folder>
python build/make_screenshots.py --audit <another folder> --before <folder>
```

The second form adds a before-and-after sheet per theme. It needs what a whole run needs - Windows,
Edge and the compiled window, run from PowerShell - and writes only into the folder it is given: it
refuses a folder in `docs/` or `assets/` and never touches the manifest. The window is captured from
a scratch installation, as for the published pictures, so your own installation is never touched.

## Fixtures and privacy

Everything committed here is public, including test fixtures and documentation examples. They
are written on a developer's machine, and that machine's own paths and identifiers leak into
them very easily. `tests/test_repo_hygiene.py` enforces the conventions below, so please keep
to them rather than working around it.

- **Home directories in examples are placeholders.** Use `ExampleUser`, `Example User` (when
  you need a path containing a space), `someone`, `<user>`, or `%USERPROFILE%`. Never a real
  account name.
- **UUIDs in tracked files are obviously synthetic.** Use the project's fixture family,
  `0a1b2c3d-0001-7000-8000-000000000001` and friends, or a repeated-nibble value such as
  `22222222-2222-7222-8222-222222222222`. Never a conversation id copied out of real Codex
  state — real ones are UUIDv7 values with a timestamp prefix and are trivially recognisable.
- **No copied runtime state.** Databases, logs and `config/` are never tracked. If you need
  evidence that something behaves a certain way, write a fixture that shows the structure with
  synthetic values, the way `docs/evidence/` does.
- **No real process ids, ports or machine-specific paths** in comments, docs or fixtures.

## Changes that need extra care

The recovery engine is small on purpose, and several of its properties are the whole reason
the tool is safe to leave running. A change that touches any of these needs a test that would
fail without it:

- a conversation is identified by its exact UUID, and by nothing else — never `--last`, never a
  title, project, working directory or recency;
- a failure that cannot be classified is never retried;
- user cancellation, permission, approval, content policy, invalid requests, context length and
  permanent authentication failures are never retried;
- a submission whose outcome is unknown is never automatically resent;
- every gate is re-checked immediately before sending, inside the dispatch lock;
- settings are policy only. Nothing in the settings schema may reach a safety limit, and the
  worst a malformed settings file can do is make recovery more conservative;
- the text of a Custom message is written only through the Dashboard's control layer, never
  through an MCP tool, and its placeholders stay a whitelist;
- no front end - the Dashboard, the notification-area popup, the panel in Codex - gains a way
  to put a continuation into Codex. The watcher is the only thing that sends.

If you are unsure whether a change crosses one of those lines, open an issue first and say
what you are trying to achieve — there is usually a way to get there that keeps the property.

## The standards

[STANDARDS.md](STANDARDS.md) is every rule the product keeps, by id, and
[EDITIONS.md](EDITIONS.md) says what they mean for the two editions: the standard edition keeps
families 0 and A to J, each advanced capability names the ones it departs from, and family K binds
every capability. The list is the owner's; adding or changing a rule is the owner's decision, made
in a commit like any other.

- **Adding a rule.** It takes the next number in its family. Ids are never renumbered or reused,
  because capability statements, the registry and the other documents cite them. Its line under
  the rule says how it is held - tested, code, docs, model or planned - and names the tests that
  hold it. In the same commit, the table of families in the advanced package's `standards.py`
  (under `advanced/src/`) gets the family's new count: `advanced/tests/test_advanced_registry.py`
  fails while the file and that table disagree, family by family, and while a test the file names
  is not in the repository.
- **Changing a rule.** It keeps its id and its place, and its sentence ends with who changed it and
  when: *(amended by the owner on 2026-09-28)*. If a capability's statement describes the rule, the
  statement changes with it, under a new revision, which turns that capability off until a person
  has read the new one (K7).
- **Both languages.** `docs/STANDARDS.ko.md` changes in the same commit, rule by rule:
  the test above also requires the same ids in the same order, naming the same tests. Then record
  it with `python scripts/ko_sync.py --reviewed docs/STANDARDS.md`.

## Sending a compatibility report

A report about a Codex version is written on your own machine by
[codex-compat-reporter](https://github.com/songyb111-gachon/codex-compat-reporter), from this
installation's own records: counts, states and times, no conversation text and no identifiers. Read
the file before you send it. It reaches GitHub only as a pull request you open, from a branch whose
name starts with `compat-report/` - the reporter's `submit` opens it from
`compat-report/codex-cli-<version>` - and that pull request adds exactly one new file, at

    docs/evidence/community/<your GitHub login>/codex-cli-<version>.json

where `<version>` is the report's own `codex_version` and the login is the one that opens the pull
request (and the report's `reporter.github_login`). One opened by hand from another branch
(`patch-1`, say, GitHub's name for an edit on the web) is refused by the check: the filer below
answers for `compat-report/` branches only. Reports are add-only: one per GitHub login per
Codex version, and a filed report is never edited. A pull request that changes anything else, adds
a second file, or adds one at a path already filed on the base or on `main` is refused, and so is a
folder that differs from a filed one only in letter case, since Windows opens the two as one.

The pull request is judged by `.github/workflows/community-report.yml`, which runs `main`'s own
check (`build/community_check.py`) on `pull_request_target`, so no pull request can change the check
it is judged by. It checks out the base commit under a read-only token and no secret, and reads your
commits as data with git plumbing only: nothing in them is checked out, merged or run
([SECURITY.md](SECURITY.md) has the whole list). The file must be at most 1 MB, UTF-8 JSON in the
report format with exactly its keys, read by `build/community_report.py`, the one reader of a
report. Its fingerprint has to be a setup that could have written it - the Codex version in the
grammar the product names engines by, a product version that is one of this repository's releases
and was out before the report was written, a plain reporter release from 1.0.0 on, Windows 10 or
later - and its times ones the machine could have recorded. A report with at least one record must
not repeat the records of a report already filed for the same version; a report with no records is
never refused as a copy. The levels and verdict a report claims are recomputed from what it
measured and only ever lowered, so a hand-edited conclusion does not survive. The Codex version
is written the one way the product writes it (no leading zero, no alpha `.0`), and the login may
not be a name Windows keeps for a device (`con`, `nul`, `com1` and the rest), since no Windows
checkout could hold that folder.

A report that passes is filed with no step by the maintainer, by
`.github/workflows/community-file.yml`: usually within minutes of the check finishing, and
otherwise on its daily run. It judges the report again, against `main` as it is by then, with the
same check, and files this project's own regeneration of it - never your bytes: every conclusion
recomputed from your records and every sentence replaced by ours. Your pull request is then closed,
not merged, with one comment that says where the file went. That one comment is edited, never
repeated, whenever what it says changes. What a maintainer used to decide is now a rule, and a
report that meets one waits rather than being refused:

- the account has to be at least 30 days old; a younger one's pull request is closed, with the date
  it can be sent again;
- one open report pull request per account at a time; another is closed, and can be sent again
  once the first is closed;
- at most 3 reports are filed from one account, and 5 for one Codex version, in any 7 days; more
  wait, with the date they are looked at again;
- a Codex version older than those the project's own compatibility data names waits for the
  maintainer; a newer one is filed while fewer than five such versions have reports;
- a report that a recovery failed on a version this project's own evidence verifies waits for the
  maintainer, who looks at that first;
- nothing is filed while `main`'s own tests are failing, or while filing is paused.

A waiting pull request's comment gives the reason and when it is looked at again; there is nothing
for you to do. A refused one's says, line by line, what to do about each reason; a new commit on
it is judged again, and one refused and left unchanged for 14 days is closed. One report pull
request per account is open at a time, and the reporter's `submit` keeps to that, so sending the
report again starts by closing the refused one - its comment says so. Filing is paused by the
repository variable `COMMUNITY_AUTOFILE` (anything but unset or `on`), an account's reports are
refused by listing its numeric id in `COMMUNITY_BLOCKED`, and the maintainer's own tool can still
file a report that waits or is refused that way, or withdraw one; the pull request of a report it
files is then closed as filed, with the same one comment.

Once filed, a report counts towards *Reported by others* beside its Codex version on the
Dashboard's Diagnostics page ([GUIDE.md](GUIDE.md#requirements) says how it is counted), from the
next release on: the same commit that files it writes `docs/evidence/community/index.json`, the
folder's README and the counts in `src/codex_auto_resume/data/reported.json` again, with the same
code whoever files (`build/community_report.py`), and `tests/test_reported_data.py` holds the
files, the index, the README and the shipped counts to each other. The commit names your login and
your account's numeric id, which is what the weekly limits count. A report file the index does not
list counts nowhere, which is why your pull request stays green under the ordinary tests. A report
found to be wrong is withdrawn in the open, by removing its file and its index entry together, and
the account and that Codex version are listed in `docs/evidence/community/withdrawn.json`, so the
same report is not filed again; the account's reports on other Codex versions are judged like any
other. No report enters the compatibility data, and none changes a tier.

## How the code is layered

The Python package is built in layers, and its imports point one way: down or sideways,
never up.

- **Domain** — the rules with no side effects, gathered in `domain/`: the stored states and
  the legal moves between them (`domain/states.py`), the gates a record passes before
  anything is sent (`domain/gates.py`), what a person is shown for a record
  (`domain/public.py`), every identifier (`domain/ids.py`) and every closed list of words
  (`domain/vocabulary.py`), beside how a failure is classified (`failures.py`) and which
  reasons are recoverable (`reasons.py`). `machine.py` is the front over the first three.
  The standard library only, and only the parts of it that touch no clock, file or process.
- **Policy and translation** — the settings schema, the continuation builder, the catalogs,
  paths and the product version, and the log.
- **Adapters** — everything that touches the outside: the store, Codex's files and processes,
  Windows (the registry, the Start menu shortcut, PowerShell, notifications), and the
  compatibility registry.
- **The engine** — decides and schedules. It reaches Codex and the store through what it is
  given rather than by importing them.
- **Control** — the one layer a front end calls.
- **Front ends** — the command line, the bridge the settings window talks to, the MCP server
  and its panel, the watcher's runtime, the notification-area icon, its popup and the card.

`tests/test_layers.py` places every module in one of these, and fails an import that points
up, a module with no layer, and an import cycle. Where the code does not match the map yet,
the test lists the real exceptions, and each one fails the test once it is gone, so those
lists only shrink. A rule about a module holds for everything inside it once it is a package,
and for the packages the split creates (`codex/`, `win/`, `ui/`, `mcp/`) before they exist, so
moving code under a new name does not take it out of a rule. The same file lists every import
made inside a function, with its reason; a new one needs a line there. `tests/test_sizes.py`
gives every module a budget of 700 lines, and holds each module already over it to exactly the
length it has now: a commit that shrinks one lowers its ceiling, so it cannot grow back.

`tests/test_stack.py` asks the other question: not which way a call points, but which binary
the code ends up inside. `docs/ROADMAP.md` names the eight parts the Rust core is planned to be
built from, and that file places every module on exactly one of them — or on one of the parts
the Windows interface keeps, or on the few that are neither. It then holds the placement four
ways, each of which only shrinks: items with no package of their own, packages whose modules
are not all one item, single modules doing two items' work, and the graph of which item calls
which. A module can sit in the right layer and still belong to two items, so a new one needs a
line there as well as in `test_layers.py`.

The window's C# is held the same way. `gui/window.sources` is the compile list and the only
place it is written, divided into `[settings]`, `[dashboard]`, `[controls]` and `[generated]`;
`tests/guiscan.py` reads it, and a rule about the window's code asks for a group rather than
naming a file, so a file added to a group joins every rule about it. `guiscan.type_body` and `guiscan.member_body`
find a type or a member by its braces and raise where it is not there — which is what a slice
that ended at "the next `private void`" did not.

A test that asserts something about the source itself — that only the watcher sends, that the
popup reaches nothing that can submit, that no module builds its own PowerShell command —
reads it through `tests/srcscan.py`: every tracked `.py` file under `src/`, at any depth, and
for each import also the package `__init__.py` files Python runs to reach its target. Do
not read one module by name, or glob one directory, to assert that something is absent: when
the code moves, a test like that keeps passing and stops checking. `tests/test_srcscan.py`
refuses both shapes, and fails when a `.py` file under `src/` is not tracked, because an
untracked module is invisible to every scan while the suite still runs it.

Some paths are contracts with programs outside the package and do not move:
`src/auto_resume.py` (it is in users' sign-in entries) and `src/codex_auto_resume/cli.py` (an
older launcher, already installed in a user's home, looks for both), and the module names
the settings window, the MCP launcher, the bootstrap and the release check call.
`tests/test_structural_invariants.py` pins them.

What the bridge and the MCP server answer is a contract too: the settings window and the
panel in Codex read those answers by field name, and nothing else connects them to the Python.
`tests/golden/` holds one file per bridge command and per MCP tool, made by
`tests/wiregolden.py` in a scratch installation with the clock, the paths and the machine
pinned. `tests/test_wire_goldens.py` makes them again on every run and compares them byte for
byte, and `tests/test_consumer_fields.py` fails when the window or the panel reads a field no
golden answer carries. Moving code leaves every one of them exactly as it was. A change that
means to alter an answer regenerates them with `python -X utf8 tests/wiregolden.py --write`,
and the diff is reviewed with the change.

Some rules are stated in one place on purpose: which wait a record goes back to, what a claim
costs its budgets, whether a record may be sitting in Codex's queue, how a command opens the
state, which settings are the user's own words, and a few more. `tests/test_single_rules.py`
pins what every caller gets from each of them, and fails when a second implementation of one
appears anywhere in the package. Call the one that exists - `machine.waiting_state`,
`machine.may_be_queued`, `openstate.open_state`, `settings.is_custom_text` and the rest the
test names - rather than writing the rule again. Every JSON writer passes `allow_nan=False`
and no `default`, which `tests/test_json_writers.py` checks: a value that is not JSON is a bug
to fix where the value is made, not text to write.

Reading an identifier is one of those rules. A conversation id, an interruption id, the marker
a continuation carries and a client id are read only through `domain/ids.py`, which also
computes an interruption's id; where two readers accept different spellings, the parser takes a
parameter rather than the reader keeping a pattern of its own. `tests/test_domain_vectors.py`
holds the exact bytes of those ids, the gate vector and `settings.json`, and what each reader
takes. The closed lists of words - states, codes, reasons, gates, categories, refusals,
choices - are one `StrEnum` each in `domain/vocabulary.py`. The module that used a list keeps
it under its old name, made from the enum (`machine.STATES = frozenset(RecordState)`), so a
word is added in one place; `tests/test_vocabulary.py` holds every list to its members and
every member to hashing, comparing and being written exactly as its string.

## Commit and pull requests

- One change per commit, with a message that says what changed and why.
- Run the full suite before pushing.
- If you fixed something a user could hit, add the regression test in the same commit.
- A commit that only moves code — lines moved verbatim into another file, nothing else
  changed — is listed in `.git-blame-ignore-revs` by a later commit, so that `git blame`
  credits each line to the change that last really touched it. Run this once in your clone:

  ```bash
  git config blame.ignoreRevsFile .git-blame-ignore-revs
  ```

## Reading the history

The full history is kept: every commit that landed is still there, with its own message, so
`git bisect` finds the commit that changed a behaviour and `git blame` names the change that
wrote a line.

To read it by release instead:

- from v0.6.5 on, each release arrives on `main` as one merge commit, so
  `git log --first-parent main` is one line per release;
- for every release, including the older ones, the changelog entry links the commits it
  contains, and `git log --oneline v0.6.3..v0.6.4` shows the same range in a clone;
- `git tag` lists the releases themselves.

Nothing about the history is rewritten to make it shorter: the published tags, the digests
pinned beside them and anybody's existing clone all point at these commits.
