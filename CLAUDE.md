# Orrerix — instructions for Claude Code

Tauri 2 desktop terminal multiplexer for AI agent management. Rust backend
(`src-tauri/`), vanilla-TypeScript frontend (`src/` — no UI framework), xterm.js
terminals, Vite. `doc/design/architecture.md` maps every module; deeper designs
live in `doc/design/`.

The repo root is a **Cargo workspace**: `src-tauri` (the desktop app, links
Tauri), `crates/loomux-engine` (the Tauri-free orchestration core, filling up
one batch at a time as #888 moves modules into it) and `crates/loomux-server`
(the remote-engine daemon that will host that core — a binary, and a leaf
nothing else depends on). One `Cargo.lock` and one `target/`, both at the repo
root. See `doc/design/engine-extraction.md` and
`doc/design/remote-engine-daemon.md`.

## Commands

| What | Command |
| --- | --- |
| Typecheck + bundle frontend | `npm run build` (runs `tsc --noEmit` first — this is the typecheck) |
| Frontend unit tests | `npm test` (Node 22 built-in runner, runs `test/**/*.test.ts` directly) |
| One frontend test file | `node --test test/layout.test.ts` |
| Backend check (what CI gates on) | `cargo check --locked --workspace` at the repo root |
| Backend tests | `cargo test --locked --workspace` at the repo root |
| One backend test | `cargo test --locked -p orrerix --test orchestration <name_filter>` at the repo root |
| Run the app | `npm run tauri dev` — opens a GUI window and never exits; don't run it unattended |

There is no lint/format gate (no eslint/prettier; rustfmt is not enforced in
CI) — match the surrounding style instead of reformatting. (Agents may still
run `rustfmt --check` as a *syntax* check, discarding its formatting
opinions — see the `ci-validate` skill.)

### Running these in an agent worktree

- **`npm ci` before any `npm`/`node` command.** `node_modules/` is gitignored
  and not shared between worktrees, so a freshly-cut one has none. A
  missing-package error is *you never installed*, never a red suite — the
  `ci-validate` skill has the trap in full.
- **Most text files are CRLF on disk and LF in the blob** — `core.autocrlf=true`
  is this project's Windows baseline. `.gitattributes` overrides that with
  `eol=lf` for three classes, which are LF at BOTH ends: the files a build
  rewrites, the vendored trees whose contract is byte-identity with upstream,
  and the prompt templates plus their `pre222` goldens, whose embedded bytes
  are a measured budget rather than a checkout artefact (#1845). Never assume
  which side a file is on — `git ls-files --eol <path>` answers it, and a file
  whose rule was added after your worktree was cut is CRLF on disk anyway until
  you DELETE it and check it out again (`rm` the files, then `git checkout --
  <dir>`). `git add --renormalize .` does NOT fix a worktree — it rewrites the
  index only, silently, leaving a clean `git status` beside a still-CRLF file —
  and a plain `git checkout --` without deleting first is a no-op, because git
  considers the file up to date (#1845).
  For the CRLF majority, a `node -e` anchor built from an LF string, or from
  `git show <ref>:<file>`, never matches the worktree copy, and writing one back
  with bare LF silently flips that region's endings. Read the file's own EOL and
  rewrite your anchor to match; run a byte-identity or prefix proof
  blob-vs-blob (`git show` both sides), never blob-vs-worktree.
  Signature: `anchor not found` on a string you can see in the file (#1196).
- **Anchor every `cd` at an absolute path.** The Bash tool's cwd persists
  between calls, so a second relative `cd src-tauri/src/...` resolves against
  the previous `cd` and fails with `No such file or directory`.
- **There is no `python3`** — the `WindowsApps` alias stub exits 126
  (`Permission denied`). Use `node -e` for ad-hoc scripting. A scratch script
  **must be `.cjs`**: the root `package.json` sets `"type": "module"`, so a `.js`
  file in its scope — `./.scratch/` included — is ESM and `require` is a
  `ReferenceError: require is not defined in ES module scope`, not a broken
  script. Node resolves `"type"` from the NEAREST `package.json`, so `npm/` (no
  `"type"`) is CJS and `npm/bin/orrerix.js` uses `require` correctly (#1181).
- **A multi-line shell script is a file, not a `-c` argument.** Inline Bash dies
  on Git Bash quoting (`unexpected EOF while looking for matching '`, reported
  far from the real line). Write it under `./.scratch/` and run the file; pipe
  prose to `gh` with `--body-file -` (#1181).

### Agent workers: NO local Rust builds — CI is the only build/test path

The Commands table above is for humans. For agent workers, **local
`cargo` builds and tests of ANY size are banned entirely** — no `cargo
build`, no `cargo check`, no single-test `-j 4` iteration, nothing that
invokes `rustc`. This is a human hard directive: a first compile costs
5-8 GB of `target/` per worktree, and a worker fleet building locally
exhausts the disk (#488).

How workers validate instead: push early, open a draft PR immediately,
and read CI (`ci-validate` skill's draft-PR-early flow). Iterate by
reasoning + pushing; CI is both the proof and the compiler.
Frontend-only commands that never invoke `rustc` (`npm run build`/`tsc`,
`npm test`/`node --test`) remain fine locally once `npm ci` has run in the
worktree (see above), as does `rustfmt --check --edition 2021 <changed .rs>`
— a parser, not a build, and the one pre-push
syntax check for Rust (#558; see the skill for the read-stderr recipe and why
`cargo check` is not covered). The one `cargo` exception: `cargo update
--workspace` for release lockfile bumps — dependency resolution only, never
compiles.

## Hard constraints — check before coding

1. **Never resize the PTY for a UI feature.** Git view, task board, audit
   viewer, badges, compose strip — all are overlays or header/board chrome
   floating over the terminal. Resizing ConPTY triggers full repaints that
   pollute scrollback. Visual padding belongs on the `.xterm` element, not on
   the layout.
   **Two panels are in the layout, and both are deliberate**: `#sessions` and
   `.sidedock` (#1150, at the human's direction) are flex siblings of
   `#grid-area`, so opening either autosizes the open panes. What makes them
   permissible is not that they are old or asked-for: it is that each width
   change is a DISCRETE human click whose purpose is to change how much room
   the terminals get, and that `src/resizeburst.ts` collapses the whole
   animated burst into one fit per pane at the settled geometry. One known
   exception is open and watched rather than claimed away: the dock also
   re-widths itself when the room around it changes, so one panel's slide can
   chain onto the other's ease and outrun that coalescer (#1203). A PASSIVE or
   continuous trigger (a focus change, a follow, a timer, an attention flip)
   may still never reach a PTY resize — the side dock's own pane-following
   costs zero, and that is the line, not the panel count. Adding a third
   in-flow panel, or animating one of these two for longer than
   `FIT_MAX_WAIT_MS` minus a window, needs the argument in
   `doc/design/side-dock.md` and `doc/design/xterm-resize-reflow.md` first.
2. **No getrandom-based crates in `src-tauri`** (uuid v4, rand, tempfile with
   default features). They import `bcryptprimitives.dll!ProcessPrng`, which
   this project's Windows 10 baseline doesn't export — the binary then fails
   to load with 0xc0000139. Ids/tokens use std's OS-seeded `RandomState`. See
   the notes in `src-tauri/Cargo.toml` before adding any dependency.
3. **Never spawn real agent CLIs** (`claude`, `copilot`) to test or validate
   anything — it burns the user's paid credits. Tests fake the agent side
   (see `src-tauri/tests/`); the user does live agent validation themselves.
4. **Backend tests that link the lib must be integration tests**
   (`src-tauri/tests/*.rs`), not unit tests: Windows test executables need the
   comctl32-v6 manifest that `build.rs` embeds via `-tests`-scoped link args.
   Those args require at least one integration-test target to exist — never
   delete `tests/smoke.rs`.
5. **Frontend never touches Tauri IPC directly.** `src/transport.ts` is the
   ONLY module that may import `@tauri-apps/*` — it owns the `EngineTransport`
   seam (`invoke`/`listen` plus the host capabilities). Every backend
   capability is a `#[tauri::command]` plus a typed wrapper in `src/pty.ts` or
   a per-feature bridge (`git.ts`, `fileapi.ts`, `orchestration.ts`), and those
   wrappers call the seam. `test/transport.test.ts` enforces this — a direct
   `@tauri-apps` import anywhere else in `src/` fails the suite. See
   doc/design/engine-transport.md.
6. **A group id becomes a path in exactly one place.** `GroupId`
   (`crates/loomux-engine/src/groupid.rs`) has one validating constructor;
   `group_dir_at` (`src-tauri`) is the only function that joins one onto a
   root, and it takes a `GroupId`, not a string. `#[tauri::command]`s parse
   their raw `group_id` at the boundary (`command_group`) and thread the type
   from there. Never add a second join, never implement `AsRef<Path>` for
   `GroupId`, and never reintroduce a `&str` group parameter on anything that
   builds a path. Two source-scanning tests in `src-tauri/tests/groupid.rs`
   enforce this: one that every group-taking command parses at the boundary,
   one that `.join` is fed a group in exactly one place — the latter also
   asserting no `AsRef<Path>` impl exists, since nothing else can. That one
   scans **both** source roots (`src-tauri/src` and `crates/loomux-engine/src`)
   because the orphan rule puts the only writable `AsRef<Path>` impl in
   whichever crate owns the type; keep every root it must watch in its `ROOTS`
   list. It is a textual scan and enumerates its own limits: qualified and bare
   spellings of `AsRef`/`Path` are matched, but an aliased `Path` import, a
   macro-generated impl, a multi-line impl header, and `PathBuf::push`
   (indistinguishable from `Vec::push`) are not. None appears today — don't be
   the first. The compiler, not the scan, is what makes a `GroupId` unable to
   reach a `join` as a value.
   Membership ("may this caller touch this group?") is a **separate** check and
   is not implied by holding a valid id.
   **Four identifier families share one validating constructor** (#925):
   `loomux_engine::pathseg::PathSegment`. The group id (via `GroupId`, which
   keeps its own type and delegates only its *checks*), the agent-session id,
   the agent id, and merge-queue batch ids (via `mergeq::valid_id_component`)
   all run the same `check_segment`. Express a **new** family through
   `PathSegment` rather than writing another private "is this a safe id"
   predicate — the reason the consolidation happened is that four had drifted
   apart and the weakest was the one guarding a live `Path::join`.
   **One family is deliberately outside it**, and it is named here so nobody
   concludes the rule is decorative on finding it: workflow **block ids** are
   validated by `workflow::sanitize_id`, which is weaker than `check_segment`
   on exactly the two rules the alphabet does not give you — it permits a
   leading `-` and a Windows reserved device name — and it **rewrites rather
   than refuses** (`sanitize_id("../x")` yields `x`), which is the
   two-strings-name-one-directory hazard `pathseg` exists to avoid; bounded
   only because `parse_workflow` rejects an id `sanitize_id` had to change. A
   block id becomes `<id>.md` in the group dir. That is operator-authored
   config rather than caller input, so it is not a containment breach and #925
   left it alone; the filename scan below carries it as an argued allowlist row
   rather than being blind to it.
   The join scan's permitted-assembly-point list is one row **per family**
   (each required exactly once, so a renamed one fails loudly rather than
   watching nothing), and a sibling scan in `src-tauri/tests/pathseg.rs` covers
   the shape it structurally cannot see: a value interpolated into a **file
   name** (`format!("{x}.json")`). Its trigger is the *shape* — an
   interpolation plus a file-extension literal, matched inside the `format!`
   template — never a binding's name, per the source-scanning-guard convention
   below; default-deny, with an argued allowlist whose rows each name a proof
   that is re-checked, and which fails when a row goes stale.
   Still open, and **not** closed by any of this: the `ft_*`/`fm_*`/git `repo`
   **roots** are arbitrary caller-supplied absolute paths checked only by
   `is_dir()`. That is a root-admission problem, not a segment one — no
   predicate separates a repo from `~/.ssh` — and it is tracked on #1042.
7. **No agent ever merges a PR to the default branch.** Open the PR and stop;
   the human reviews and merges. This is the rule for *every* agent —
   workers, reviewers and planners have no merge authority at all, anywhere,
   and must never merge, tag, or publish a release.
   **One narrow carve-out, for the orchestrator only:** an orchestrator may
   merge a sub-PR into a **non-default branch** it owns — typically an
   integration branch collecting a batch of sub-PRs for a single human
   review — and only once that sub-PR has a reviewer's approval, green CI,
   and every review finding fixed or explicitly deferred. Merging to the
   default branch is **never** covered: it always needs a per-PR grant from
   the human, as does creating a release or pushing a `v*` tag. The carve-out
   exists so a human reviews one combined PR instead of five, not to reduce
   how much a human reviews. When in doubt, open the PR and ask. (#469)
8. **Orrerix is a generic agentic-dev tool — never bake this repo's or this
   machine's quirks into product code.** No toolchain special-casing (nothing
   cargo-/npm-specific in `src-tauri`; express "what's expensive/guarded/built
   here" as repo config, the way the resource guard's `resources:` block does)
   and no operator-setup assumptions (paths, core counts, installed tools). A
   behavior that only makes sense for developing orrerix itself belongs in
   `.orrerix/` config or the dev docs, not the product (precedent: #263).
9. **Never self-approve a security/install gate** (npm's `allow-scripts`
   review, a `gh` shim confirmation, anything else that exists to make a
   human or the orchestrator decide). If one fires, stop and
   `message_orchestrator`/`report("blocked", …)` instead of running the
   approve command yourself — even a narrowly-scoped approval is a security
   decision, and it isn't yours to make unprompted (precedent: #357). The
   repo pre-declares the one approval the build genuinely needs
   (`package.json`'s `allowScripts` field, committed); if `allow-scripts` or
   any other gate fires for something new, the answer is still to ask, not
   to decide.
   **If you're staring at an `allow-scripts` warning right now:** the
   `package.json` entry pins esbuild to an exact version
   (`"esbuild@0.25.12": true`) on purpose, not by oversight — it's the safer
   of npm's two forms (a name-only entry would silently cover every future
   version too). That means a routine `esbuild` version bump (pulled in via
   `vite` or a direct upgrade) makes the gate fire again for the new version
   — that is the pin working as designed, not a fix that broke. The right
   response is the same as for a brand-new package: stop and get a fresh
   human approval for the new version. Do not bump the pinned version
   yourself, do not switch it to a name-only entry to make the warning stop
   recurring, and do not add any other package's entry alongside it —
   widening this the "convenient" way is exactly the self-approval this
   constraint exists to prevent.
10. **Never let a panic or unwind escape a synchronous `#[tauri::command]`.**
    Tauri runs a non-`async` command inline on the webview/GUI thread inside
    WebView2's COM callback; nothing on that path has a `catch_unwind` and the
    `extern "system" Invoke` thunk has no `-unwind` ABI, so an unwind aborts
    the process rather than degrading anything. Registry-taking sync commands
    route through `OrchRegistry::mutating_command`/`read_command` — the
    `read_budget` frame is the barrier — and `src-tauri/tests/synccommands.rs`
    default-denies the class so the next one cannot forget. So a change that
    turns a WAIT into a panic or an unwind owes a **measured** cost per
    executing-thread class, traced to the ABI boundary in the vendored sources
    rather than asserted: the unwind that releases a lock on a pool thread
    takes the app down on this one. Signature: a closed caller-class
    enumeration stated on permanent surfaces, with no measurement for the class
    that runs on the GUI thread (#1713 B1). Chain, armed-build asymmetry and
    residual: `doc/design/lock-order.md` §2.1; a *genuine* panic there still
    aborts (#1717).

## Code conventions

- Frontend logic that needs tests is extracted into DOM-free pure modules
  (`layout.ts`, `steer.ts`, `spawnexpiry.ts`, …) and tested in
  `test/*.test.ts` with `node:test` + `node:assert/strict`. DOM wiring is
  validated by hand — don't simulate a DOM in tests.
- **An in-list editor's un-submitted state lives in the view, never in its DOM
  elements.** The board re-renders on every agent write (`orch-tasks-changed`
  fires on EVERY `write_tasks`) and `refreshNow` defers only while
  `isEditing()` — `document.activeElement` being an `INPUT`/`TEXTAREA` inside
  the list. It reads tagName, never `type`, so a focused checkbox DOES defer,
  while a `<select>` and the click on the form's own commit button do not and
  the render rebuilds the controls from their seeds. Hold the draft in a
  `Map<rowId, …>` the elements are a view of, prune it beside
  `selected`/`collapsed`, and put "is this draft untouched" in ONE pure
  predicate reading EVERY field the form has — the renderer's seed and the
  predicate's default are one question asked twice. Clearing on success alone
  discharges it on the Enter route and leaves it on the button route, which is
  the one most people use. Signature: a control whose value is read at submit
  rather than written on `change`, seeded from a literal instead of from view
  state (#1348 N1/N4; `TasksView.linkDrafts`, `linkDraftIsPristine`).
- Backend: unit tests inline under `#[cfg(test)]` only if they don't link the
  full lib; otherwise integration tests (constraint 4). Orchestration logic is
  covered in `src-tauri/tests/orchestration.rs`.
- **An edit to a role template (`orchestrator|worker|reviewer|planner|manager|lead.md`
  under `src-tauri/src/orchestration/templates/`) re-blesses
  `src-tauri/tests/fixtures/pre222/` in the same commit** — the fixtures pin those
  six templates byte-for-byte modulo registered placeholders
  (`block.md`/`workflow.md` are deliberately not fixture-pinned; an edit whose
  only change is a `{{...}}` placeholder registered in LIVE needs no re-bless —
  the pin strips registered keys before comparing, precedent #859). Signature: `a_workflow_placeholder_must_sit_at_the_end_of_a_line_it_shares`
  and `the_toggle_off_leaves_every_instruction_file_byte_for_byte_what_it_was` go red
  alone, on a round where nothing else moved. Procedure and re-bless log:
  `src-tauri/tests/fixtures/pre222/README.md` (#867, #868, #874).
- **A source-scanning guard must not decide from a binding's *name*** — a rename
  steps over it, so it enforces nothing. Decide on name-independent axes and
  default-deny: the receiver (anything building a path off a declared root is
  denied unless it is on an allow-list carrying a reason per entry) plus a shape
  that cannot compile any other way (`.join(x.as_str())`); a name heuristic is a
  labelled supplement at best, and the residual blind spot is stated where the
  scan is implemented. Precedents: `tests/groupid.rs`, `tests/perf_dispatch.rs`,
  `test/perfpolicy.test.ts`. Signature: the guard's own doc quotes the line it
  was written for, and that line still passes (#922).
  A scan also bounds where a value is **constructed**, never where it travels or how
  long its effect lasts — close that half with the type system (an auto-trait opt-out:
  a `PhantomData<*const ()>` field makes a thread-keyed guard `!Send`), never with a
  wider scan. Signature: a guard whose effect is keyed on the constructing thread and
  held by a value the compiler still lets move off it, or whose exemption outlives the
  scope the scan read (#1722 N6 and B1, `LongHoldPermit`; same idiom as constraint 6's
  absent `AsRef<Path>`).
- **A guard that REFUSES ships only after it has run clean over known-good subjects.**
  Reading a check never finds a false block; running it against real PRs — merged ones,
  and the one in hand — does, and the refusals cluster on the artifacts this repo
  MANDATES: a base-measured run id, a cited commit SHA, a pasted Windows panic path.
  The harness that runs the corpus is itself an instrument — prove its extraction against
  a subject known to FAIL before reading its clean report, or the report is about the
  harness rather than the corpus (the #1209 census bullet, one level up). Signature: ALL
  FIVE false blocks found by RUNNING checklists that had survived every read of them, and
  one of the five invisible to a harness that examined only the FIRST of the body's
  stated diffstats (#1395 B1/B2/B3/B5/B6; the false-NEGATIVE direction is the
  positive-control bullets below).
- `src-tauri/src/orchestration/mod.rs` is tens of thousands of lines — grep for
  the function/struct, don't read it top to bottom. Anchor an INSERT above the
  item's `///` block, never above its `#[tauri::command]`/`fn` — those sit BELOW
  the doc that owns them, so splicing there hands your item the neighbour's
  preamble and leaves the neighbour undocumented, with nothing red to say so.
  Signature: a `+///` line in the diff sitting directly under a context `///`
  line (#1229).
  That signature is a FILE-STATE shape, and the diff-shaped sweep for it is blind
  wherever the neighbouring doc block is ALSO new in the same diff — the insert has no
  *context* `///` above it — so the sweep returns an IDENTICAL hit set on the defective
  and the fixed blob while a match-somewhere positive control still passes. Decide it
  with a name-keyed doc census blob-vs-blob, and read every doc block the diff ADDS
  against the `fn` it now sits on (#1426 B3; recipe in
  `.claude/skills/ci-validate/SKILL.md`).
- Comments in this codebase explain *why* (design constraints, Windows quirks,
  issue numbers) — keep that density and style.
- **A user-facing message is ONE paragraph, and the leak has TWO shapes.** `\n` plus
  indentation in a Rust literal ships the source's leading spaces to the reader; a `\`
  line-continuation avoids that only if it survived the authoring path, and one that
  collapsed leaves the same run of spaces with no `\n` at all. A test pinning the message
  with `.contains(<substring>)` sees neither, since no asserted substring straddles the
  break — it survives a fully green suite. Pin the SHAPE beside the content, as
  `is_one_paragraph` does (`src-tauri/tests/manager_lifecycle.rs`): no `\n` AND no
  ten-space run. Signature: `cat -A` shows a >=10-space run mid-literal, with or without
  a preceding `\n` (#1426 B2; #1457 is the collapse form).
- Write tests that test intent, not implementation echoes.
- **A coverage claim is a claim.** When a PR body or comment says a test or mechanism
  polices a property, run the one mutation that removes it and watch WHICH tests
  redden — a match is evidence, a mismatch is a correction; disclose it (#664, #673,
  #682). A red evidences only the assertion it REACHED and MOVED: a panic before it,
  a split test's already-green half, or a companion that also passed broken prove
  nothing — split the test, or say which half moved (#710, #712, #727). A mutation a
  *reviewer* names is still unrun; run it before quoting it into the body, which the
  reviewer reads and the gate digests (#868). A suite green ACROSS a redesign is a
  control, not coverage — its fixtures were written against the old shape's
  failure modes. List what the NEW predicate reads and check some fixture varies
  each; a value every fixture happens to share is an unpinned axis. Signature:
  the fixtures all carry one incidental constant (four WIP caps, all `review` or
  `in-progress`, none on the status rows are born into) and the axis the
  redesign made load-bearing has no witness (#1182).
  A mutation is evidence only if it LANDED: a `sed`/`node -e` edit whose anchor
  matches nothing exits 0 and the suite then passes for the wrong reason, which reads
  exactly like coverage. Assert the mutation is present — anchor count, or a diff
  against the pre-mutation blob — and abort rather than record a run you did not
  produce; the CRLF trap under *Running these in an agent worktree* is one way the
  anchor silently misses, and decoding the file in one encoding while the anchor is source
  text in another is a second — a `latin1` read (the byte-faithful choice) leaves a UTF-8 em
  dash as three characters, and nearly every source file here carries a non-ASCII character,
  so an anchor cut from a real message usually does too. Decode and anchor in ONE encoding
  (#1396 round 2). Signature: the pre- and post-mutation runs report identical
  pass counts (#1297). An anchor can also match and the edit still land wrong: JS
  `String.replace` with a *string* replacement expands `` $& ``, `` $` `` and `` $' ``,
  so an anchor or payload containing one splices the file into itself — pass a function
  replacer, and diff against the pre-mutation blob rather than trusting an anchor count
  (#1395). An anchor that matched still says nothing about REACHABILITY — an edit landed
  perfectly INSIDE the very gate it meant to bypass is inert, and neither check sees it;
  `ci-validate` forks the diagnosis of a round that reddened nothing (#1426 round 2).
  A mutation table is only as wide as its INSTRUMENT: `npm test` is `node --test` over `.ts`,
  which strips types without checking them, so a row reading "no test reddened" has not asked
  whether the compiler had an opinion — run `tsc --noEmit` on every row, and never state which
  of the suite and the compiler catches an omission until both have been run against it.
  Signature: a real `TS2322` in a heavily-tested module leaves `npm test` 2230/2230 green,
  while a sentence assigns the catch to one side off a table produced by `node --test` alone
  (#1337 round 1; caught in review there, so its merged table carries a `tsc` column on every
  row).
  And only as wide as its SCOPE: a per-file mutation run licenses a per-file sentence, nothing
  more. "The only test that reddens" is a whole-suite claim — measure it there, and on a
  permanent surface most of all, since a code comment outlives the body it was copied from.
  Signature: a whole-suite superlative stated off a per-file run — "deleting `blocked` reddens
  exactly ONE test" beside that file's own `130→129` row, where the whole suite reddens two
  (#1337: `test/decisions.test.ts` also goes red, pinning the set difference instead of
  iterating the list).
  And only as wide as its OPERATOR SET: a residual claim ("this line is pinned by nothing")
  derived from DELETION mutations alone says nothing about a STATEFUL guard, which fails by
  polarity, by placement, and by a per-branch side effect going missing — so invert the gate,
  move the guarded statement out of the block that gates it, and drop each assignment that
  sets the flag, one at a time. Re-derive the residual on the round that ADDS a guard: the
  earlier round's operator set no longer spans the code. On a hand-validated module (DOM glue
  with no test file of its own) the residual rests on `tsc --noEmit`/`noUnusedLocals` ALONE —
  which sees a deletion and not an inversion — so a green suite there is the module having no
  tests, never evidence about the mutation. Signature: a round-1 residual scoped to "one call,
  if deleted" still standing after a later round's fix, whose inverted gate reverts that very
  fix with `tsc --noEmit` at exit 0 and the suite green throughout (#1487 N2/N4 — four such
  mutations, two of them polarity or placement rather than deletion).
  That enumeration is a SAMPLE, not a span, and it is sampled twice over: the mode list
  omits operator SWAP (`&&`→`||`) and operand SUBSTITUTION (one field for its sibling),
  each landing the very failure the gate exists to stop; and a mode measured on ONE of two
  sibling gates generalises from whichever the instrument happens to be blind on. So state a
  residual STRUCTURALLY — "these modules have no test file" — never as a list of N invisible
  mutations. Signature: "all four are invisible" beside a twin gate whose identical hoist IS
  caught, by `TS6133` on the field its condition reads (#1470 round 3).
- **An absence-only assertion needs a positive control, and the vacuity is a SHAPE.**
  `is_empty()`, `!contains(…)`, "renders nothing" — each passes just as well when the
  mechanism never ran at all. Pin first that it DID (`fired.len() == 1`, `scanned > 0`
  — a loose floor, not a second brittle pin on the thing's shape), then grep the suite
  for the same shape: the site a review names is rarely the only one. Signature: fixing
  a vacuous-test finding uncovers its twin one test over, green against an empty scan
  (#1209).
  A positive control proves the mechanism RAN, never that it SAW every subject: where it
  guards a pattern over a population, put the raw-count cross-check under *Every number in
  a PR body* in the assertion itself, where it fires on a blind instrument without anyone
  thinking to mutate the one subject it cannot see. Signature: one field renamable alone
  while a guard already carrying a vacuity control stays green (#1297, `test/reposlug.test.ts`).
- **A population control counts at the VERIFIED site, never at the MATCH site.** A subject
  the guard matched and then `continue`d past — unknown name, shape its branch cannot judge —
  still incremented the counter, so the control certifies coverage that was never delivered;
  assert `matched == verified` per surface and name what was skipped. Signature: a false
  figure in the guard's own canonical shape rides a scanned surface green, while blinding
  that surface's real figures reddens the same guard (#1327, `test/theme.test.ts`).
- **A guard's green is evidence about its POPULATION, not about its property.** When a
  human's on-screen report contradicts a suite that pins exactly the reported property,
  the suspect is the list the assertion runs over — not the assertion, and not the report.
  The site the report NAMES is a symptom, not a location: measure the property there first,
  since a perceived GLOBAL cast is routinely carried by interaction-state surfaces (one
  selection fill, three hover washes, one chosen fill) while every token called "ground" is
  provably clean. Widen the population by ROLE, not by the names you happen to recall.
  Signature: "gold is tinting everything" against `r === g === b` green on all nine ramp
  steps, with `SEMANTIC.selection` never in the list (#1344 — a second population defect in
  `test/theme.test.ts`, in a different guard from #1327's).
- **A validity check is evidence about the bytes it READS, never about the region it
  licenses.** Ask of every guard "what is the smallest edit that PASSES this?", not "what
  does it catch" — a fixed-width fingerprint clears its own window, so the promise above it
  is narrowed to that window or the residual is BOUNDED in code (a revalidation ceiling).
  Signature: a "fails toward slow, never toward wrong" promise beside a 64-byte anchor,
  the residual written as an AND of three conditions the real failure needs none of
  (#1361 B1; pinning the residual is the escape-hatch bullet below).
- **A non-interference pin is fail-able only when its two operands COLLIDE.** A test
  asserting operation X leaves Y alone must build the fixture so X's key IS Y's subject —
  disjoint literals hold under every implementation, the symmetric one the pin forbids
  included. Where a guard refuses that fixture at write time, build it in two steps: name
  the not-yet-existing subject, then bring it into existence. Reconcile a mutation wave
  against the properties CLAIMED, never against a stable pass total. Signature: the
  assertion's two literals never meet (links `"#7"`, deletes `"t-2"`) while a body and a
  design note call the non-interference pinned and a doc comment leans on it (#1300 B1,
  `doc/design/board-sprints-and-links.md` §3).
- **A function's doc may only claim what survives its pipeline's LAST writer.** A doc block
  justifying a local choice by a property of the file on disk ("appended, so the order is the
  human's") is false wherever a downstream canonicaliser rewrites it, and its test then measures
  the downstream property under the upstream one's label — #1300 B1 / #1182's non-discriminating
  fixture with the prescription inverted: for an ORDER pin the two candidate outputs must
  DIVERGE, and that divergence is itself pinned (`assert.notDeepEqual`) so a later fixture edit
  reddens before the claims do. Signature: a doc block on why a list is appended rather than
  sorted, upstream of a serializer that sorts it — `sortByBlocks` has four call sites (#1396 B1;
  `connectToGate`, `test/workflowmodel.test.ts`).
- **A test's specimen must stay a member of the class it witnesses.** When a directive
  moves a real specimen out of that class (a declared value converging with the
  default, a file gaining its "absent" block, a concrete list going stale), relocate
  the property onto a witness that still distinguishes — never relax the assertion to
  fit today's specimen. If the converged case still deserves coverage, give it its own
  strictly-weaker, explicitly-labelled assertion (#689). A **mechanical sweep** is the
  commonest way a specimen leaves its class: a rename that rewrites a test's string
  literal to the new spelling deletes the witness in the same commit that changes the
  behaviour, so CI stays green over it (#1225). The same drift bites outside tests: a
  hand-derived value a claim rests on (a line cite, a count) is valid only at the
  commit it was derived on, and your own next commit invalidates it as silently as a
  rebase. Cite a SYMBOL (#763); a position that must be recorded is swept in the LAST
  commit touching its source (#752). A hand-derived COUNT dates to the BLOB of the one file
  that can move it (`git rev-parse HEAD:<file>`), never to a commit: a rebase invalidates
  every SHA a body cites while leaving that blob — and so the count — checkable, and when the
  blob DOES move the anchor says which rebase to re-measure on (#1470 B1, census 56/32 on
  `src/tasksview.ts` blob `71c0d0b9` across three rebases).
- **A rename of an identity string classifies every site as EMIT or ACCEPT before
  rewriting it.** An emit site takes the new spelling alone; a reader keeps every
  accepted spelling — and a reader whose question is *what did the author DECIDE*
  fails by WIDENING a capability grant when it stops recognising the old one, which is
  the app granting itself capability that #222's closure forbids. Accept-both is not
  the blanket answer either, so split per question: `doc/design/rebrand-protocol.md`,
  "The one reader that must NOT accept every spelling". Pin the pre-rename specimen
  BESIDE the current one (#1225).
- **A documented escape hatch is a counterfactual — only a test that performs the
  edit pins it.** When a comment, design note or PR body says a policy can be undone
  by changing one arm or flag, the dispatch below it must give that variant its own
  arm, and a test must feed the *reverted* arm's return value to the real dispatch —
  plus a set assertion that exactly the intended variants take the dangerous branch,
  so the count fails when one is folded back in. Signature: an arm folding the
  escape-hatch variant in with the live one, excused by a comment saying that variant
  is unreachable — which the documented edit is precisely what makes false. Worked
  example: `obs::root_action`, `the_documented_revert_really_stops_the_migration` and
  `exactly_one_plan_variant_moves_anything` (#1205 B1). A disclosed **residual** is the
  same counterfactual pointing the other way: pin the blind spot ITSELF — that the guard
  really does miss the case the note admits — beside the bound that limits it, or the
  suite pins only the arms that work and the disclosure goes false with nothing red to say
  so (#1361 B1, `an_edit_below_the_anchor_window_is_not_detected_by_any_guard` +
  `the_revalidation_timer_bounds_that_blind_spot`, and its non-vacuity control
  `an_unexpired_cursor_is_not_revalidated`).
- **A per-CLI identity string is read off the source, never branched on it.**
  `source === "claude" ? "claude" : "copilot"` is right only while there are
  exactly two CLIs; a third silently inherits the else-branch and the pane
  name, badge or resume command asserts the wrong CLI. Gating *behavior* a CLI
  genuinely has (`cli == "claude"` for hook settings) is fine — producing a
  *name* that way is a defect. Adding a CLI means grepping `"claude" ?`,
  `== "claude"`, `"claude" =>` (match-arm dispatch the first two patterns
  miss) and the `!= "claude"` polarity across `src/` and `src-tauri/src/`,
  and classifying every hit as behavior or mistype (#722, #841).
- **A guard reads every one of its inputs by one rule.** Taking one signal from
  "the options OR the existing state" and the next from the options alone is a
  bypass exactly the width of that asymmetry; so is a check present at one call
  site and absent from its sibling. Union every field on one side *inside* the
  pure guard — never at the DOM call sites, which drift — and pin all four
  crossings of {which side says X} × {which side says Y} plus the negative
  control, so "refuse everything" cannot pass either. Worked example:
  `sshOrchestrationRefusal` and `doc/design/ssh-panes.md` (#859, #906, #921).
  The two signals can also be ONE state read at two POINTS: a "before" snapshot
  taken below any part of the write — the row insertion included — is the same
  asymmetry, and it leaves the guard inert exactly where before and after
  coincide. Hoist the snapshot above every mutation rather than subtracting the
  written row back out in your head, and when a review names one asymmetry
  re-derive EVERY input — the redesign is where the next one lands. Signature:
  the fix for a one-rule finding ships a second of the same class (#1182).
- **A multi-tenant whole-file store never publishes from a handle it has not read.**
  An in-memory map initialised empty and serialised whole erases every OTHER tenant's
  record the first time a gesture beats the load — and forever after a read that
  REJECTED, since "I could not look" is not "there was nothing there". Every write awaits
  the read; a failed read declines the write rather than defaulting, and is not latched,
  so one transient rejection does not disable persistence for the session. Narrow the
  payload to the fields the caller OWNS and merge passthrough off the record just re-read
  — a caller cannot lose what it never carries, and the cousin (this tenant's own record
  overwritten from the view's constructed defaults) lands a review round later otherwise.
  Signature: `save(encode(this.store))` where `this.store` is seeded by an `await` that a
  gesture can beat, or by a `.catch(() => empty())`; every individual step succeeds, so
  the loss is silent. Worked example: `BoardPrefsStore` (`src/boardprefs.ts`) and
  `doc/design/board-tree-view.md` (#1299 B1/N5).
- **A cache or snapshot placed in FRONT of per-item reads inherits everything those
  reads answered.** Enumerate what the replaced path could do that the new one cannot —
  which item classes it served (live AND persisted-only), and what it recovered from (a
  re-probe, a reopen). The miss is SILENT: an absent entry renders as "nothing here"
  rather than failing, so neither the compiler nor a unit test over a faked registry sees
  it. Signature: the new path is keyed on what the live map or this session knows, the
  reads it replaces on what the CALLER named (#1625 round 2, `views.rs`'s strip lease;
  #956 rev-507, `src/modelcatalog.ts`'s `worthKeeping`).
- **A `Mutex` that serialises tests is locked with `lock_safe`, never
  `.lock().unwrap()`.** One failing test panics under the guard and poisons it,
  so every later test on that lock dies of `PoisonError` — one genuine failure
  reported as N, and a mutation round's reds stop being attributable to the
  behaviour they were cut for. Restore any global the harness overrode from a
  `Drop` guard, for the same reason. Signature: extra tests reddening with
  `Result::unwrap() on an Err value: PoisonError` beside the one you
  expected (`SERIAL` in `crates/loomux-engine/src/obs.rs`, #1236).

## Refinements & scope increases from the user

Default: when the user asks for a refinement or feature addition on work already in
progress (an open PR, an active branch), **fold it into the active PR** rather than
deferring it to a follow-up issue. This is different from an agent inventing extra scope
mid-diff — that's still a review ground to bounce ("scope drift... split it"). Here the
user is the one increasing scope, deliberately, because they thought of the right shape
while watching the work land — that's a refinement, not drift. Only defer to a separate
issue when the user explicitly says to ("later", "follow-up issue", "separate PR"). Don't
narrow their ask back down to the original ticket on your own judgment.

## When the brief can't be followed as written

- **A self-contradicting instruction is not implementable — say which half you dropped.**
  Where a plan states a rule twice and the two readings differ, never silently pick one:
  name the contradiction, implement the reading it states first and argues for at length,
  get the deviation approved, and record it where the plan's NEXT implementer looks — the
  design-note section and, for a role-template edit, the `pre222` re-bless log — not only in
  a PR body nobody re-reads. Signature: a "take the first that decides it" ladder given a
  rung BELOW one that always decides (board order over an array never ties), so the new rung
  is unreachable text (`doc/design/board-sprints-and-links.md` §7,
  `src-tauri/tests/fixtures/pre222/README.md`, #1300).
- **A routed instruction's factual premise is a claim to verify, not text to transcribe.** A
  disposition relayed reviewer → orchestrator → worker can carry a reason that was true when
  someone wrote it and is false in the tree you are editing; transcribing it onto permanent
  surfaces ships a fresh false claim, and the round that routes one is usually the round FIXING
  one. Check the premise against the code, decline the clause, and say in the commit message
  AND the PR which half you dropped and what the surviving reason is — naming the surfaces that
  really carry it. Signature: a routed reason offers "recapped in `<X>`" and `<X>` names none of
  the things it is said to recap (#1429 N1, adjudicated for the worker in review round 5).

## Git & GitHub workflow

- Commits: `type(scope): imperative subject (#issue)` — e.g.
  `fix(orchestration): expire timed-out spawn requests (#106)`. Common scopes:
  `orchestration`, `pty`, `gitview`, `launcher`, `tasks`, `clipboard`,
  `metrics`, `ui`, `build`, `release`.
- Branch from `main`; PR to `main`.
- **No tool footer or session link in a PR body or commit message.** Claude Code's
  default `🤖 Generated with [Claude Code](…)` line and any `claude.ai/code/session_…`
  URL or `Claude-Session:` trailer are dropped before posting; the squash message
  is permanent and a chat-session link is not provenance. `Co-Authored-By:` stays.
- **Delete a PR's branch once it merges.** `gh pr merge --delete-branch`
  handles it, but skips the remote delete when a local worktree still holds
  the branch — after cleaning the worktree, verify with
  `git ls-remote --heads origin <branch>` and `git push origin --delete
  <branch>` if it survived. Whoever performs the merge owns this step (#662).
- **Retarget every open PR based on a branch BEFORE deleting that branch, and
  rebase each one onto its new base.** Deleting a base ref auto-closes every PR
  stacked on it, and while that ref is gone `gh pr edit --base` answers
  `Cannot change the base branch of a closed pull request` and `gh pr reopen`
  answers `Could not open the pull request`, so every review round spent there
  is stranded. The hand `git push origin --delete` above is what the auto-close
  follows, so it lands on whoever performs the merge, in this order:
  `gh pr list --state open --search "base:<branch>"`, then
  `gh pr edit <n> --base <the merged PR's own base>` per hit (usually `main`;
  the integration branch under constraint 7), then a rebase onto that base —
  the squash commit that replaced the parent on that base is not an ancestor
  of the child, so its diff against the base otherwise re-shows the parent's
  work — then delete. Signature: a
  `base_ref_deleted` timeline event with a `closed` event one second later, and
  no `base_ref_changed` between them (#1736).
- **A closing-keyword sweep of a squash message must be MULTILINE, and the
  merge is verified on the issue.** GitHub's scan spans the line break, and in a
  commit message it is not markdown-aware — no fences, no code spans, only
  lines — so a `##` heading ending in *fix* above a paragraph opening `#1702`
  closes that issue, while a line-oriented `grep` positive-controlled on a
  one-line `Closes #N` returns exit 1 and reads clean. Sweep the concatenation
  the squash message actually is (title, blank line, body — separate sweeps miss
  a keyword ending one above a reference opening the next) with
  `LC_ALL=C.UTF-8 grep -Pzoi '\b(close[sd]?|fix(e[sd])?|resolve[sd]?)\s*:?\s*#[0-9]+'`,
  then after the merge re-read the state of every issue the body only said
  `Part of` and reopen what closed. That outcome check is the half that cannot
  be blind — `closingIssuesReferences` on the PR is markdown-aware and answers
  EMPTY for a body that closes an issue anyway — and whoever performs the merge
  owns it as they own the branch delete (cf. #1697, the same blindness in a
  claim sweep). Signature: a `closed` timeline event carrying the squash
  commit's SHA on an issue no keyword names (#1702 by `d8bb4e8e`).
- **Git Bash mangles a `<ref>:<path>` argument when the path starts with a
  dot.** `git rev-parse origin/main:.github/x` is rewritten to
  `origin\main;.github\x` and errors, while `origin/main:src/x` works — so a
  blob-by-blob sweep silently reports exactly the dot-directory files
  (`.claude/`, `.github/`, `.orrerix/`) as mismatched, and an error string
  compared as a blob reads as a real difference. Prefix `MSYS_NO_PATHCONV=1`
  on any `git`/`gh` invocation whose argument carries a ref-colon-path (#841).
- **An end-of-file append conflicts on its shared trailing tokens, not on its
  content.** Test blocks in `src-tauri/tests/orchestration.rs` all end `);` + `}`,
  so two branches appending there get that tail matched as common context and
  each side arrives ending mid-assertion; concatenating splices one block into
  the middle of the other's final `assert!`. Prove the resolution rather than
  parse-checking it: the base blob must be a verbatim **prefix** of the resolved
  one (`startsWith` over `git show <ref>:<file>` for both), with a single append
  hunk in `git diff -U0`. Signature: a conflict whose two sides are each
  syntactically incomplete (#1196). That prefix proof is valid only when exactly ONE
  side appended: where both did — or your side also edits elsewhere in the file — the
  checkable statements are that the resolution DELETES nothing of the other side's blob,
  and that a census of the file's named units matches at both ends — measured once, at
  #1299's own resolution: 102 test names at the base, 116 at the head, 0 lost. A splice
  is silently GREEN — one side's block nested inside the other's final assertion still
  parses and still runs — so parsing the result proves nothing (#1299).
- **A conflict hunk whose other side is EMPTY is not add-vs-add, and a union silently
  reinstates what that side deleted.** Where a sibling branch REPLACES the block your change
  lives inside, `git merge-tree` prints that side of the hunk empty, and "keep both sides"
  restores a guard that no longer guards, a second read beside the replacement, or a `catch`
  that is now dead code — parsing, passing, and reverting your own earlier fix. #1299's
  "deletes nothing of the other side's blob" census is the wrong instrument here: a correct
  resolution of a replace-vs-augment hunk deletes YOUR lines. Classify per HUNK, and treat the
  prose that tells a future resolver what to do — a body's overlap section, a shipped comment —
  as load-bearing text reviewable as code, never one blanket sentence over a multi-file
  conflict. Signature: a body licensing "resolve by keeping both sides" across a file list
  `git merge-tree` shows an empty other side for (#1487 B3).
- GitHub issues are the work queue. Labels the orchestration workflow uses:
  `agent-managed` (an orchestrator owns it), `agent-ready` (groomed — go),
  `agent-investigation` (research only — post findings as an issue comment,
  no code), `agent-prototype` (build for demo/feedback).
- User-visible behavior changes must update the matching user-docs page under
  `docs/` (the README is a pitch, not a manual — only touch it when the pitch
  itself changes); substantial designs get a `doc/design/*.md` note.
- **"The PR body" in every evidence rule below means the body's AGENT LAYER** — the
  collapsed `<details>` block opened by `<!-- agent-layer -->` +
  `<summary>Agent context — evidence, receipts, instruments</summary>`, which is where
  agent-authored bodies, reviews and issues put receipts, run ids, mutation tables and
  measurements while the human layer above the fold stays short (#1968). Position only:
  every rule below applies to it in full, and GitHub's closing-keyword scan still reads
  the whole body, fold included.
- **Every number in a PR body is measured at the base AND at the head** — never
  derived by arithmetic, remembered, or carried from a mid-branch run. Counts,
  deltas, diffstats and run ids all go stale on the next commit. Read both
  totals out of the two runs' own logs, and check that the per-file deltas sum
  to the total you are claiming (#859, #862, #889, #907, #914, #921); which
  `gh pr diff` form a diffstat may be measured from at all is a recipe in
  `.claude/skills/ci-validate/SKILL.md`.
  A number is also only as good as the instrument that produced it: a regex character
  class is a GUESS about the alphabet of its own subjects, so census by walking the real
  delimiters and cross-check the total against a raw count of the container. Signature:
  two totals stated confidently and both light by exactly one, from a `([a-z-]+)` that
  stops dead at the digit in a real value (`no-sha256`) — a census that cannot see one
  of its own subjects is not a census (#1209). Build the pattern from what a token may
  CONTAIN (a fact), never from what may FOLLOW it (unbounded prose): the second instance
  was a follow-class omitting `#`, blinding a guard to `…/loomux#readme` (#1297).
- **A body revised across review rounds is DATED per section, never certified
  by a sentence.** "Everything above is measured at `<sha>` and stands as
  written" is itself a hand-maintained claim over text: it goes stale with the
  numbers it covers, and is then the second false claim rather than the fix for
  the first. Name the SHA in each section that carries a number, so a reader can
  check it instead of trusting the certificate; when one number is found stale,
  re-date the sections rather than widening the sentence. Audit by sweeping
  EVERY NUMBER for a date, not every section for a number — the ones the
  sentence names are the ones already thought about, and a figure in a prose
  sentence, a heading or a bullet belongs to no section at all, so a per-section
  audit cannot reach it. The stale one is routinely collateral of THIS round's
  own fix rather than of the original draft (#1470 B1, #1764 B3, #1758).
  Signature: a section whose only SHA is the BASE, with
  its head written as `HEAD` (which moves), sitting under tables headed by a
  literal SHA (which don't) and a sentence saying only one section needed the
  edit (#1348 B1: a Diffstat 109 insertions light, certified as not needing the
  touch).
- **A commit SHA in a PR body is re-resolved against the PR's own ref, never your worktree.**
  A rebase rewrites every SHA the body cites while the prose survives untouched; the orphans
  still `git cat-file -e` locally, so existence proves nothing, and ancestry against `main`
  fails for EVERY branch commit once the PR squashes. Signature: the run ids were re-derived
  after the rebase and the commit SHAs beside them were not — the reproduction SHA the body
  tells a reader to check out included (#1327; recipe in `.claude/skills/ci-validate/SKILL.md`).
- **The head-SHA SWEEP that fixes that is the other way a body goes false — it rewrites lines
  naming a BASE.** A body cites two kinds of SHA and a mechanical re-stamp cannot tell them
  apart: a head citation ("measured at", "applies at") must move, a base one ("cut from") must
  not, and the re-stamped result passes every check above — it resolves, it is an ancestor of
  the PR ref, and its subject is this PR's own commit. Prefer a citation the sweep cannot
  reach: DELETE a base claim from a line that does not need one, derive it (`#1432`'s head's
  parent), or date the claim to a BLOB hash, which survives the rewrite that invalidates every
  SHA. Signature: two adjacent "cut from" sentences naming different SHAs for one scratch
  round, one of them committed hours AFTER the run it supposedly seeded (#1429 B2/B3; census
  and temporal check in `.claude/skills/ci-validate/SKILL.md`).
- **A range's BASELINE is re-derived with `git merge-base`, never inferred from an ancestry check.**
  A rebase moves the merge base while leaving the commit you rebased onto LAST time a
  perfectly valid ancestor — resolvable, right subject, passing every check the SHA rule
  above applies — so an isolation diffstat re-run against it is freshly measured and still
  wrong. Signature: `git diff <base>..HEAD --stat` cited as proof nothing else bled in,
  where `<base>` is the previous rebase's target (#1324: 63 files/314+ against it, 61/258+
  against the real merge base; recipe in `.claude/skills/ci-validate/SKILL.md`).
  **A rebase-NEUTRALITY claim takes a different instrument again.** `git diff <old-head>
  <new-head>` answers "what did the new base absorb", never "did my patch change" — it reports the
  base's own commits, so a rebase that replayed perfectly still reads as a FAIL. Read
  `git range-diff <old-base>..<old-head> <new-base>..<new-head>`, whose `=` OUTRANKS a raw diff
  that disagrees: they answer different questions, not one question twice. (Diffing each head
  against its OWN merge base asks the right question too, but the two patches differ on `index`
  and hunk-header lines — strip those or you re-manufacture the false FAIL.) Signature: a blocking
  finding citing insertions the rebase absorbed from the new base — in a file your patch also
  touches, or one it does not — recorded beside a `range-diff` the same review already ran and got
  `=` on (#1755; recipe in `.claude/skills/ci-validate/SKILL.md`).
- **A sweep is dated to the base it was run on.** A rename or purge is complete only
  against the tree it was grepped on: a rebase replays your patches but not your grep,
  and work merged meanwhile authors fresh instances of the string you removed — a live
  defect, not a stale measurement. An all-`=` `git range-diff` (`ci-validate`'s recipe)
  does not cover it and cannot: it says your patches replayed unchanged, never that the
  base they replayed onto is clean of what you swept. So re-grep the entity across EVERY
  root (`crates/`, `src-tauri/`, `src/`, `docs/`, `test/`, `e2e/`) after each rebase and
  before the final green — scoping it to the directory you last edited is the miss —
  and `git log -S` names the commit that authored each survivor. Signature: review names
  N stale sites and the whole-tree grep finds N+1 (#1205, whose range-diff was `=` on
  every commit with five fresh instances sitting in the new base; #1191).
  A rebase also widens a SET, and no grep finds that one because nothing YOU wrote
  went stale: a sibling refactor routing a second list through one shared refusal
  leaves every test enumerating that rule covering only the list that existed when
  it was written. Re-read each shared helper the new base put your tests' rules
  behind, and perform the edit on every site it serves. Signature: the shared helper's
  own doc names the divergence it prevents — `gate_reviewer_error`, "static list ends
  up refusing a manager while a routing rule quietly accepts one" — and no test builds
  the second list (#1229).
  A rebase imports RULES as well as code, and those apply retroactively to your OPEN diff
  with nothing mechanical pointing at what you now violate — no red, no stale grep hit, no
  range-diff row. Diff the convention surfaces across the rebase span (`git diff
  <old-base>..<new-base> -- CLAUDE.md .claude/skills/ .github/agents/ .orrerix/lessons.md`)
  and re-check your own diff against each bullet the base gained. Signature: an all-`=`
  range-diff and a green suite over a diff that matches a convention younger than your
  branch point (#1300).
- **A sweep whose success shape is ZERO needs a positive control.** Every sweep this file
  mandates reports success as an empty result — byte-identical to the instrument never
  having run. Two forms produce that silently, measured on GNU grep 3.1: `grep -rn "a|b"`
  is a BASIC regex, so `|` is a literal and the alternation matches nothing; splitting one
  across `grep "PAT1" -e "PAT2"` makes grep read `PAT1` as a FILENAME and match `PAT2`
  alone. Both do signal (exit 1; exit 2 plus stderr) — but `| wc -l`, the form a receipt
  quotes, discards both and prints a number. Quote the sweep without the pipeline, and run
  the same string against a specimen that MUST match (`git show <base>:<file>`) before
  citing a zero. Signature: a clean-sweep receipt of `0` whose pattern carries an
  alternation and whose command ends in `| wc -l` (#1344).
  A third form never runs at all: on this machine's GNU grep 3.1, `-i` combined with `-F`
  ABORTS — `SIGABRT`, exit 134, zero bytes on stdout AND stderr — so `grep -riF` over a tree
  that DOES contain the term prints an empty result indistinguishable from a clean one. The
  trigger is the C/POSIX locale, never the pattern: an unset locale env resolves to it and
  `LC_ALL=C`, the reflex spelling for a deterministic sweep, asks for it, while any other
  locale clears it. Use `-rni`, or `LC_ALL=C.UTF-8`. Signature: a case-insensitive literal
  sweep returns zero for EVERY pattern, one you can see in the tree included (#1369 review;
  repro: `grep -niF vacuity` on a file holding `Vacuity`).
  Stop enumerating flags — the trigger is that locale, and the CLASS it disables is grep's
  non-trivial matchers: `-F` with `-i` (above), `-P` (`-P supports only unibyte and UTF-8
  locales`, exit 2), and `-i` with more than one `-e` (`SIGABRT`, exit 134, silent). Run
  every sweep as `LC_ALL=C.UTF-8`, or plain with ONE pattern per invocation, and give each
  its own SAME-SHAPE positive control — a control run in a shape the sweep did not use
  certifies nothing, and a single-pattern control is exactly the shape that survives a
  multi-`-e` sweep's abort. The consequence the general rule does not carry is the CENSUS
  one: nothing reaches stdout, so `grep -oP … > a.txt` writes an EMPTY file and a
  before/after diff of two of them reports `0 lost, 0 added`. Signature: a census whose two
  operands are both zero-byte files (#1361 review round 1; #1471 N5 for the multi-`-e` form).
- **Correcting a false claim is a multi-surface edit.** A design rationale here
  lives on several permanent surfaces at once — the code comment, the
  `doc/design/*.md` note, the PR body (whose human layer becomes the squash message), and
  the `docs/` page when the claim is user-visible (the bullet above mandates
  it) — so a claim deleted from one survives on the others. Verify the purge by
  grepping the *entity* the claim names, never the phrasing you rewrote.
  Signature: a re-review that clears a claim on two surfaces and finds it alive
  on the third (#878). **Correct the twin, not just the named site**: one entity
  grep clears the sites you thought of, while each line you rewrite still has a
  paraphrase elsewhere (a comment and its design-note gloss), so grep each
  corrected line's own distinctive noun (`by provenance`, `strictly narrower`)
  across the tree in the same pass. Signature of the miss: the same finding
  reopens a third round, on twins of lines an earlier round corrected (#922).
  An earlier **commit subject** superseded later in the same PR is a surface
  too — the squash aggregates it and it cannot be edited in place, so flag it
  in the body for whoever squashes (#909). Run the sweep whenever YOU narrow a
  guarantee, not only when a review names a false claim: a mid-branch fix
  falsifies your own earlier prose and nothing MECHANICAL points at it — no
  number to re-derive, no test to redden — and a reviewer's list of sites is a
  sample, not the set (#1189: a module header falsified by that PR's own later
  commit, and 6 sites named against 11 found; #1215).
  Where the claim is a **quotation** rather than a paraphrase it is checkable,
  so check it instead of sweeping: every passage a PR body quotes out of a file
  in its own diff must still hold in that file at head — modulo whitespace, and
  by hand for an inline quotation the mechanical harvest does not reach.
  Signature: the body's *What changed* quotes the exact phrasing a later commit
  on the same branch removed, and the squash republishes it on the one surface
  nobody can edit afterwards (#1271). Recipe, and the blind spots it is scoped
  to: `.claude/skills/ci-validate/SKILL.md`.
  **That sweep's blind spot is the LINE, and its failure shape is a NON-ZERO
  receipt.** Prose and rustdoc here are hand-wrapped, so a line-oriented `grep` for a
  multi-word claim cannot match an instance the wrap split, and the same-shape positive
  control still passes because it matched the UNWRAPPED copies. Discover on a SINGLE
  TOKEN — a phrase can be split by a wrap, so only one token cannot — then confirm
  with one wrap-tolerant `grep` over the same ROOTS (`-Pz`, every space of the
  phrase spelled as a class that absorbs the break and the comment marker). Pass 1
  over-matches by design — the surplus is the sites carrying the token in other
  phrasings, and you read those rather than reconcile them away. Both passes are
  bounded by the token you chose. Signature: a healthy non-zero receipt that a later
  re-sweep beats — #1346 went 1 → 2, #1408 3 → 4, #1667 2 → 4 (`"no timeout, no try-lock"`
  over three pre-fix blobs misses the two where the phrase straddles the wrap). Recipe:
  `.claude/skills/ci-validate/SKILL.md`.
  **A TEST is one of those surfaces, and it fails LOUD rather than silent.** An
  assertion quoting the wording (`err.contains("never")`) does not merely carry
  the false claim, it ENFORCES it: the correction reddens a test and reads as a
  regression, so the pressure is to revert the fix rather than the pin. Repin per
  *tests test intent, not implementation echoes* above, and add a `doesNotMatch`
  on the retracted claim so it cannot come back. Signature: correcting a claim
  reddens a test whose assertion quotes it (#1502 — `test/mailboxbadge.test.ts`
  and `nothing_loomux_sends_mid_session_can_reach_a_manager_pane`).
- **A doc naming a file or test that hasn't landed must say so in its tense
  and name the slice** — `` `tests/perf_dispatch.rs` *will* enforce … (#743
  S2/S3) `` — or the pointer waits for that slice. Present tense beside a
  shipped guarantee in the same construction reads as shipped, and the reader
  who acts on it gets silent green (#750).
- **A claim about how markdown RENDERS is measured or decided from the surface,
  never read off the source.** Put the text through GitHub's own GFM endpoint
  before claiming a PR body, issue comment or `docs/` page renders a certain way
  — `gh api -X POST markdown -f mode=gfm -F text=@file.md`. A blank line
  silently ends a table, and the row you claimed becomes a paragraph of literal
  pipes (#926).
  The trigger is EDITING a table, list or fence — not claiming anything about it. The
  commonest miss is rendering the PR body and never rendering the `doc/design/*.md` note
  it mirrors, a `docs/` page, or a test-fixtures README nobody filed under "rendered
  surface" (#926 B1 and #1361 B2, both design notes; #1196 N1). Rendering a page once
  does not clear it either: render every construction you touched, since #1140 B4 shipped
  a broken nested list off a page whose anchor link the author HAD checked through the
  endpoint. A blank line is also only one of the two forms: a MISSING one makes the
  following paragraph or row a lazy continuation of the list item above it, so it renders
  swallowed into that bullet with no literal pipes to notice (#1140 B4, #1196 N1).
  **An INSERT into a list damages the NEIGHBOUR, so render the BASE too.** A new entry takes the
  block that follows it — by a missing blank line, or by re-parenting a correctly indented
  continuation paragraph — and nothing is malformed, so a head-only render of the slice you edited
  clears it while the item ABOVE has silently lost its closing paragraph. Compare WHERE `</li>`
  falls at both ends, never the `<li>` TOTAL: a new entry moves the total legitimately, and #1773
  B2 hid inside that move (slice 1 → 2, whole file 55 → 56, both the healthy +1). Anchor on the
  NEIGHBOUR's own closing BLOCK TAG and count the `<li` opens before it — that INDEX is the read
  (`</p>` in a loose list, `</li>` where it renders tight, `</pre>` where the entry ends in a
  fence; #1773 B2: base li #1 → damaged li #2); diffing every `</li>` offset instead shifts them
  all past any insert and reads as noise. The hazard is an insert BETWEEN entries; an append past the
  last one has no neighbour below it to re-parent — where the list ends the file. Signature: a
  re-bless entry inserted among entries that carry indented continuation paragraphs (#1196 N1,
  #1773 B2 — both `pre222/README.md`).
  **That endpoint is blind to a `mermaid` fence**, and so is a browser: GFM returns every
  such fence as a syntax-highlighted `<pre>` — byte-for-byte the raw-DSL failure you are
  checking for — while GitHub's own file viewer renders it in a cross-origin sandboxed
  iframe a signed-out headless run cannot reliably see (two runs, opposite readings). Decide
  a mermaid claim from the SURFACE instead: GitHub's file viewer renders one natively, the
  published site does not while `docs/_config.yml` has no `mermaid:` key; corroborate with
  byte-identity against a fence already rendering there. Signature: a fence moved between
  files and its rendering "measured" (#1324, `doc/design/group-workflow-diagram.md`).
  **A hand-wrap inside an inline code span renders as a space**, so a path or
  identifier broken across a line names something that does not exist — a break
  at a space is harmless (`` `delivered_mask_lines(pty,` `` / `` `session)` ``), a
  break inside a token is the defect (`src-tauri/src/orchestration/ mod.rs`). It is
  outside the trigger list above: the subject is a SPAN, not a table, list or fence,
  and the PR body counts because a squash makes its human layer permanent and the
  agent layer renders on GitHub either way. Signature: the fix
  for one instance ships another one surface over (#1703 B2 in the design note, then
  R1 in the body it re-posted); the repo-wide backlog and the scanner are #1716.
  **Two ways that endpoint lies about its own output.** Pass the file as `-F text=@file.md`:
  under PowerShell `-f text="$(cat file.md)"` interpolates `Get-Content`'s `Object[]` on `$OFS`,
  so every newline becomes a space and the whole document renders as ONE `<p>` of literal pipes —
  the exact failure being checked, manufactured by the instrument (Git Bash is unaffected, so it
  reproduces for half the fleet only). And count tags by PREFIX (`<code`, `<table`): GFM attributes
  every tag (`<code class="notranslate">`, `<markdown-accessiblity-table><table role="table">`), so
  a bare `<code>`/`<table>` count reads 0 on one that rendered perfectly. Signature: a render check
  reporting one `<p>` and no table, or a zero tag count on a table you can see (#1755).
- **A claim about the PR body is measured on the POSTED body, never on your
  draft.** Writing it is not posting it: a body rebuilt from sources destroys any
  edit made to the assembled file, so edit the sources, assemble, then re-read the
  result with `gh pr view <n> --json body`. On the READING side the body is unpinned
  by the head SHA and drifts under a recorded verdict, so re-read it immediately
  BEFORE recording one — `body-unchanged` refuses a post-pass edit at the merge, but
  cannot give back a round already spent on stale text (#565). Signature: a re-review
  quoting a body line as verbatim what it was, on a finding your own response section
  says was narrowed (#1225).
- **Historical context lives in design notes, ADRs, and issue/PR history —
  never in user docs, this repo's own agent instruction files
  (`.github/agents/`, `.claude/skills/`, `.orrerix/workflow.yml`), or this
  file.** Incident stories, superseded rules, dates, and "how we got here"
  narratives pollute every future reader's context. Reader-facing text
  carries the current rule and its operational why, with at most a bare
  issue/PR ref as provenance; strip any such narrative you find when
  editing these surfaces — including `.orrerix/lessons.md`, which carries
  the rule and fix only, with refs as provenance. Out of scope: code
  comments (the "comments explain *why*" convention), the shipped
  agent-role templates (`src-tauri/src/orchestration/templates/`, governed
  by their design notes), and **vendored files** (any skill directory with
  a "Vendored skill — do not edit in place" README, e.g.
  `.claude/skills/frontend-design/`):
  editing those silently forks the vendor — re-vendor from upstream instead,
  per `THIRD_PARTY_NOTICES.md`.
