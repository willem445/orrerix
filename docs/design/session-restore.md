# Session restore (issue #194)

On reopen, loomux can bring back the **whole prior session** — every tab, each
tab's pane layout, and, where possible, the live agent sessions — or start
clean. This note is the architecture of the **data layer** for that: the
persisted schema, the restore decision model, and the per-pane restore policy.
The boot splash, the grid rebuild, and the auto-resume wiring are the wiring
layer (`main.ts`, Phase 4) and are described only where they consume this core.

This extends **project tabs** ([project-tabs.md](project-tabs.md)), which already
persists the tab shells (name / color / order / active / group binding) through
`tabstore.ts` → the opaque `tabs.json` blob. Session restore adds a per-tab
**pane layout tree** and two top-level fields to that same blob — no backend
change, because the blob stays opaque to `uistate.rs`.

## What the schema captures (and deliberately does not)

`tabstore.ts` is the single source of the tab schema. The `tabs.json` blob gains:

- **`schemaVersion`** — bumped to `2`. A pre-#194 file has no version; decode
  reads that as `1`.
- **`restorePref`** — `"ask" | "restore" | "fresh"`. First run is `"ask"`
  (show the splash), then the human's remembered choice.
- per-tab **`layout`** — an optional split tree mirroring `grid.ts`'s
  `GridLayoutNode`, but with serializable **`PersistedPane`** leaves instead of
  live `Pane` objects. Each leaf records only what restore needs:
  `paneKind` (`terminal | agent | orch`, plus the later content kinds and
  `ssh`), `name`, `cwd`, `command`/`argv`, `shellKind`, and a recorded resumable
  `sessionId`. One kind carries a field of its own: an `ssh` leaf records
  `sshProfileId`, the saved connection it belongs to — see the #887 S4 section
  below for why that, and not its command line, is what comes back.

What is **never** captured: the live PTY, the terminal buffer/scrollback, or any
geometry. A pane is re-created or resumed from its record; its process history
is gone (the PTY died with the app). This preserves the cost/#78 stance and the
no-resize invariant — capture reads `layoutSnapshot()` (in-memory tree + flex
weights, no geometry) plus `Pane.capture()` (retained launch inputs + live cwd).

### Migration contract — old files load cleanly

Every #194 field is **optional and additive**, so an old `tabs.json` decodes
exactly as before — shells-only, `restorePref` defaulted to `"ask"`,
`schemaVersion` `1`, and **no `layout` key invented** on any tab. `encodeTabs`
also accepts a pre-#194 snapshot *object* (no `restorePref`/`schemaVersion`/
`layout`) unchanged and stamps the current version on write — which is why
`main.ts`'s `tabs.snapshot()` needs no change to keep producing a valid blob.

A malformed `layout` is **fail-safe**: any invalid node (bad pane, unknown kind,
empty or mis-directed split) collapses that tab's **whole** layout to `null`
rather than throwing — the tab then restores as **one empty pane on the welcome
surface** (`main.ts`'s empty-tab fill; no PTY spawns until the human picks a
kind). This is
the same "degrade, never crash boot" guard the tab decoder already applies to
malformed tab entries. Malformed *scalar* fields inside an otherwise-valid leaf
coerce to `null`/defaults (bad `cwd` → `null`, non-string `argv` element → whole
`argv` `null`, unknown `shellKind` → `null`, bad `weight` → `1`).

## The restore decision — `restoredecision.ts`

`decideRestore(pref, hasSnapshot) → "restore" | "fresh" | "prompt"`. Tiny by
design: the remembered preference decides, except that with **nothing worth
restoring** we always go `"fresh"` — never prompt over an empty session, never
claim to restore a blank state. `hasSnapshot` is computed by `main.ts` from the
decoded blob (at least one tab, with a captured layout worth rebuilding).

| `pref` \ `hasSnapshot` | `false` | `true` |
| --- | --- | --- |
| `"ask"` | `fresh` | `prompt` (splash) |
| `"restore"` | `fresh` | `restore` |
| `"fresh"` | `fresh` | `fresh` |

## The per-pane restore policy — `panerestore.ts` (the adopted hybrid)

The issue's key insight: **resuming a CLI session re-opens its context but costs
nothing until a prompt is sent.** That makes auto-resume viable for agent panes
without burning credits — but *not* for whole orchestration groups, where a
resumed autonomous orchestrator (#83) can idle-tick and spawn a worker storm
(#78). So the policy is **kind-aware**:

| Pane kind | On restore | Why |
| --- | --- | --- |
| **Terminal** | Re-spawn a fresh shell in the recorded cwd + `shellKind` | No session to resume; zero cost; layout/cwd back instantly. |
| **Agent** (has `sessionId`) | **Auto-resume** via `--resume <id>` into the idle TUI; **never** replay a queued prompt | Loads context, spends no credits — the "near-exact state" goal. |
| **Agent** (no `sessionId`) | **Dormant** pane with a Start button, in the same cwd — plus, when a matching session is found, a second "Resume last session" button (#440) | Best-effort CLIs (copilot/codex/gemini) have no clean resumable id; honest, not silently broken. A claude/copilot pane can *also* land here despite being session-capable — see [session-id-learning.md](session-id-learning.md) for how loomux learns an id it didn't itself mint, and why "no id recorded" isn't always "no session exists". |
| **Orchestrator / worker / reviewer** (`orch`) | **Dormant** — the human resumes the whole group via the existing `resumeOrchSession` | The one place a resume can actually burn credits; keep the safety stance exactly here. The rule is keyed on **kind, not the presence of an id** — a worker with a session id still stays dormant. |
| **File explorer** (`files`, #214) | Re-open the listing at its recorded root — or, if that folder is gone, **fail soft to the welcome form** in that slot with a toast | Pure content: no process, no session, no credits, nothing to resume. The only thing that can rot under it is the *folder*, so the root is re-probed (`ftRootIsDir`) before the pane is built. Keyed on kind like the orch rule: a stray `sessionId` on a files leaf must never send it down an agent path. |
| **File editor** (`editor`, #217) | Re-open the editor at its recorded root, **re-opening the file it was showing** (`file`, a root-relative path — read fresh from disk); same `ftRootIsDir` probe, same fail-soft | Same reasoning, plus one wrinkle: a pane opened from the file browser is *titled after its file*, so restoring a bare tree under that title would name a file the pane isn't showing. What is **not** restored is the BUFFER. Persisting unsaved text would make the layout file a second, silent copy of the user's work — the close guards are what ensure they were *asked* before it could be lost, and a snapshot that quietly preserves it undermines exactly that. A file deleted since just fails to open (a toast); the pane still comes back, rooted. |
| **Git** (`git`, #217) | Re-open the git view over its recorded repo — probed with **`gitRepoRoot`**, not `ftRootIsDir`. A probe that *throws* (git not on `PATH`, unreadable path) keeps the pane; only git's own "not a repo" fails soft | A folder can still exist and no longer be a work tree (a pruned worktree, a deleted `.git`, a repo restored from backup as plain files), and a git pane over a non-repo can only tell you it isn't one. But a git that cannot be RUN is a fact about the environment, not the repo: failing soft on it would swap every git pane for a welcome form *and* drop the recorded path from the next save — losing it for good over a transient hiccup. Also **not** restored: the selected worktree and the read-only unlock (#208) — a restored pane opens on the primary, locked, like a fresh one. An unlock that survived a restart is the one piece of this pane's state that could quietly cost you something. |
| **SSH** (`ssh`, #887 S4) | **Dormant** with a **Reconnect** button. Nothing connects until it is clicked, and the click rebuilds the command from the **saved profile**, resuming the recorded remote session when the profile still names a CLI loomux mints ids for | Two independent reasons, neither of which applies to a local shell. The CLI on the far end is an agent on *someone else's machine*, so an automatic reconnect spends **remote** credits with no human present — the orch-pane argument, one host removed. And a host that is down, asleep, or behind a VPN that isn't up yet would put a TCP connect (which may not fail for a minute) on the **boot path**. See the section below for what the leaf records and why it is not a command line. |

None of the content kinds needed a **schema change**: each one's root rides in the
existing `cwd`, so `SCHEMA_VERSION` stays at 2 and older files (which simply never
contain such a leaf) decode unchanged — the same shape-driven, additive move `role`
made in #194.5. A rootless content leaf is *well-formed but unrestorable*, so it
decodes (rather than triggering the whole-tree fail-safe and taking its sibling
panes down with it) and is resolved in the one slot at restore time.

`planPaneRestore(pane) → RestoreAction` is the per-pane core; `planLayoutRestore`
turns a layout tree into an ordered `RestoreOpenStep[]` — one `grid.openPane`
call each, with `relativeTo` (the index of an earlier step's pane to split from),
`dir`, and a `weights` chain. This is the **reconstructible** plan: a split's
first child stays put as the anchor and its siblings open beside it, so the
direction and the subtree's weights ride on the sibling steps. A flat
`{dir, weight}[]` (an earlier draft) dropped `relativeTo` and split weights, which
made a 2×2 grid and four stacked panes flatten to the *identical* sequence —
unreconstructible. A serialize → `planLayoutRestore` → replay round-trip is now
structure- **and** weight-identical; `test/panerestore.test.ts` proves it with a
pure model of grid's `insertBeside` (and pins that the 2×2 and 4-stack plans
differ). `grid.openPane` resets flex to equal shares as it splits, so `main.ts`
applies the `weights` after building. All three functions are pure and
exhaustively unit-tested.

**The one-line flip.** The plan promised that switching to all-dormant (every
agent gets a Start button, matching the earlier #167 default) is a single-line
change. It is: `export const AUTO_RESUME_AGENTS` in `panerestore.ts`. Set it to
`false` and every agent restores dormant; groups are dormant regardless.

Rejected outright: **re-attaching** to the old PTY (impossible — it died with the
process) and **auto-resume-with-a-replayed-prompt** (would spend credits on boot).

**Orch leaves + the double-spawn contract.** Unlike the earlier plans, `capture()`
*does* serialize orchestration panes (as `paneKind: "orch"`) rather than dropping
them, so the layout keeps its shape — but `planPaneRestore` maps them to
`dormant-group`, which **must spawn nothing**. The group is revived only by the
tab's `groupId` binding through `resumeOrchSession`; if Phase 4's handling of
`dormant-group` ever opened a pane, a subsequent group resume would double-spawn
every worker (the #78 storm). That contract lives on the `RestoreAction`
`dormant-group` variant and must be honored in the Phase 4 rebuild.

### #887 S4 — SSH panes: the leaf records a CONNECTION, not a command line

An SSH pane's process is a local `ssh` client (see `docs/design/ssh-panes.md` for the
transport argument). Persisting it needed **one new field**, `sshProfileId`, and
the choice of what *not* to persist is the whole of this design.

**The record is `{paneKind: "ssh", name, sshProfileId, sessionId}`** — no `cwd`
(the pane's local directory is deliberately home; the remote directory belongs to
the profile) and, pointedly, **no `argv`**. A reconnect re-derives the whole
command line from the saved profile through the same builders a fresh launch
uses (`sshReconnectArgv` → `sshLaunchParams` → `buildSshArgv`/`sshResumeArgv`).

Replaying a captured `argv` was rejected for two separate reasons, either of which
would be sufficient:

1. **The profile is what the human edits, and it is what a pane points at.** That
   is `sshprofile.ts`'s stated contract for `SshProfile.id` — a pane records the
   id, not the contents, so renaming or re-editing a connection keeps its panes
   pointed at it. A pane that replayed a captured command line would still be
   dialling last week's port, with nothing on screen to say why.
2. **A captured `argv` is not replayable.** A claude remote command carries
   `--session-id <id>`, which *creates* that session; replaying it against a
   session the earlier run already created is an error, not a reconnect. Nor can
   it be rewritten from outside: the entire remote command is **one shell-quoted
   string** inside that argv, so a rewrite would mean re-parsing the quoting
   scheme `sshcommand.ts` exists to be the sole implementation of.

**Resume vs fresh is decided by the profile as it is now**, not by the record. The
recorded id is resumed only while the profile still names a CLI whose identity
travels on the command line (`sshMintsSessionId` — claude, because every other
CLI's id is *discovered* by reading a **local** store, a mechanism that cannot
reach the far host). A profile switched to copilot since gets a fresh connect with
no id at all: the recorded id names a conversation copilot cannot read, and
`--session-id` is not a flag it would accept. A claude profile with no recorded id
**mints a new one**, so the reconnected session is itself resumable next boot —
the same reasoning `agentFreshCommand` applies locally.

**A profile that is gone is not guessed at.** A deleted connection (or one lost
when a corrupt `sshprofiles.json` was quarantined) leaves the card in its error
state saying so, offering nothing. There is deliberately no fallback: inventing a
connection out of a stale command line is how a pane would silently reconnect
somewhere the human removed on purpose.

**Forward/backward compatibility, stated exactly.** `SCHEMA_VERSION` stays at
**2**: the addition is shape-driven and additive, so a v2 file written before this
simply never contains an `ssh` leaf and decodes unchanged. The **downgrade**
direction is where it costs something, and it costs more than a per-entry drop: an
older build's `decodePane` rejects the unknown kind, and `decodeLayout`'s
whole-tree fail-safe then collapses **that tab's entire layout** to a single fresh
shell. (A *docked* ssh pane is the softer case — `docked` entries are dropped
individually.) That is accepted rather than worked around, because the alternative
— persisting an ssh pane under a kind an old build recognizes — means an old build
**spawning the wrong process under the right title**: a local PowerShell wearing
the remote host's name. A dropped tab layout is legible and recoverable; that is
neither.

**The #887/#888 boundary at the restore seam.** SSH panes are display-only in v1
and can never be orchestration group members (the refusal lives in
`sshOrchestrationRefusal`, and the reasons are in `docs/design/ssh-panes.md`). Restore is
the one path that turns a **hand-editable file on disk** into a spawn, so the
boundary is enforced there structurally rather than by filtering: the
`dormant-ssh` action has **no field** that could carry `role`, `groupId` or an
orchestration embed, and the placeholder record `main.ts` builds pins all three to
`null`. An `ssh` leaf hand-edited to claim `role: "worker"` restores as an
ordinary dormant SSH card; `test/panerestore.test.ts` pins that, and goes red if a
future edit copies the adjacent `dormant-group` arm's shape.

**A resume that can never succeed has an escape.** The remote conversation lives
on a machine loomux cannot see, so it can be gone (deleted on the far host, a
cleared `~/.claude`, a rebuilt box) while the id naming it is still recorded here
— and then `claude --resume <id>` fails every time and plain Reconnect loops. The
card carries a second, quiet **Reconnect fresh** action whenever a session was
recorded: the same connection, a new remote session. Deliberately *not* the local
#194 BUG-1 machinery, which cannot serve here — that backstop triggers on a resume
the frontend itself launched and can rewrite, whereas the failing `--resume` is a
token inside a remote command string on a host we cannot inspect (a non-zero exit
from `ssh` says only "something over there ended", never which). It is also
deliberately a human's choice rather than an automatic downgrade: silently
starting a new conversation would abandon one that might just be behind a host
still booting.

A reconnect is **single-flight per pane**, and that is a correctness rule rather
than a UI polish: the card carries two actions, a pane can bind only one pty, and
two overlapping attempts leave the loser orphaned — output routed nowhere, an exit
nobody claims, and no way to kill it, because a kill goes through the pane's own
`ptyId`. An orphaned *local* process is a nuisance; an orphaned **remote agent CLI
is an unaccountable agent running on someone else's machine**, which is the exact
cost this whole restore policy is argued from. So every reconnect entry point
funnels through one latched function (`withSubmitLatch`, reusing the `SubmitLatch`
the welcome form's own double-submit fix introduced), and the card's two buttons
share one pending state so neither stays live while the other is connecting. The
latch releases on failure as well as success — a reconnect that failed must stay
retryable, since retrying is what the card is for.

**A minted id can outlive a spawn that never happened** — pre-existing, and named
here because this is where a reader will meet it. `Pane.start` records
`opts.sessionId` before `attachPty`, so a *fresh* connect whose spawn throws
leaves the pane holding an id for a remote session that was never created; the
next `capture()` persists it, and a later Reconnect resumes an id the far host has
never seen. This is not specific to SSH — the local agent launch path has always
recorded its minted id the same way — and it is not what this slice changed, so it
is left for its own fix rather than folded in here. What S4 does contribute is the
way out: the fresh escape above turns that state from a trap into one extra click.

**A disconnect keeps the pane.** `keepOpenOnExit` gained an `isSshPane` input, and
that is a fix as much as a feature: an SSH pane spawns through the *argv* path, so
`launchedCommand` is false for it and the crash rule would have closed the pane
the instant the link dropped — taking the scrollback that explains it. The rule is
not loosened: an expected (loomux-initiated) exit and a clean exit 0 (the human
typed `exit` on the far end) still close. The Reconnect card that then appears
**floats over the still-mounted terminal** instead of replacing it, because that
output is precisely what the human is deciding on; it is absolutely-positioned
chrome, so nothing resizes the terminal or the ConPTY (CLAUDE.md constraint 1).
Auto-reconnect was rejected outright: a surprise reconnect re-enters a remote TUI
in a state nobody has looked at.

**What a reconnect that fails AT SPAWN costs, stated rather than traded quietly.**
Both relaunch paths tear the card down and (on the disconnect path)
`term.reset()` *before* the spawn, so a spawn that then throws has already
discarded the scrollback the card exists to sit over. The reset ordering is not
this feature's to change: it is #720's, and deferring it until after a successful
spawn would paint the dead session's tail over the new one's first bytes, because
`reset()` clears synchronously while `term.write` parses asynchronously. What the
failure *does* get back is a surface: the launch callback re-mounts a Reconnect
card carrying the error, so the pane keeps a persistent reason and a one-click
retry instead of an empty pane and a transient toast. The residual — a lost
scrollback on a failed reconnect — is accepted, and the window is narrow (the ssh
client is re-probed moments earlier; a host that is merely down fails seconds
later, with the spawn long since succeeded).

**Reaping a spawn that dies too early.** Both reconnect paths call
`reapIfExited` after the relaunch, exactly as the fresh SSH launch always has. An
`ssh` that exits before the frontend has finished wiring the pane parks its exit
in `earlyExits`, keyed by a pty id no pane claims yet; nothing else would ever
drain it, and the pane would sit looking alive over a dead PTY — no banner, no
card, keystrokes into nothing. This is the one feature whose *expected* case is a
connection that fails, so the reap is not left to the convention that every other
dormant-card click path in `main.ts` still follows.

### #439 fix — a standalone agent's solo channel identity must be RE-MINTED, never replayed

`agentResumeCommand`/`agentFreshCommand` keep every recorded flag except the
session ones — which is exactly right for `--model`, `--permission-mode`, etc.,
but wrong for one flag group: a standalone (launcher-spawned) claude/copilot
pane with channel tools on gets a solo channel identity at launch
(`soloPrepare`/#271 W3 addendum), and its command line carries that identity's
MCP flags (`--mcp-config <path> --strict-mcp-config --allowedTools mcp__orrerix`
for claude, `--additional-mcp-config "@<path>" --allow-tool orrerix` for
copilot) — **or, on a tab recorded before #1153 phase 3, the same flags naming
the old MCP identity, which `stripSoloMcpFlags` still recognises for exactly the
reason the rest of this paragraph gives.** That config file — and the identity's
token — are deleted the moment
the pane's agent process exits (same lifecycle as an orchestration member).
Replaying the recorded flags on restore therefore points at a file that is
**guaranteed gone**: claude hard-errors (`MCP config file not found`) and
copilot would authenticate nothing even if the file happened to still exist.

The fix is a strip-then-re-mint pair, kept in `panerestore.ts` for the pure
half:

- `stripSoloMcpFlags(command, argv)` recognizes the exact, contiguous flag
  group either CLI's mint emits and removes it, reporting which CLI it
  belonged to (`null` — nothing to re-mint — for a custom command or a
  channel-tools-off launch, which never had the flags to begin with). The
  minted path is a real Windows profile path and the backend quotes it
  *because* a username can contain a space ("Will H") — review round 1 (B1)
  caught a naive `.split(/\s+/)` tokenizer fracturing that quoted path across
  two tokens, silently failing the fixed-offset match and letting the dead
  path straight through. The fix excises the flag group with a regex against
  the **original string** (`"[^"]*"|\S+` for the path group) rather than a
  tokenize/rejoin round trip — which also settled a second finding (N1,
  escalated to blocking) in the same move: a `cli: null` command — the common
  case, every restore that never had a solo identity — now comes back
  byte-identical, including whitespace runs inside unrelated quoted flags,
  instead of being silently reflowed by a `.split/.join`.
- `appendSoloMcpArgs(command, argv, mcpArgs)` appends a freshly-minted
  identity's flags back on. Its argv-form branch (latent — solo panes are
  never argv-spawned today) tokenizes `mcpArgs` quote-aware too
  (`splitQuotedTokens`), stripping the quotes rather than embedding them
  literally in an argv element (N2) — a spaced fresh path lands as one clean
  element, not two with stray `"` characters glued on.

`main.ts`'s `remintSoloIdentity` composes them with the actual I/O: strip →
`await soloPrepare(cli, cwd, name)` (best-effort, same contract a live launch
already states — a failed mint just leaves the flags stripped, so the pane
boots **delivery-only** rather than not at all) → append → hand the caller a
`command`/`argv`, a `channelAgent` carrier for `PaneOptions`, and a `bind`
thunk to call with the pane's `ptyId` once it's spawned (mirroring the launch
path's `channelAgentFor`/`bindSoloIfNeeded`). It is applied at all three
places a recorded standalone-agent command gets replayed:

- `resume-agent` and `fresh-agent` (the two `RestoreAction`s above) — before
  `ws.grid.openPane`.
- `dormant-agent`'s Start button — copilot never gets a recorded `sessionId`
  (only claude does, at launch), so a copilot solo pane restores dormant
  *every* time and this is its only replay point; the re-mint happens inside
  the button's `onclick`, lazily, only if the human actually clicks Start.
- The runtime resume-failure backstop (`tryResumeFallback`, BUG-1 above) — its
  fresh-respawn command is built from the same recorded fields, so it can
  carry the identical dead flags. The re-mint there is **lazy**, done only when
  the fallback actually fires (not pre-minted alongside the initial resume
  attempt): the common case never needs the fallback, and pre-minting one
  "just in case" would leak an orphan `solo-N` config/token on disk for every
  ordinary successful resume.

One wrinkle worth flagging for the next reader: `Pane.start` (used by
`openPane`/`startFromDormant`) applies `opts.channelAgent` itself, but
`Pane.respawnFresh` does **not** — the fallback path sets it explicitly via
`Pane.setChannelAgent` after the respawn resolves.

## Module map (this phase)

| Piece | File | Role |
| --- | --- | --- |
| Schema + validators | `src/tabstore.ts` | `PersistedPane` / `PersistedLayoutNode` / `RestorePref`, versioned encode/decode, the fail-safe layout validator. Unit-tested. |
| Restore decision | `src/restoredecision.ts` | `decideRestore` — restore/fresh/prompt. Unit-tested. |
| Per-pane policy | `src/panerestore.ts` | The adopted hybrid + tree flattening + the all-dormant flip. Unit-tested. |
| Capture getter | `src/panecapture.ts` | `Pane.capture() → PersistedPane \| null`, delegating to `capturePane` (null for a setup-state welcome pane); retains launch inputs (`command`/`argv`/`shellKind`/`sessionId`) for it. DOM-coupled → hand-validated. |
| Wiring (Phase 4) | `src/main.ts` | Splash, `hasSnapshot`, layout capture into `snapshot()`, grid rebuild, auto-resume, dormant Start/Resume. |
| Splash overlay (Phase 4) | `src/restoresplash.ts` | Cold-boot "Restore last session?" overlay (thin DOM over `decideRestore`). |
| Counter/markers (Phase 4) | `src/tabcounts.ts` | Pure per-tab live-agent count + live/dormant orchestration markers. Unit-tested. |
| Group resume (Phase 4) | `src/groupresume.ts` | Pure whole-group resume plan (orchestrator first, delegates rejoin/skip). Unit-tested. |

`shellKind` is recorded here but the backend spawn plumbing that acts on it lands
in the shell-kinds phase; `sessionId` is populated by the launcher when it spawns
a session-capable CLI (Phase 4). This phase makes both **capturable**.

## Phase 4 — the wiring (this phase)

The data layer above is now driven end to end by `main.ts` and a thin overlay.

**Capture, populated.** `Pane.capture()` already reduced a live pane to a
`PersistedPane`; Phase 4 fills the last gap — the **session id**. The launcher
mints one for a session-capable CLI (Claude only) as `crypto.randomUUID()` — the
webview's Web Crypto, **not** a getrandom crate, so constraint 2 (which governs
`src-tauri` Rust) doesn't apply — appends `--session-id <uuid>` to the command,
and threads the id onto the pane. `Workspace.captureLayout()` walks
`grid.layoutSnapshot()` into a `PersistedLayoutNode` tree (pruning welcome/setup
leaves, collapsing a split that thereby loses a sibling), and `TabManager.snapshot()`
now carries each tab's `layout` plus the remembered `restorePref`. A new grid
`onChange` callback (fired on pane open/close) re-persists and re-renders the tab
strip, so **live panes persist on change and close** — no longer only on tab-level
edits.

**The boot decision.** `main.ts` decodes the blob, computes `hasSnapshot`
(`hasRestorableContent`: ≥1 tab with a layout, a group binding, or simply >1 tab),
and calls `decideRestore(pref, hasSnapshot)`. `prompt` shows `restoresplash.ts` —
Restore / Start fresh, with a *Remember my choice* box that writes the preference
back (unticked keeps it `"ask"`). It's a pure overlay before any tab exists, so it
resizes nothing.

**The rebuild.** For each restored tab, `rebuildLayout` runs
`planLayoutRestore(layout)` and replays each `RestoreOpenStep` into the tab's grid
(`relativeTo` → the anchor pane from an earlier step, `dir` → the split direction),
then calls the new `grid.applyLayoutWeights(layout)` **once** — `openPane`/
`openDormantPane` reset flex to equal shares as they split, so the saved divider
drags are re-applied after the tree exists. The replay matches the pure model in
`test/panerestore.test.ts` (same `insertBeside` semantics), so structure and
weights come back identical.

Per action:

- **spawn-terminal** → `grid.openPane` with the recorded `cwd` + `shellKind`.
- **resume-agent** → `grid.openPane` with `agentResumeCommand(command, argv,
  sessionId)` — the recorded launch line with any `--session-id`/`--resume`
  stripped and `--resume <id>` appended (flags like the autopilot permission flag
  survive; **no prompt is ever appended** — the no-replay rule). The session id is
  re-recorded so a *second* restore resumes identically.
- **dormant-agent** → `grid.openDormantPane` showing a **Start** card that calls
  `pane.startFromDormant(...)` with the recorded command.
- **dormant-group** → `grid.openDormantPane` showing a **Resume group** card. This
  is where the **no-double-spawn contract** is honored: the placeholder spawns
  nothing. Resume looks up the group's recorded orchestrator session
  (`orchSessionRoles`) and revives the whole group through the existing
  `resumeOrchSession` — the *one* path that spawns it — **then** closes the now-
  redundant dormant ORCH placeholders (after the revive added a real pane, so the
  grid never empties). A dormant pane re-captures its record verbatim, so a session
  closed without resuming offers the identical restore next boot.

Every pane rebuilds `background` (no focus theft); the active tab is focused last.
The rebuild runs with a `booting` guard so the many intermediate opens don't each
re-persist — boot persists once at the end.

**Counter + markers.** The tab strip's agent counter was unreliable (it read only
a 4-second backend group poll, so a plain-agent tab showed nothing and a just-
opened group flashed a stray `0`). It now derives from `tabcounts.ts` over the
panes actually open in the tab (`Workspace.paneInfos()` → `Pane.tabPaneInfo()`):
`agents` counts live agent + live orchestration panes; `liveOrch` drives the `⛓`
icon; `dormantOrch` (a bound-but-not-live group, or a dormant ORCH placeholder)
drives the static `ORCH` chip — never both at once. Cost/paused still come from the
poll. The grid `onChange` re-render makes the count immediate, not poll-latent.

**Stranded-form fix (P1 debt).** A welcome form fires its result and is retired,
but an orchestrator launch that threw afterward left the form stranded with a
disabled *Working…* button. `handleWelcomeSubmit` now catches it, toasts the
error, and calls `form.reopenAfterLaunchFailure` (restoring the fired callback and
re-opening the `SubmitLatch`) so the human can fix the cause and retry.

### rev-80 hardening — every population/layout change flows through one notify

The first cut hooked `grid.onChange` only at leaf placement, which fired *before*
`pane.start()` assigned a `ptyId` and never fired at all on the in-place
conversion paths — so the counter missed a single-agent submit and undercounted a
fan-out by one, and a divider drag or pane drag-move was never persisted (the
demo's "drag then quit" restored stale weights). The rule now is: **anything that
changes a tab's live pane population or its layout re-renders + re-persists.**

- `grid.openPane` fires `onChange` *after* `pane.start()` resolves (PTY live), and
  the in-place conversions (`startFromWelcome`, `startFromDormant`) + the
  kept-open exit path call `onGridChanged()` in `main.ts` once they settle.
- Terminal layout mutations that only touched flex/order — the divider-drag
  `mouseup`, the drag-reorder commit, and dock/undock — now fire `onChange`. All
  are terminal (one per gesture), so `persistTabs`'s snapshot dedup absorbs the
  rest; no per-mousemove write storm.
- A kept-open exited pane sets `Pane.exited`, so `tabPaneInfo().live` is
  `ptyId !== null && !exited` — a dead agent stops inflating the count.

**Docked panes are captured.** `layoutSnapshot` only covers the split tree, so a
minimized pane would have been silently dropped. `PersistedTab.docked` (additive,
migration-safe) carries `Workspace.captureDocked()`; restore reopens each via the
same `openActionPane` used for layout leaves, then `grid.minimize`s it back into
the dock. So the live buffer/scrollback is still never captured, but no *session*
is lost to the dock.

### Post-demo fixes — resume-of-empty-session and the boot ordering

**BUG-1 — a `--resume` with no conversation must not strand a dead pane.** We mint
`--session-id` at launch, but a session the user never prompted persists no
transcript, so `claude --resume <id>` exits 1 ("No conversation found …"). Two
layers now handle it, both keeping panerestore pure:

- *Pre-check.* `main.ts` fetches `listSessions()` (which lists exactly the
  sessions that HAVE a transcript) and passes a `SessionResumable` predicate into
  `planLayoutRestore`/`planPaneRestore`. An agent whose id is absent plans a new
  `fresh-agent` action instead of `resume-agent` — a fresh session **in place**
  with the same name/cwd/CLI, reusing the recorded id (via `agentFreshCommand`,
  which pins `--session-id`, not `--resume`) so it's resumable again next boot.
  On an empty/failed session list we assume resumable and lean on the backstop.
- *Runtime backstop.* A resumed pane registers a one-shot fresh-fallback. If its
  PTY exits unexpectedly non-zero **within a short window** of the resume spawn
  (`shouldRespawnFresh` + a time gate), `Pane.respawnFresh` reuses the open
  terminal to start fresh in place — covering a transcript deleted between the
  pre-check and the spawn, or any other resume-time CLI failure. The time gate is
  essential: a resume that *succeeded* and was worked in for a while and then
  exits non-zero is the human's own session ending, not a resume failure, so it's
  left alone. Unlike the pre-check, the backstop mints a **new** session id for the
  fresh command instead of reusing the recorded one: a resume can fail because the
  transcript EXISTS but is corrupt/half-written, and `--session-id <recorded>`
  would then hit the same conflict again — a brand-new id always creates cleanly.
- *Early-exit symmetry.* Both restore open paths (`rebuildLayout`, `restoreDocked`)
  call `reapIfExited` after each `openActionPane`, matching the welcome/session
  paths — a spawn that exits in the sub-tick before `ptyId` is assigned is drained
  from `earlyExits` (and can trip the fresh-fallback) rather than leaking.

### Whole-group resume (demo rounds 3–4)

The dormant **Resume group** button restores the panes that were LIVE at close —
the whole group, but **exactly** that group, no more.

**The set comes from CAPTURE, never the roster.** An early cut derived the member
set from `orchSessionRoles()` → `session_roles()`, which lists every member the
group *ever* had (long-killed workers included) — so a group that closed with an
orchestrator + 1 worker came back with a swarm of stale worker panes (demo round 4
over-restore). The fix: each captured orch pane now records **its own session id
and role** (`Pane.capture()` for kind `orch`, the id parsed from the backend-built
command by `sessionIdFromCommand` at spawn, or — for a copilot/opencode pane,
whose id does not exist until after boot — from the backend's
`orch-session-learned` event; see
[session-id-learning.md](session-id-learning.md)), so the persisted layout carries one
leaf per orch pane that was open at close. On restore those become `dormant-group`
placeholders each holding that record; `resumeDormantGroup` reads the member set
straight off the tab's placeholders (`Pane.restoreRecord`). `session_roles()` is
no longer consulted for the SET — the backend still validates membership and drives
re-registration when each member resumes, but it can never EXPAND beyond what was
captured. Members that were not open at close stay dead; they remain resumable
later from the session browser (out of scope, by design).

`planGroupResume` (pure, unit-tested) turns the captured members into an ordered
plan: orchestrator first, then the delegates, split into `rejoin` (session has a
transcript) and `skipped` (none). Its tests pin captured-set-in == planned-set-out
— a 10-member historical roster is irrelevant because it's never an input.
`resumeDormantGroup` executes the plan through the **existing** `resumeOrchSession`
path — no backend change:

1. Resume the orchestrator → the backend `resume_recorded_session` relaunches the
   whole control plane (`create_orchestration_group` with the resumed session),
   bringing the group live.
2. Resume each `rejoin` delegate **sequentially** — the backend refuses a rejoin
   into a group that isn't live yet, so order matters and the orchestrator must be
   awaited first. Each rejoin runs `spawn_agent_ex` with the recorded session id,
   which **re-registers** the agent into the group (MCP identity, roster, cwd) so
   the orchestrator can message it again, and `--resume`s its idle TUI (credit-
   neutral, no prompt replay). Its pane arrives in this tab via the group→tab
   routing.
3. The per-group latch (`resumingGroups`) wraps the whole sequence, so one click is
   one atomic multi-pane restore — the many placeholder cards of a group can't each
   kick off a resume, and no member is double-spawned.

**What restores:** exactly the captured members (the orch panes live at close),
each whose session has a saved conversation — re-registered with the group and
resumed into its idle TUI; same number of panes out as were captured in. **What
does NOT (stated, not silent):** a captured delegate that was never prompted has no
transcript, so `--resume` would fail and strand a dead pane, and the frontend can't
spawn a fresh *group-registered* worker (only the orchestrator spawns delegates).
Those members — plus any captured member with **no resumable id at all** (a copilot
delegate: copilot mints its own id after boot, so there's nothing to `--resume`) —
are counted together in the skip toast and left behind; the orchestrator can respawn
a fresh one on demand once it's live. The **orchestrator itself** is gated on the
same transcript predicate (`planGroupResume` → `orchestratorUnresumable`): a stale
orchestrator session doesn't relaunch into a dead pane — the whole resume falls back
to the session browser with a specific message. Pane **positions** within the tab
are also approximate — the orchestrator and rejoining workers lay out as they arrive
(a fresh group layout), not the exact captured split; the tab, sessions, and roster
are what's preserved.

**BUG-2 — decline crashed with "no active workspace".** The restore splash is
awaited while the app has zero tabs, and the window-focus handler (plus voice
init) resolve through `tabs.activeWorkspace`, which throws when the manager is
empty. Root cause was ordering, not a missing guard: boot now **seeds one tab
before** the splash, so there is always an active workspace. The restore path
builds its saved tabs and then drops the seed (indexing `activeIndex` against the
tabs it created, not `tabs.tabs`, since the seed offsets it); the fresh/decline
path just keeps the seed as the blank welcome tab.

**The credit/data sharp edges.** The dormant **Resume group** button disables on
first click and re-enables only on failure — a second click while the first resume
is in flight can't double-create the group (the double-spawn the contract
forbids), and a resume error is a toast, not the crash banner. The restore splash
is non-committal on **Esc**: a keyboard dismiss is a one-time fresh that never
writes the preference, and boot skips the end-of-boot persist for a non-committal
decline, so the saved `tabs.json` survives for the next launch's splash (one
habitual Escape can't wipe the session). An orchestrator launch that fails tears
down the tab it just created (`launchOrchestratorTab`'s catch) instead of leaking
an empty tab per retry, and re-focuses the form's own tab.

### #412 hardening — resolution robustness, and failing loudly

Root cause (confirmed on this machine, not inferred): a worker/reviewer resume's
launch cwd came from the roster's cached `AgentRecord.cwd` — the directory that
worktree was cut into at spawn time. When that worktree is later removed (its
branch merged, `git worktree remove`), `resume_recorded_session` used to
`.filter(|c| Path::new(c).is_dir())` the stale cwd down to `None` and let it fall
through to `spawn_agent_ex`'s per-role default — **the group's main clone**. The
pane then launched `claude --resume <id>` from the main clone's cwd. Per the CLI
reference, "passing a session ID searches only the current project directory and
its git worktrees" — Claude Code's own project-directory store is keyed off the
*launch* cwd (`~/.claude/projects/<munged-path>/<id>.jsonl`), so a resume from the
wrong cwd searches the wrong project directory and reports "no session found" —
even though `list_sessions` (which walks every `~/.claude/projects/*/` directory,
not one cwd) finds the exact same session fine, which is why the session browser
shows it as resumable while the resume itself fails. Reproduced directly: a
session's own `cwd` field (inside its `.jsonl`) named a worktree no longer present
in `git worktree list` for that repo; a resume attempt recorded against the main
clone's cwd instead failed with "no session found" for a session plainly on disk.

**Resolution (`sessions::find_session_cwd`, `orchestration::resolve_resume_cwd`/
`resolve_worker_resume_cwd`).** Locate the session directly in its CLI's store BY
ID — a bounded scan of `~/.claude/projects/*/<id>.jsonl` (claude, filename-keyed)
or `~/.copilot/session-state/*/workspace.yaml` (copilot, matched on the parsed
`id:` field, since its dirname isn't guaranteed to equal the id) — and read back
the cwd the session itself recorded. This is the best available signal, not a
guarantee (#412 review N2): it's the exact string the CLI already wrote for
itself, so it sidesteps a stale/moved worktree AND any casing/separator drift
between loomux's cache and the CLI's own record, without loomux ever having to
reproduce Claude's project-directory munging algorithm — but the recorded
`cwd` is not always the directory `--resume` actually searches (see
`find_session_cwd`'s doc comment in `sessions.rs` for the `.claude/worktrees`
case this doesn't cover: 2 of 691 real sessions on the machine this was
verified against).

**Testability.** The claude/copilot store roots are each overridable via a
`thread_local!` seam (`set_claude_projects_root_for_test`/
`set_copilot_session_state_root_for_test`, both `sessions.rs`), scoped to the
calling thread only — deliberately NOT a process-wide env var (#412 review
B2): Rust's default test harness runs each `#[test]` on its own OS thread, so
a thread-local set inside one test's body can never be read by a concurrently
running test the way a `std::env::set_var` mutation could (real,
unsynchronized-mutation undefined behavior across threads, which is why that
function is `unsafe` as of recent Rust editions — not just a style concern).
`tests/orchestration.rs`'s `fixture_claude_session`/`fixture_copilot_session`
helpers write the on-disk shape these seams point at.

**Launch-cwd choice, stated (corrected after #412 review N1 — this section
previously claimed the opposite of what the code does).** The roster's cached
cwd wins whenever it's still a real directory on disk — `resolve_worker_resume_cwd`
returns it directly, without ever consulting the store. Only a missing, empty, or
no-longer-existing cached cwd falls through to the store scan. This is
deliberate, not merely the cheap path: a live worktree the roster still points
at IS the session's current home, and is strictly better evidence than the
store's possibly-stale snapshot of where that same session happened to run
*at some point* — the store is consulted only because loomux's cache has gone
stale (the one case it's actually needed), never used to second-guess a cache
entry that's still checked out. A caveat this stance accepts: if the roster's
cwd and the store's cwd disagree while BOTH still exist as real directories
(e.g. a worktree re-added at a different path than the one the session
originally ran under), the roster wins even though it may not be the exact
directory the CLI itself would search — a narrower case than the #412 repro
(worktree gone entirely), left unhandled by design rather than by omission.

**Failing loudly.** When resolution comes up empty, `resume_recorded_session`
(worker/reviewer path) now resolves the cwd **synchronously, before** the
background `spawn_agent_ex` thread — so an unresolvable resume returns `Err`
straight back through the IPC call, and **no pane is ever opened** for it (no
"normal agent pane with no steering box" to degrade into, because nothing gets
spawned at all). The error is tagged (`resume-not-found:` / `resume-workspace-
missing:` / `resume-store-unreadable:` / `resume-ambiguous:` — the last from
`resolve_session_ref`'s existing prefix matching), so an orchestrator's
`spawn_agent(resume_session:)` can branch on the tag instead of parsing prose, and
`resumeerror.ts` (`resumeFailureKind`) does the same on the frontend. The session
browser turns a `not-found`/`workspace-missing` failure into a confirm dialog
("Session not resumable — Start fresh?") instead of a dead-end fatal banner;
confirming re-spawns fresh with the SAME recorded group/role/block/task brief
(`start_fresh` on `resume_orch_session`/`resume_recorded_session`), cutting a new
worktree rather than resuming the unresolvable one.

**`start_fresh` is a fresh CONVERSATION, never a fresh LAUNCH (#412 rev-17
blocker, fixed).** For an orchestrator, "start fresh" must reattach to the
group's EXISTING state — its persisted roster, and whatever its merge gate
currently is — not re-read `.loomux/workflow.yml` itself as if this were a
new launcher session. (Pre-#385, "existing state" and "the one the human
previewed and approved at the actual launch" were the same thing for the
gate, same as they still are for the roster. Post-#385 they can differ: the
background reload (`run_workflow_gate_reload`) keeps the gate in sync with
the CURRENT workflow file independent of any of this, so "existing" just
means "whatever's armed right now," launch-approved or since drifted. What
this paragraph is actually about — `start_fresh` itself never being the
thing that re-derives either — is unaffected either way.) The first cut
of `start_fresh` got this wrong by conflating two questions that happened to
coincide in every case that existed before it: `resume_session.is_some()`
used to double as "does this launch read the workflow file"
(`create_orchestration_group` derived `Launch` from it directly). `start_fresh`
introduced a THIRD case — an existing group, no session id to resume — where
that derivation gives the wrong answer: `Launch::Fresh`, which silently
swapped the group's roster to whatever the repo currently declares and could
delete its merge-gate spec file if the repo no longer declares one. Neither
the roster swap nor the gate deletion goes through anything a human sees; a
two-button "Start fresh?" confirm is not the launcher's roster preview, and
`Launch`'s own contract (`orchestration/mod.rs`) is explicit that a resume's
consent moment is the ORIGINAL launch, not this one.
`create_orchestration_group` now takes `launch: Launch` as its own explicit
argument instead of inferring it — `resume_recorded_session`'s orchestrator
branch always passes `Launch::Resume`, whether or not it's carrying a session
id to `--resume`, because either way it is reopening a group that already
has a roster and gate on disk — approved at launch for the roster; for the
gate, whatever's currently armed (see the aside above). `tests/orchestration.rs`'s
`start_fresh_on_an_orchestrator_does_not_re_read_the_workflow_file` pins both
directions (roster identity, merge-gate content) byte-for-byte across a
repo-file change that would otherwise have been silently adopted.

**Scope, stated (updated after #412 rev-17 B1 — this paragraph's second half
described the pre-B1-fix behavior, which shipped and was then found still
broken).** The orchestrator's own resume is NOT put through the store's cwd —
its launch cwd is always the group's repo path, fixed, never a worktree, so
the moved/deleted-worktree failure mode can't arise for it structurally. That
part still holds: there is no cwd SWAP for the orchestrator. What's no longer
true is "a cleared session still surfaces from inside the pane" — the
orchestrator branch DOES now run the same existence-only pre-check as the
worker/reviewer path (session genuinely absent from the store, or the store
unreadable) before opening a pane, tagged the same way, so `start_fresh` is
reachable for it too — closing #412's titular symptom (a cold-started
orchestration pane that fails inside with no steering box), not just its
worker/reviewer half. See `resume_recorded_session`'s orchestrator branch.
Copilot's own `--resume <id>` cwd-scoping behavior is **undocumented** (the
official reference is silent on it — see the `agent-cli-reference` skill's
citation discipline); the fix applies the same store-lookup mechanism to it
defensively (its session-state layout is flat and id-keyed, so the "wrong project
directory" failure mode is Claude-specific by construction), but this is not
empirically verified against a real `copilot --resume` the way the Claude repro
above is.

### #456 — restoring a copilot session must not guess its autopilot posture

**Root cause.** `sessions.rs::scan_copilot` rebuilds every copilot session's
resume command from scratch — `copilot --resume <id>` — reading only
copilot's own `~/.copilot/session-state` files, which know nothing about how
loomux originally launched the pane. A solo copilot pane launched with the
launcher's Autopilot toggle on carries `--autopilot --allow-all-tools
--allow-all-paths` on its ORIGINAL command line (`single_pane_autopilot_flags`,
#364); resuming it from the Sessions tab silently dropped all three flags,
landing the human back in plain interactive mode with no dialog and no
indication anything had changed — they had to notice and manually cycle
Shift+Tab into autopilot mode. This was invisible before #364 because a solo
pane never had TRUE autopilot to lose: pre-#364 it only carried the
permissive tool/path flags, which a bare resume also drops, but losing "every
tool pre-approved" reads very differently from losing "the agent keeps working
across turns" — the regression only became observable once #364 gave solo
panes the real mode.

**Why this isn't just "carry the launch command forward" the way an app-boot
restore can.** `panerestore.ts`'s restore actions (`resume-agent`/
`fresh-agent`/`dormant-agent`) replay loomux's OWN persisted `PersistedPane`
record, which already has the full original command string. The Sessions-tab
scan is a different, independent mechanism entirely: it discovers sessions by
reading the CLI's OWN on-disk state, which can include sessions loomux never
launched at all (a copilot session the human ran by hand, outside loomux). It
has no persisted command to replay — `resume_command` is synthesized from
nothing but the session id.

**The fix records loomux's own launch intent, and reads it back — never
copilot's files, which structurally cannot know.** `sessions.rs` gains a
capped store (`<data root>/copilot-posture.json`, `COPILOT_POSTURE_CAP =
300`) of ONE ENTRY PER CWD — `{cwd, posture, touched_ms}`, where `posture`
is `True | False | Conflicted` — written by `record_copilot_launch_posture`
at the one moment this information exists: launch time, for BOTH toggle
states (recording `false` matters as much as `true` — a later restore must
distinguish "explicitly launched without autopilot" from "no record at
all"). `scan_copilot` looks the session's own recorded cwd up in this store
and, only when the stored posture is unambiguously `True`, appends the SAME
`COPILOT_GROUP_AUTOPILOT_FLAGS` constant a fresh launch uses — one seam,
never a second copy of the flag string that could drift.

**The rule this store enforces, and why it isn't last-write-wins: on a
permission decision, ambiguity resolves to the smaller grant, never the
larger one — and that has to hold under store pressure and across
filesystems, not just in the ordinary lookup (review round 1, findings B1
and B2 below).** The store is keyed by cwd, not by copilot's own session id
— copilot never hands loomux a session id at launch (unlike Claude, which
gets one minted up front); it mints its own, invisibly, discoverable only
after the fact (`spawn_copilot_session_watcher`, group agents only). Because
two copilot sessions launched in the same folder at different times can
disagree (toggle on, then later off, or the reverse), a naive "most recent
record wins" resolution reintroduces exactly the escalation this fix exists
to avoid, just one step removed: restoring an OLDER, differently-postured
session in that folder would silently inherit whatever the folder's LATEST
launch happened to be — including granting `--allow-all-paths` to a session
the human deliberately launched without it, with no way for them to notice.
The precise fix would key on the resumed session's own start time and take
the newest posture record at-or-before it; that needs a reliable session
start timestamp, which copilot's `workspace.yaml` does not document (the
official reference is silent on its internal fields — see the
`agent-cli-reference` skill — and the file's OS birth time is not a safe
substitute, since copilot may rewrite it turn-to-turn). So instead:
`copilot_launch_posture(cwd)` returns `Some(v)` only when this cwd's stored
posture is unambiguously `v`; the moment a cwd has ever recorded BOTH `true`
and `false`, its posture becomes (and stays) `Conflicted`, which resolves to
`None` (no flags) — losing autopilot on restore costs a Shift+Tab, which is
recoverable and visible; silently granting a declined permission is neither.
Precise per-session keying (matching copilot's own session id once loomux
can learn it for solo panes, the way `spawn_copilot_session_watcher` already
does for group agents) is left to #457, the restore-path unification issue
this fix's architecture question prompted — not reimplemented here, to avoid
duplicating that work's unmerged scope (#446).

**Review round 1 (rev-34), B1 — the "permanently" claim above was false as
first shipped, and the bug was in the store's SHAPE, not the lookup.** The
first cut kept a flat, append-only log — one entry per WRITE, not per cwd —
and re-derived agreement at READ time by scanning every surviving entry for
a cwd. `copilot_launch_posture`'s lookup logic was correct; the problem is
that eviction (oldest individual entries dropped once the log exceeded the
cap) could remove ONE side of a conflict and leave the other as a lone
surviving record, which the read-time re-derivation then read as
unambiguous — silently flipping a conflicted cwd from `None` back to
`Some(true)`. Proven with a runnable counter-test before the fix: write
OFF then ON for one cwd (correctly `None`), push enough unrelated writes to
evict exactly the older (OFF) entry, and the cwd resolves to `Some(true)`.
**Fixed by moving conflict detection from read-time re-derivation to
write-time state, stored as one sticky value per cwd** (`CopilotPosture::
{True, False, Conflicted}` — `Conflicted` never reverts to a single value no
matter what's written or evicted afterward), and by making the cap count
CWDS rather than writes, evicting the least-recently-*touched* cwd
**wholesale** (`touched_ms` bumped on every write to that cwd, including a
repeat of the same value, so an actively-relaunched folder is never the
eviction target). This closes the failure mode structurally: eviction can
now only ever remove one cwd's entry ENTIRELY, moving it from `{True |
False | Conflicted}` to NO RECORD — which resolves to `None` right alongside
every other "nothing to go on" case. There is no state eviction can produce
that resolves to a grant a write didn't unambiguously establish. Pinned by
`conflicted_cwd_never_yields_flags_no_matter_how_much_other_activity_follows`
(asserted at the EXACT eviction boundary that would expose a flat log —
evicting far past that boundary evicts both conflicting entries together and
would pass for the wrong reason) and `re_touching_a_cwd_protects_it_from_
eviction`; both mutation-verified against the flat-log design.

**The one residual bound this doesn't close, named plainly rather than left
for someone to rediscover while changing eviction policy later (rev-6,
round 2 close-out).** `Conflicted` survives every partial eviction — but if
a conflicted cwd is evicted **entirely** (it becomes the least-recently-
touched of 300+ cwds — i.e., untouched while 300 OTHER folders were), its
whole history, including the fact that it was ever conflicted, is gone. If
that same folder is then explicitly re-launched, the store records the
fresh value as if it were the folder's first-ever posture; restoring an
OLDER session from that same folder — one whose posture disagreed with the
fresh write — would then inherit the fresh value, because post-eviction the
store cannot distinguish "no history" from "history that once disagreed and
was forgotten." This is the structural floor of any CAPPED, CWD-KEYED store:
eviction can only ever discard information, and once a cwd's entry is gone,
there is nothing left FOR the ambiguity rule to act on. The fix is precise
per-session-id keying (never cwd-approximated in the first place), which is
exactly the follow-up already named above and tracked as **#457** — not
reimplemented here. Accepted as a residual, not a claim-vs-reality gap: the
sticky-`Conflicted` state genuinely holds for as long as the cwd's entry
survives; this is a statement about what happens once it doesn't.

**Review round 1, B2 — the permission key must not case-fold on a
case-sensitive filesystem.** The first cut reused `norm_path` (the
SESSION-CWD MATCHING normalizer — `loomux_engine::sessions::norm_path`,
re-exported as `crate::sessions::norm_path`) as the posture store's key. That function
unconditionally lowercases: correct for Windows, where the filesystem
itself is case-insensitive, but wrong on Linux/macOS, where `/foo` and
`/Foo` are genuinely different directories — folding them onto one
permission key would let a session from one inherit the other's
`--allow-all-paths` grant purely because of a spelling collision — a
cross-directory permission leak that `norm_path`'s own intended use never
had to consider (a MATCHING miss there just falls back to "newest session
wins", low-stakes). **Fixed with a key function scoped to the permission store**
(`posture_key`, structurally distinct from `norm_path` so the two can never
be conflated again by a future edit): case-folding happens ONLY under
`cfg(windows)`; everywhere else the key is exact-match, so a case-differing
path simply fails to match and resolves to `None` — fails safe on every
platform under one rule, with no platform branching in any CALLER. The
underlying logic lives in `posture_key_for(s, windows: bool)`, taking the
platform as a parameter specifically so BOTH branches are directly
unit-testable from any single host (this fix was authored and verified
entirely on Windows) — `posture_key_never_folds_two_distinct_directories_
into_one_on_a_case_sensitive_platform` exercises both, mutation-verified
against the case-folding-everywhere design.

**The watcher gap, closed the same way for every restore path.** Independent
of the flags themselves, NONE of the restore paths previously started the
fail-soft dialog-answering watcher (`confirmSoloCopilotAutopilot`) a fresh
launch gets — only `spawnAgentPanes`/`startFromWelcome` called
`watchCopilotAutopilotIfNeeded`. A restored kickoff is trusted no
differently than a fresh one (the same stance #364 already took for the
group path's `Delivery::ResumeKickoff`), so the watcher is now wired into
all four sites that can (re)open a copilot pane: the Sessions-tab restore
(`restoreSession`'s plain-session branch) and all three `panerestore.ts`
actions (`resume-agent`, `fresh-agent`, and `dormant-agent`'s Start click).
The three `panerestore.ts` sites share one gate, `shouldWatchCopilotOnRestore`
(review NB1 — the original cut inlined the same check three times, and
asymmetrically: it derived "is this copilot" from BOTH `command` and `argv`
via `programFromRestore`, but checked `--autopilot` against the string
`command` only, which would silently skip the watcher for a hypothetical
argv-only copilot autopilot pane). `shouldWatchCopilotOnRestore` scans both
representations for `--autopilot`, the same shape `hasForkSession` already
uses for `--fork-session` above, and is the single source the three call
sites share. `programFromRestore` itself stays a minimal, single-purpose
"what CLI does this command invoke" lookup — narrower than the fuller shared
CLI-derivation #452 asks for, a deliberate scope call for this PR, not a
design stance that the two should stay separate; #452 has a note that a
third derivation now exists to converge when that broader work happens.
Every site also checks that the restored command actually contains
`--autopilot`, so the watcher never spins up its up-to-10-minute poll for a
pane that could not possibly show the dialog it exists to answer.

**Review round 2 (rev-6 close-out), the last unpinned corner: a store the
code cannot parse.** `load_copilot_posture` already degraded a missing,
corrupt, or wrong-shape store file to an EMPTY store — never a crash, never
a stale grant — via the same `uistate::load_or_quarantine` + atomic
`serde_json::from_str` this file's other stores use. rev-6 verified this by
hand (a scratch test against a fresh store, a corrupt file, a
valid-JSON-but-wrong-shape file — including a leftover file from this
module's OWN pre-B1-fix schema, the concrete case a real upgrading user
hits — and an unrecognized `posture` enum variant, all resolving to no
flags) but nothing shipped pinned it: a future edit adding lenient
per-entry recovery, or a new `CopilotPosture` variant resolved by a
catch-all arm, could silently reopen exactly the grant path B1 closed, with
nothing to fail. `any_unparseable_or_malformed_store_state_grants_nothing`
lifts that scratch test's shape and generalizes it to the invariant —
several distinct failure classes, several cwds each — mutation-verified
against a lenient-per-entry-salvage regression that defaults a
missing/unrecognized posture to `True`.

### #458 — the copilot resume command used the wrong flag syntax

**Root cause.** Every `resume_command` `scan_copilot` synthesized (both the
bare and the autopilot-flag-carrying branches from #456 above) joined
`--resume` and the session id with a space: `copilot --resume <id>`. Copilot's
own CLI reference documents the flag as **optional-value** —
`` `-r`, `--resume[=VALUE]` `` — and its own generated hint after a `-p`
run spells the unambiguous form the same way: "The exit summary includes a
`copilot --resume=SESSION-ID` hint for continuing the session." (raw-fetched:
`curl -sL https://docs.github.com/api/article/body?pathname=/en/copilot/reference/copilot-cli-reference/cli-command-reference`,
grepped for `--resume`, per the `agent-cli-reference` skill's no-WebFetch
rule — see #453). The reference never shows `--resume <id>` as a literal
invocation syntax (one unrelated prose line pairs `--remote` with
`--resume <TASK-ID>` informally, describing the concept, not demonstrating
the parse). Bare `--resume` (no value) is separately documented to open an
interactive picker (needs a TTY) or, where no TTY is available for one, exit
with an error — never to silently start or attach to the wrong session on
its own. Whether today's underlying arg parser actually mis-reads the space
form as bare-flag-plus-positional is therefore **UNVERIFIED, not
confirmed** — CLAUDE.md constraint 3 rules out spawning a real `copilot` to
settle it empirically, and the docs don't say either way. This fix is
"remove a latent, plausible risk for free," not "confirmed and fixed a live
bug," and is stated that way rather than overclaiming a repro that was never
observed.

**The fix.** Both `scan_copilot` branches now join with `=`:
`copilot --resume=<id>` and `copilot --resume=<id> <AUTOPILOT_FLAGS>`. This
is a pure syntax change — the #456 posture-lookup and ambiguity-resolution
logic above is untouched, and Claude's `claude --resume <id>` is untouched
too: Claude's own CLI reference documents `--resume` as a **required**-value
flag (`claude --resume abc123 --fork-session`, `claude --resume
auth-refactor` — space form, no bracket-optional notation), so there is no
analogous risk on that path.

**This fix's `panerestore.ts` reads are safe, but scoped to
`scan_copilot`'s own emission — it does not close every copilot
`--resume` emission path (rev-11, PR #473 review).** The frontend
token-scanners that read a resumed command back out (`programFromRestore`,
`shouldWatchCopilotOnRestore`, the session-id extractor) already branch on
both `t === "--resume"` (space form, next token is the value) and
`t.startsWith("--resume=")` (the `=` form, one token) — they were written
defensively for exactly this kind of CLI-syntax variance, so *reading*
either form needed no frontend change.

**The residual: a copilot session resumed via the Sessions sidebar gets its
id captured for the NEXT app boot (`main.ts`, #440 D1c) as an ordinary
`paneKind: "agent"` pane. On that next boot, `resume-agent` calls
`agentResumeCommand` (`panerestore.ts`), which unconditionally strips any
recorded `--session-id`/`--resume` (either form) and re-appends the literal
tokens `"--resume", sessionId` — the space form, unconditionally, for
whatever CLI the command line happens to be.** `agentResumeCommand`'s own
doc comment says "Only Claude has a clean resumable id... so this rewrites a
`claude …` line," but the code has no CLI check — it runs the same rewrite
on a copilot command line just as readily. So this PR's fix holds for a
copilot session's FIRST restore (`scan_copilot`'s own emission, from the
Sessions browser) but a copilot session resumed a SECOND time — once
loomux's own tab-restore captured it as an agent pane — goes back through
`agentResumeCommand` and comes out in the space form this PR removed.
**Not fixed here**: `agentResumeCommand` becoming CLI-aware (or emitting the
`=` form unconditionally, which would need its own doc-reference check the
way this PR's `scan_copilot` change did) is tracked under **#471/#457**, the
restore-path-unification work already named earlier in this document, and
is deliberately left to that unified builder rather than duplicated here.

**Pin.** `scan_copilot_restores_autopilot_flags_only_when_unambiguous`
(`sessions.rs`) now asserts, for every session `scan_copilot` produces
regardless of which posture branch built it, that `resume_command` contains
`"--resume="` and never contains `"--resume "` — a future edit reverting
`scan_copilot`'s OWN emission to the space form fails this test immediately.
It does not and cannot pin `agentResumeCommand`'s separate emission, above.

### #457 — generalizing #456's launch-intent store to claude, and correcting the issue's own premise

**The premise #457 was filed on is wrong, and the record should say so
plainly rather than let the next reader generalize the wrong lesson.** The
issue frames the pattern as "restore replays a recorded command string
instead of re-deriving launch flags" and names that replay as the
anti-pattern across all three restore entry points. It isn't, for the entry
point that actually does it: `panerestore.ts`'s tab-restore actions
(`resume-agent`/`fresh-agent`/`dormant-agent`) replay loomux's OWN
`PersistedPane.command`, captured verbatim at launch — every flag baked into
that string, including autopilot, survives forward by construction, which is
exactly why #439 (MCP re-mint) and #449/#471/#458 (session-flag rotation)
were the only surgery that path ever needed. **The actual anti-pattern —
the one #456's own investigation named — is narrower: `scan_claude`/
`scan_copilot` RECONSTRUCTING a resume command from the CLI VENDOR'S OWN
session files**, which structurally cannot know what loomux originally
launched with, because that information never lived there. Replaying a
loomux-recorded command is the safe path; reconstructing from a foreign
source is the one that keeps losing flags, once per flag, forever, unless
something reads loomux's own record instead.

**A new, previously-unidentified instance of the same class: `scan_claude`
carried NO launch-intent record at all.** Every Sessions-tab resume of a
claude session emitted a bare `claude --resume <id>` unconditionally — not
"one flag lost" the way #456 diagnosed for copilot's autopilot posture, but
every flag, always, for every claude session ever resumed from that tab.
This was never filed as its own bug; it surfaced only while reading
`scan_claude` end to end to design #457's fix.

**The fix generalizes #456's `copilot-posture.json` into a two-key
`launch-intent.json`, in place, rather than building a second parallel
store.** The value shape (`Posture: True | False | Conflicted`) and the
sticky-at-write-time, LRU-whole-entry-eviction machinery are lifted
verbatim — this section is not re-litigating #456's B1/B2 findings, both
still hold, now for both keys. What's new is the key:

- **Claude solo panes key by `IntentKey::Session { id }`** — the session id
  `launcher.ts` already mints before launch, so the record is exact, no cwd
  approximation needed. Because a session id is unique by construction (no
  code path mints the same id for two different launches), **a
  `Session`-keyed entry can never become `Conflicted`** — pinned by
  `session_keyed_entries_are_never_conflicted` (a disagreeing repeat write
  for the same id, which should never happen in practice, resolves to the
  latest value, never to `None`, proving there is no ambiguous state this
  key shape can reach). This is strictly better than copilot's situation and
  **retires, for the claude case specifically, the eviction-ambiguity
  residual** the #456 section above named as the structural floor of any
  capped, cwd-keyed store — that residual is a property of cwd-keying, and
  claude no longer cwd-keys.
- **Copilot solo panes still key by `IntentKey::Cwd { cli, cwd }`** —
  unchanged from #456, for the unchanged reason: copilot never hands loomux
  a session id at launch. Precise per-session keying for copilot solo
  remains a further follow-up, not attempted here — it needs the same class
  of watcher machinery (`spawn_copilot_session_watcher`) #456 already
  deferred for the group-agent case.

**This is a genuine, deliberate WIDENING of what a claude restore can grant
— stated here so a reviewer weighs it, not discovers it.** Before this PR, a
Sessions-tab claude resume carried zero flags, unconditionally; after it, a
claude session CAN carry autopilot flags, where — and only where — loomux
itself recorded that it should. The same rule #456 established for copilot
governs claude identically: flags only from a recorded intent, never by
inference, never by default. A session with no recorded intent — foreign
(never launched by loomux at all), pre-upgrade (existed before this PR, so
no id-keyed record could ever have been written for it), or evicted —
resolves to nothing, exactly like an unrecorded copilot cwd. Pinned
end-to-end (not just at the lookup helper) by
`scan_claude_grants_nothing_to_a_session_with_no_recorded_intent` and, for
the positive case, `scan_claude_restores_autopilot_flags_only_when_recorded`
— the claude-side counterpart of #456's own `scan_copilot_restores_
autopilot_flags_only_when_unambiguous`.

**Soft migration, not a cold reset.** A cold reset — start `launch-intent.json`
empty and ignore any pre-#457 `copilot-posture.json` on disk — would still be
*safe* under the ambiguity rule (no record resolves to no flags, the smaller
grant), but it would silently re-inflict the exact annoyance #456 was filed
to fix ("I have to toggle autopilot manually, per folder") on the very
release that fixes it, for every existing user, once. `load_launch_intent`
instead reads the legacy file, read-only, when-and-only-when the new file has
never been written on this machine (existence-gated, not
parseability-gated — a CURRENT corrupt `launch-intent.json` degrades to
empty and is never rescued from a possibly-stale legacy file; pinned by
`a_corrupt_new_store_never_falls_back_to_the_legacy_file`). The very next
write lands on the new path and carries the migrated entries forward, so the
legacy file is read at most once per machine
(`soft_migration_reads_legacy_copilot_posture_file_when_new_store_is_absent`).

**Fixing `scan_claude`'s own test seam.** Writing this PR's claude-side pin
surfaced a second, unrelated pre-existing gap: `scan_claude` built its
projects root inline via `dirs::home_dir()` rather than the testable
`claude_projects_root()` helper `find_claude_session_cwd` already used, so
`set_claude_projects_root_for_test` silently had no effect on it — the new
`scan_claude_*` tests failed by scanning the real machine's `~/.claude`
directory instead of the fixture, not by a real behavior bug. Routed through
the shared helper; behavior-preserving on the default (no-override) path,
since both resolve to the identical `dirs::home_dir().join(".claude").join
("projects")` when no test override is set.

**CLI-name detection, converged (closing #452's concrete named instance).**
`programFromRestore` (`panerestore.ts`), `Pane.agentCli` (`pane.ts`), and
`main.ts`'s D2 dormant-resume-candidate sniff were three independent copies
of the same "first token, lowercased, exact-match `claude`/`copilot`"
derivation — and identically incomplete: a path-qualified command
(`C:\tools\copilot.exe`) or an `.exe`/`.cmd`/`.bat`-suffixed one matched
neither literal, so every per-CLI restore behavior gated on it (the
autopilot watcher, the resume-candidate card, `agentCli` itself) silently
did not apply, with no error. All three now call one new
`normalizeAgentProgram` (`panerestore.ts`), which strips a directory prefix
and a trailing executable extension before lowercasing. This is **not** the
full #452 convergence — the value/quoting grammar (`QUOTED_OR_BARE_VALUE`)
is a different axis, already converged per #471; the D2 card's own
`.command`-vs-`.argv` extraction step and the launcher's `plan.command`
probe are untouched; this only converges what happens to an
already-extracted raw token. Pinned by
`programFromRestore recognizes an .exe-suffixed command` /
`recognizes a path-qualified command` and
`normalizeAgentProgram: bare name, path-qualified, and .exe/.cmd/.bat
suffixed all converge` (`test/panerestore.test.ts`) — the first pair
red-before-green verified against the pre-fix literal-comparison logic.

**Deliberately left open, named rather than silently skipped, per the
design-intake reply that scoped this PR:**

- **The Rust orchestration builder's latent copilot-resume space-form arms**
  (`build_agent_command`/`build_agent_argv`, `orchestration/mod.rs`
  ~18499/~18700) are a different architecture entirely — group agents
  already re-derive their launch command from structured group state
  (persona, session, resume, auto_ops) every time, never a replayed string,
  so they are not an instance of THIS issue's pattern, just a separately
  latent risk in already-correct code. Left with a breadcrumb comment at
  both arms pointing at this section, not folded into the launch-intent
  store — unifying a TypeScript solo-pane builder and a Rust group-agent
  builder across that architecture boundary is a larger, separable PR.
- **Full #452 convergence** (a single shared CLI-derivation type/module,
  covering the D2 card's own extraction step and the launcher's probe) is
  future work — this PR converges only the one concrete failure named above.
- **MCP/channel-identity is not re-minted for Sessions-tab restores.** A
  session resumed from the Sessions tab still gets no `--mcp-config`/channel
  identity, same as before this PR — the existing "Connect" adopt-later flow
  (`orch_solo_adopt`) is the sanctioned manual path for that, and extending
  automatic re-mint to a third entry point (beside `resume-agent`/
  `fresh-agent`) is a separable change.
- **Copilot solo session ids are still never learned at spawn**, so copilot
  stays cwd-keyed — the same residual #456 already documented, still points
  at future work, not resolved here.
- **The launch-intent value stays `autopilot: Posture` only** — not widened
  to also carry channel-tools/model/other future per-CLI semantics. Those
  either don't need persisting (MCP identity is deliberately re-minted fresh
  every restore, never replayed — #442) or don't have a second instance yet
  to generalize from; widening the store ahead of a second real need would
  be speculative generality this PR doesn't have evidence for.

### #479 — restore UX: click feedback, an unmistakable error state, and where the latency actually was

Two complaints about the same screen: clicking **Resume group** on an
orchestrator agent session had a visible lag with nothing on screen to show
the click had registered, and the dormant-agent **Start** card ("no
resumable session") was visually just another neutral dormant card — no
more alarming-looking than "Resume group" waiting for a click, even though
one of them means something is actually wrong.

**Where the latency was — measured, not guessed.** `resume_recorded_session`
(`orchestration/mod.rs`) looked up which group/role a session id belongs to
by calling `session_roles()` unconditionally — a scan of **every** group
ever created on this machine, live or long dead: each one's `group.json` and
`tasks.json` read and parsed, plus its **full audit log** (`records_from_
audit`) read and every line parsed, just to throw away every row but the one
actually being resumed. The dormant-group Resume button always already knows
which group it's resuming (`hint: (group_id, role)`, threaded through since
#412) — that hint went unused for this lookup, so a resume click's latency
scaled with the total history on the machine, not with the one group being
restored. `session_role_in_group` (new, `orchestration/mod.rs`) reads and
merges only the hinted group; a miss (a stale/wrong hint) falls through to
the unchanged full scan.

Measured in `resume_recorded_session_group_hint_avoids_scanning_every_
other_group` (`tests/orchestration.rs`, 200 decoy groups × 300 audit lines
each, red-before-green against the fast path disabled): **419ms → 42ms** on
one dev machine, debug build. **Three caveats on this number, all raised by
review and all real (correcting this doc's own first draft):**

- **The test asserts a same-run relative comparison, not that specific
  figure.** Its first version asserted a fixed `< 200ms` bound — which CI
  itself then falsified at 211ms, on a build where the fast path was
  otherwise genuinely working, simply because that runner was slower/
  noisier than the dev machine the bound was picked against. Fixed bounds
  against wall-clock time are exactly this fragile under CI hardware
  variance. The assertion now compares the timed call against a bare
  `session_roles()` baseline measured on the SAME run, immediately before
  it: CI being N times slower scales both sides roughly together, so the
  ratio (currently asserted at "under half the baseline," observed at
  roughly 8-10x on a dev machine) stays meaningful even though neither
  absolute number does.

- **The axis measured is "many groups, each modest," not "few groups, one
  huge."** This fast path still reads and parses the HINTED group's OWN full
  audit log (`merged_records` → `records_from_audit`, both rotation
  generations, bounded at ~16 MB by the 8 MB rotate cap) — it eliminates the
  O(other groups) term, not the resumed group's own read. A machine with a
  handful of long-lived groups and a near-cap audit log on the one being
  resumed will not see anything like 42ms; it will see whatever that one
  group's own parse costs, same as before this PR. What's actually fixed for
  every machine, regardless of which axis it sits on: a resume click no
  longer pays for groups it isn't touching.
- **A correct hint is NOT proven equivalent to the full scan — it is a
  different, and only usually-agreeing, tie-break.** When a session id has
  an `agent-spawn` audit row in more than one group, this fast path resolves
  to the HINTED group; the full scan's `.last()` resolves to whichever group
  `fs::read_dir` happened to enumerate last (arbitrary iteration order, not
  a considered choice either). The two can disagree. This is not
  hypothetical: **#485** (found on this same batch's #481) is exactly this
  shape — a delegate rejoined into the wrong group writes its `agent-spawn`
  row into that group too, so the same session id now has a row in both. Do
  not read this fast path as a proof of sameness; it's a deliberate,
  arguably more defensible choice (the hinted group is the one the clicked
  tab is actually bound to) that happens to coincide with the full scan
  outside that corner. #485 has since closed the way NEW two-group rows get
  written (see below) — but rows written before that fix are still on disk,
  so the corner remains reachable for existing data and the two are still
  not provably equivalent. Neither this PR nor #485 makes them so.

CLI boot time itself (the other component the issue calls out) is not
loomux's to remove or measure — never spawn a real agent CLI to benchmark it
(CLAUDE.md hard constraint 3); the fix here is scoped to the part loomux
actually controls.

**Feedback and the error state are one component, not two.** `restorecard.ts`
(new) is a small, DOM-free state machine — `idle --click--> pending`,
`pending --fail--> error`, `error --click--> pending` (retry), `* --settle-->
idle` — unit-tested in `test/restorecard.test.ts`. `main.ts`'s `dormantCard`
wires it to the actual card DOM:

- A click is acknowledged **immediately**: the button disables and a spinner
  shows the instant `nextRestoreCardState` returns `pending`, before the
  underlying `onClick` (which does the real work — session lookup, MCP mint,
  PTY spawn, CLI boot) has resolved at all. A second click while pending is a
  no-op (the transition table returns the SAME state object), generalizing
  the #194 P4 MED-3 double-spawn guard past its original single call site.
- A failure **always** lands on the error state — red accent, a warning
  icon, a heading that says so (e.g. "Couldn't resume this group") — never a
  spinner that quietly clears back to looking like an untouched card. The
  diagnostic message (what `resumeDormantGroup`/`startFromDormant` actually
  threw) rides into the card's body text unchanged — the #440 lesson
  generalized: diagnostic detail is what makes a wrongly-unresumable session
  diagnosable, so it's never traded away for a cleaner-looking card.
- The dormant-agent **Start** card mounts directly in the error state
  (`errorRestoreCardState`) — it doesn't need a failed click to discover it
  has nothing to resume, it already knows that at render time. `resumeDormant
  Group`'s call sites were also reclassified: "no binding to resume from" /
  "nothing captured" redirect to the session browser and settle back to idle
  (nothing wrong with *this* card, the human's focus just moved), but "this
  group's orchestrator session has no saved conversation" and a thrown
  `resumeOrchSession` failure now return `{ok: false, message}` and land on
  the error state — that IS a "no resumable session" outcome for this card's
  own action, not a redirect.

Both halves share the same `RestoreCardResult` (`{ok: true} | {ok: false,
message: string}`) return shape from every dormant-card `onClick`, including
`startFromDormant`'s call site, which previously had **no** error handling
at all (an uncaught rejection on a rare spawn failure) — now caught and
surfaced through the same contract. **Narrowing an over-broad first draft of
this sentence (review round):** this covers every `dormantCard` PRIMARY
action (Resume group, Start); the separate #440 D2 "Resume last session"
secondary button (`addDormantCardAction`) is a plain button outside this
state machine entirely, unchanged by this PR — a failure there still falls
back to the pre-#479 uncaught-rejection-reaches-the-global-banner behavior.
Not a regression (that was already the status quo for it), but also not
"surfaced the same way" as the primary action, and folding it into the same
state machine — two buttons on one card, one pending/error visual — is a
separate, non-trivial design question this PR doesn't take on.

**Review round: two wiring gaps in the mechanism the paragraphs above
describe, both closed.** The transition table itself (`restorecard.ts`) was
green throughout because neither gap was reachable FROM the table — the
table says "fail carries the message"; the wiring simply never called `fail`
in these two cases, or called it into a dead node. Per CLAUDE.md, DOM wiring
is hand-validated, not simulated in tests, so both had to be closed by
construction:

1. **`dormantCard`'s `opts.onClick().then(...)` had no rejection handler.**
   A throw anywhere in `resumeDormantGroup` outside its two `resumeOrchSession`
   try/catches (the grid traversal, `closePane` loop, `persistTabs`, `sessions.
   toggle`) left the card at "pending" — spinner spinning, button disabled —
   **forever**. This is the DoD's named anti-goal in as many words. Fixed by
   moving the call itself behind `Promise.resolve().then(() => opts.onClick())`
   (so even a synchronous throw from a future non-async `onClick` is covered)
   and giving `.then` a second (rejection) handler that dispatches `fail` —
   structural, not a discipline each `onClick` has to remember.
2. **`startFromDormant` (`pane.ts`) removed the placeholder element BEFORE
   awaiting `start()`.** A failure in the caller's OWN post-spawn wiring
   (`remint.bind`, `onGridChanged`) — which happens strictly after that
   await resolves — rendered its error card into an element already gone
   from the document: invisible, and a regression against the pre-PR
   behavior, where that same throw escaped as an uncaught rejection and hit
   the visible global banner. Fixed by deferring the element's removal to a
   `finally` around `start()`, while keeping the `isDormant`-flipping field
   assignment (`this.dormantEl = null`) exactly where it was — widening
   THAT window would let the #440 D2 background prefetch add a second action
   button while a Start is still in flight, a race this fix must not trade
   the other one for. `dormantCard`'s `render()` also grew a
   `!wrap.isConnected` fallback to a toast, as a backstop for any FUTURE
   teardown-then-fail ordering this same class of bug could reintroduce
   elsewhere, not only these two named instances.

**Enumeration of every path out of `pending`, done once rather than trusted
to have been done** (the request behind fixing the class, not just the two
named instances): `pending` is entered only via a click, and left only by
`dormantCard`'s own `.then(onOk, onErr)` pair now that finding 1 is fixed —
there is no third exit. That pair fires on exactly the three ways a Promise
settles: resolves `{ok: true}` → `settle` → idle (card usually torn down by
the caller's own success path first, which is fine — an idle render on an
already-detached element is inert, not silent, because there was nothing
left to report); resolves `{ok: false, message}` → `fail` → error, rendered
into whatever `wrap.isConnected` says at that moment (visible card, or the
toast fallback); rejects for ANY reason → `fail` → same as above. A
synchronous throw from `onClick` before its first `await` is covered by the
`Promise.resolve().then(...)` wrapping. That accounts for every path — the
two the reviewer named were both instances of the THIRD bullet (a rejection)
combined with either no handler (finding 1) or a detached target (finding
2), not additional exits from the state machine itself.

**A residual gap, stated rather than implied away:** the toast fallback is
not a full substitute for the card — a toast carries no retry button, so a
failure that reaches it doesn't hand the human an inline "try again" the way
a still-visible error card does. Concretely, for the dormant-agent Start
card: `pane.ts`'s ordering fix keeps the placeholder mounted through
`this.start()` itself, but `main.ts`'s `onClick` still does `remint.bind` and
`onGridChanged()` AFTER `await pane.startFromDormant(...)` returns — by
which point `startFromDormant`'s own `finally` has already torn the
placeholder down, since `start()` already settled. A throw from either of
those two calls therefore still lands on the toast path, not the visible
card. This is the residual case fix 2's ordering change does not itself
close — fix 1's `!wrap.isConnected` fallback is what keeps it from being
silent. Stated plainly rather than glossed: that toast fires only once
`start()` itself has already resolved successfully, i.e. the pane is
already LIVE (a real PTY is running) and what failed is bookkeeping after
the fact — `onGridChanged` is `tabs.notifyLayoutChanged()`, not anything the
pane's liveness depends on. So the "no inline retry" gap exists only on a
path where there is nothing left to retry; it does not reach a genuinely
stranded pane.

### #485 — two groups in one tab: each restores its own, or fails loudly

A tab can hold panes belonging to **two different orchestration groups**.
That state is not exotic: `restoreSession`'s `owning ?? tabs.activeWorkspace`
fallback has always been able to bind a restored group into whatever tab was
active, and #481 (fixing #478) makes it reachable from the *primary* gesture —
split an orchestrator tab, pick "Orchestrator", and the new group is bound to
the tab you split. The persistence and resume layer could not represent it:

- `tabs.snapshot()` stored **one** `groupId` per tab (`groupForWorkspace`,
  a first-match over the binding map).
- `resumeDormantGroup` swept **every** dormant orch placeholder in the tab
  into one plan, taking the group from the TAB.
- `planGroupResume` kept **one** orchestrator and rejoined **every** delegate
  into that single group.

So one click on a two-group tab resumed group A, dropped group B's
orchestrator **with no message of any kind**, rejoined B's delegates toward
A, and then cleared every dormant card — leaving a tab that looked fully
restored with one group silently missing from it. The silence is the defect;
a visible failure would have been a bad restore, this was an invisible one.

**The rule this establishes: a session's group is a property of the SESSION,
never of the tab it sits in.** Three layers now say so, and the middle one is
the only one that could be called defence in depth — the outer two are each
load-bearing on their own:

1. **The record carries it.** `PersistedPane.groupId` (new, `tabstore.ts`) is
   captured for every "orch" pane from `Pane.capture()`'s own `orchGroup`,
   and rides into `panerestore.ts`'s `dormant-group` action. Absent in a
   pre-#485 snapshot → `null`, which means "this placeholder doesn't know its
   group", never a group named `""`.
2. **The plan refuses to cross groups.** `planGroupResume(members, resumable,
   group)` puts any member whose record names a *different* group into a new
   `foreign` bucket — it cannot reach `rejoin`, so no downstream confusion can
   turn it into a rejoin. `partitionByGroup` (same module) is the one rule
   used both to pick a click's members and to pick which placeholders that
   click may clear, so those two can't drift apart.
3. **The join point enforces it.** `resume_recorded_session`
   (`orchestration/mod.rs`) refuses outright — `resume-group-mismatch:`, the
   same tagged-error contract `resumeerror.ts` already parses — when the
   caller's group hint disagrees with the group the session's own record
   names. Every rejoin in loomux funnels through this function, so this is
   what makes a wrong-group rejoin unreachable rather than merely avoided by a
   correct frontend.

   **Scope of that claim, narrowly (review finding 1 on the PR).** The check
   compares the caller's hint against a *recorded* membership, so it covers
   exactly the sessions that have one — a roster row or an audit line in some
   group. A session with **no** recording anywhere reaches the signature-only
   fallback, which builds its record *from the hint itself*, making the
   comparison vacuous by construction: the caller's claim would be the only
   evidence. That was a real remaining route into the wrong group — a pre-#485
   snapshot whose tab-derived hint names group A while the placeholder is
   really group B's **pre-roster** worker, with B's own orchestrator pane
   closed before exit (so the `ambiguous` check doesn't fire either). It is a
   nearly-extinct population, and it was reachable, which is what matters for
   a claim of impossibility.

   So the fallback is now split by what the operation actually *is*:

   - **Orchestrator** — reopening the control plane of a group whose
     `group.json` is on disk is not a membership operation. The group's
     identity comes from that file and no other group's roster is touched, so
     the fallback survives (pinned by
     `hint_restores_sessions_unknown_to_roster_and_audit`).
   - **Delegate** — "rejoin into group X" *writes membership into X*. With
     nothing to verify against, that is refused with its own tag,
     `resume-group-unknown:` ("cannot be verified" is a different fact from
     "contradicted", and deserves different copy and a different next step).

   The cost is real, deliberate, and **terminal for that class** — this is the
   part the first version of these notes got wrong (review round 2). It said
   the human could "still reach that session from the session browser", which
   is circular: `SessionsPanel.roleFor` falls back to the transcript-signature
   classification (`orch_role`/`orch_group` off the scanner), so a pre-roster
   delegate still shows an orch chip, clicking it hints the same group, and it
   lands back on the same refusal. The browser has exactly one action per row
   (`item.addEventListener("click", …onRestore)`) — there is no "open it
   plainly" affordance to fall through to — and start-fresh is not an escape
   either, since a fresh spawn would join the very group that could not be
   verified. A wrong escape hatch in an error message is worse than none: it
   sends the human in a circle and reads as though the door exists.

   What is actually reachable, and what the copy now says in all of its
   places:

   - **No in-app rejoin.** Nothing puts this session back into a group. That
     is the refusal working, not a gap to route around.
   - **The conversation is not lost.** It reopens *outside* orchestration via
     the CLI's own resume command — the session row's tooltip already shows it
     (`item.title = s.resume_command`) — as a plain pane with no group
     membership, which is precisely the thing that could not be verified.
   - **The work continues** by the orchestrator spawning a fresh agent: a new
     session in a group that vouches for it, not a recovery of this one.

   Between the two arms of the fallback, **no delegate rejoin proceeds on a
   group id only the caller vouches for**; that is the exact claim, and it is
   the one the code makes.

Why refuse at (3) rather than silently proceed with the record's own group,
which would already put the agent in the right place? Because the caller acts
on its own belief afterwards — it binds panes, routing and badges to the group
it *asked* for. A disagreement resolved in silence still files the agent's
pane under the wrong group in the UI. Two ids disagreeing means the caller's
model is wrong, and the only safe move is to say so where the human clicked.
`group-mismatch` deliberately does **not** offer "start fresh": a fresh
session would be spawned into that same wrong group, which is the
contamination the refusal exists to prevent.

**What is loud, and where.** Each group in the tab keeps its own dormant
card, and each card resumes its own group — so a group that cannot come back
fails on *its own* card (`restorecard.ts`'s error state, #479), while the
other group restores normally beside it. Nothing sweeps another group's card
away; the second group's absence can no longer be mistaken for success.

**The pre-#485 snapshot corner, and why it now fails instead of guessing.**
An old snapshot records no per-pane group, so two orchestrator placeholders in
one tab are indistinguishable from one group with a duplicate record. The old
code preferred whichever was resumable — i.e. exactly the silent drop. The
plan now reports `ambiguous` for that set and the click fails with a message
pointing at the session browser, where each session's real group IS known.
This flips one prior test's expectation on purpose ("with duplicate
orchestrator records, a resumable one wins" is now scoped to records that both
NAME the same group): a legible refusal on a rare genuine duplicate is a much
better trade than a silent wrong-group restore on a common two-group tab.

**Tab bindings are a set now.** `PersistedTab.groupIds` (new) carries every
group bound to a tab; `groupId` is still written as `groupIds[0]` so an older
build reads a binding rather than nothing, and a pre-#485 file decodes as
`[groupId]`. Restore binds all of them (`main.ts`), so the second group's
rejoined panes route back into the tab they were closed in instead of into a
freshly minted background tab. `TabManager.groupForWorkspace` survives for the
"is this an orchestration tab" questions (tab badge, close guard) with a doc
comment saying what it must not be used for; `groupsForWorkspace` is the one
to act on.

**What this does NOT undo.** A session that already has a roster/audit row in
a second group — residue a pre-#485 wrong-group rejoin left on disk — still
resolves through `session_role_in_group`'s hinted-group fast path, agrees with
itself, and passes the check. This closes the way new contamination is
created; it does not clean up old contamination, and nothing in the code or
these notes should be read as claiming it does. That is a claim about stale
*data*, and it is the only gap left in this area: the two ways a *live* call
could name the wrong group — a contradicted hint and an unverifiable one — are
both refused above.

**Where the coverage boundary sits.** The decision layers are unit/integration
tested end to end (the partition, the plan, the schema round-trip, the join
point, and the two refusals). What no test here touches is the DOM wiring, per
this repo's convention: two Resume cards rendering side by side on one tab,
the `ambiguous`/`group-mismatch` copy landing on the right card's error state,
and per-group card clearing in a live grid. Exercising those needs a real
window and real agent CLIs (hard constraint 3), so they are left to the
human's own validation rather than approximated with a simulated DOM.

### #781 — the Sessions tab routed orchestration restores by CLI, not by membership

**Symptom (human report, beta8, work PC on copilot 1.0.77).** Manually
restoring an orchestrator session from the Sessions tab "only restores the
session itself, not the entire orchestration setup" — the resumed agent hit
permission prompts, including MCP, and looked like it was running with autopilot
alone.

**Root cause.** `restoreSession` (`main.ts`) chose its route with
`s.source === "claude" ? sessions.roleFor(s) : undefined`. Written when copilot
session ids were not tracked at all, that gate was correct then and was never
re-derived when `spawn_copilot_session_watcher` began recording them — for
delegates *and* for the orchestrator ("Track the copilot session this
orchestrator just minted"). So a copilot session with a perfectly good roster
row could never take the group-rejoin branch. It restored through
`build_resume_command` instead: `copilot --resume=<id>` plus, at most, the
recorded autopilot posture. No `--additional-mcp-config`, no `--add-dir` for the
group dir or the workdir, no `--model`, no persona, no containment denies, no
group binding.

The session browser meanwhile rendered that row's `ORCH` chip and its "click to
restore the whole orchestration" tooltip, and `docs/orchestration.md` promised
the same. The UI's claim and the code disagreed, and the UI was right.

**Why it read as "autopilot only" rather than "broken".** Per copilot's
changelog (1.0.76, 2026-07-29), *"Resuming a session now restores its autopilot
or plan mode instead of reverting to interactive"*. A bare `copilot --resume`
therefore comes back **in autopilot mode** on any current copilot, so the pane
presents as a healthy unattended agent while carrying none of the group's
wiring — the flags the human went looking for were genuinely absent, but the
mode they expected them to produce was there anyway.

**Fix.** The route is a pure module, `sessionroute.ts`, and its rule is recorded
membership alone: a session rejoins its group iff loomux has a record that it
belonged to one, whatever CLI wrote it. `main.ts` executes the returned route
and no longer computes one. The rule is unit-tested
(`test/sessionroute.test.ts`) across both CLIs, which is the regression pin —
the failure mode here was not a wrong rule but a *stale* one, and the cheapest
guard against a second staleness is a test that names the CLI-independence
explicitly.

**Two claims from #458's section above are now out of date, and are corrected
here rather than edited into that dated record.** First, its residual —
`agentResumeCommand` re-emitting the space form on a *second* restore — was
closed by the restore-path work it was tracked under: `panerestore.ts` branches
on `programFromRestore(...) === "copilot"` and emits `--resume=<id>` for both
the string and argv forms, with `test/panerestore.test.ts` pinning it and the
function's own doc naming the oscillation hazard (two fixes undoing each other
forever) as the reason. Second, that section labelled the space form's actual
mis-parse **UNVERIFIED**, which is still the right label and is the one this
change keeps: see the builder comment for what the reference does and does not
say. `--session-id` deliberately stays space-form on both paths, because the
reference documents *that* flag in the space form specifically.

**What is deliberately NOT changed.** `build_resume_command` stays exactly as
it is. It is the right command for a session with no recorded membership, which
is what such a session honestly is; the bug was never that it built a poor
command, but that sessions which had a better one available were routed to it.

**Residual, stated rather than assumed.** A copilot orchestration session whose
id the watcher never captured (it times out — `copilot-session-untracked`) has
no roster row, so it shows no chip and restores plain. Claude has a second
route for exactly that case, a loomux-signature scan of its own transcript
(`scan_claude_jsonl` → `detect_orch_signature`); copilot has no equivalent
because it stores no transcript beside the session. `session-state/<id>/` holds
`workspace.yaml`, `checkpoints/`, `files/` and `research/` — the conversation
itself lives in `~/.copilot/session-store.db`, a SQLite file loomux will not
take a dependency on to read. So that class of session is unrecoverable *into a
group* on copilot today, and the row does not pretend otherwise: no chip, no
promise, a plain pane.

**Flag-spelling re-verification (secondary, #781's original hypothesis).**
`--allow-all-tools` and `--allow-all-paths` were re-checked against copilot
1.0.77's reference and have not been renamed or deprecated; the citations now
sit on `COPILOT_UNATTENDED_FLAGS`. One documented limit is recorded there too,
because a work machine is where it bites: the *Permissive options* section
states that on a Copilot Business or Enterprise license "these commands may be
blocked by an enterprise administrator". An org that blocks bypass-permissions
mode neuters both flags while leaving `--autopilot` (not a permissive option)
working — a posture indistinguishable from this bug from the outside, which is
why the flag path was worth clearing before concluding it was innocent. loomux
cannot flag its way past a policy; the targeted grants it already emits
(`--allow-tool orrerix`, `--add-dir`) are not permissive options and are what
keeps such a pane usable at all.
