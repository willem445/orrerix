//! Session-digest friction extraction (#250/#324 slice B).
//!
//! A worker's raw transcript (Claude `.jsonl`, Copilot `session-state`, or
//! OpenCode's SQLite `message`/`part` rows) is too large and too noisy to feed
//! an agent directly — full file contents, tool output, thinking blocks. This
//! module normalizes every source shape — one normalizer per CLI, all of them
//! producing [`TranscriptEvent`], and no parallel mechanism behind any of
//! them — into one small event stream, then reduces that stream, deterministically
//! and without any LLM, into "friction windows": the wall, the attempts, the
//! fix. Only those windows (plus three cheap anchors) are meant to reach an
//! agent — see `session_digest` in `mcp.rs` / `OrchRegistry::session_digest`
//! in `mod.rs` for the registry-facing side that resolves a task/agent/pr
//! into a transcript and calls into here.
//!
//! Everything in this file is pure: it takes text/events in and returns data
//! out, so it is fixture-tested without touching disk or a real agent CLI
//! (never spawn one to produce test data — CLAUDE.md constraint 3).

use serde::Serialize;
use serde_json::Value;

/// One event in a normalized transcript, source-agnostic — the same shape
/// whether it came from a Claude `.jsonl` line, a Copilot session-state read,
/// or an OpenCode `part` row. `role` is `"user"` or `"assistant"`.
#[derive(Debug, Clone, PartialEq, Serialize)]
pub struct TranscriptEvent {
    pub role: String,
    pub kind: EventKind,
    pub ts_ms: Option<u64>,
}

#[derive(Debug, Clone, PartialEq, Serialize)]
#[serde(tag = "kind", rename_all = "snake_case")]
pub enum EventKind {
    Text {
        text: String,
    },
    ToolCall {
        id: String,
        name: String,
        /// Shell-like tools carry their invocation here (`input.command`);
        /// drives near-duplicate-rerun and test-red-to-green detection.
        command: Option<String>,
        /// Edit/Write-like tools carry the touched path here
        /// (`input.file_path`); drives reverted-edit detection.
        file_path: Option<String>,
        /// The `Edit` tool's `input.old_string`/`input.new_string`, when
        /// present — the exact text a call replaced and what replaced it.
        /// Reverted-edit detection needs this: "same file touched twice" is
        /// too loose (two unrelated edits to one file aren't friction); "the
        /// second edit's old_string is the first edit's new_string" is cheap,
        /// deterministic evidence the second call is undoing or overwriting
        /// what the first one just wrote. `Write`/`MultiEdit` calls don't
        /// populate these (different input shape), so they never trigger the
        /// signature — conservative under-detection beats a noisy one.
        /// Truncated like every other text field here (`TEXT_CAP`), so two
        /// very long, genuinely-different strings sharing a common prefix
        /// could in principle compare equal after truncation — accepted for
        /// the same reason the rest of this module truncates: an
        /// approximate mechanical signal, not a byte-exact diff.
        old_string: Option<String>,
        new_string: Option<String>,
        /// Short display string for a window's summary text — the command
        /// if there is one, else a truncated compact form of the input.
        summary: String,
    },
    ToolResult {
        tool_use_id: String,
        is_error: bool,
        text: String,
    },
}

const TEXT_CAP: usize = 300;

fn truncate(s: &str, cap: usize) -> String {
    if s.chars().count() <= cap {
        s.to_string()
    } else {
        let head: String = s.chars().take(cap).collect();
        format!("{head}…")
    }
}

// ---------------------------------------------------------------------------
// Claude .jsonl normalization
// ---------------------------------------------------------------------------

/// Parse a Claude Code transcript (one JSON object per line) into a
/// normalized event stream. Only `"user"`/`"assistant"` lines carry
/// conversation content — kickoff/meta lines (`mode`, `permission-mode`,
/// `file-history-snapshot`, `attachment`, `ai-title`, `summary`) are skipped,
/// matching `sessions.rs::scan_claude_jsonl`'s own line-type filtering.
/// Malformed lines are skipped, not fatal — a transcript is append-only and
/// can be read mid-write.
pub fn parse_claude_transcript_events(text: &str) -> Vec<TranscriptEvent> {
    let mut events = Vec::new();
    for line in text.lines() {
        let line = line.trim();
        if line.is_empty() {
            continue;
        }
        let Ok(v) = serde_json::from_str::<Value>(line) else { continue };
        let ty = v.get("type").and_then(Value::as_str);
        if !matches!(ty, Some("user") | Some("assistant")) {
            continue;
        }
        let role = ty.unwrap().to_string();
        let ts_ms = v
            .get("timestamp")
            .and_then(Value::as_str)
            .and_then(parse_iso8601_ms);
        let Some(content) = v.get("message").and_then(|m| m.get("content")) else { continue };
        match content {
            Value::String(s) => {
                if !s.is_empty() {
                    events.push(TranscriptEvent { role, kind: EventKind::Text { text: truncate(s, TEXT_CAP) }, ts_ms });
                }
            }
            Value::Array(blocks) => {
                for b in blocks {
                    push_claude_block(&mut events, &role, ts_ms, b);
                }
            }
            _ => {}
        }
    }
    events
}

fn push_claude_block(events: &mut Vec<TranscriptEvent>, role: &str, ts_ms: Option<u64>, b: &Value) {
    match b.get("type").and_then(Value::as_str) {
        Some("text") => {
            if let Some(t) = b.get("text").and_then(Value::as_str) {
                if !t.is_empty() {
                    events.push(TranscriptEvent {
                        role: role.to_string(),
                        kind: EventKind::Text { text: truncate(t, TEXT_CAP) },
                        ts_ms,
                    });
                }
            }
        }
        Some("tool_use") => {
            let id = b.get("id").and_then(Value::as_str).unwrap_or_default().to_string();
            let name = b.get("name").and_then(Value::as_str).unwrap_or_default().to_string();
            let input = b.get("input");
            let command = input
                .and_then(|i| i.get("command"))
                .and_then(Value::as_str)
                .map(str::to_string);
            let file_path = input
                .and_then(|i| i.get("file_path"))
                .and_then(Value::as_str)
                .map(str::to_string);
            let old_string = input
                .and_then(|i| i.get("old_string"))
                .and_then(Value::as_str)
                .map(|s| truncate(s, TEXT_CAP));
            let new_string = input
                .and_then(|i| i.get("new_string"))
                .and_then(Value::as_str)
                .map(|s| truncate(s, TEXT_CAP));
            let summary = command
                .clone()
                .or_else(|| file_path.clone())
                .unwrap_or_else(|| truncate(&input.map(Value::to_string).unwrap_or_default(), 120));
            events.push(TranscriptEvent {
                role: role.to_string(),
                kind: EventKind::ToolCall { id, name, command, file_path, old_string, new_string, summary: truncate(&summary, 120) },
                ts_ms,
            });
        }
        Some("tool_result") => {
            let tool_use_id = b.get("tool_use_id").and_then(Value::as_str).unwrap_or_default().to_string();
            let is_error = b.get("is_error").and_then(Value::as_bool).unwrap_or(false);
            let text = truncate(&tool_result_text(b.get("content")), TEXT_CAP);
            events.push(TranscriptEvent {
                role: role.to_string(),
                kind: EventKind::ToolResult { tool_use_id, is_error, text },
                ts_ms,
            });
        }
        _ => {}
    }
}

/// A `tool_result` block's `content` is either a bare string or an array of
/// `{type:"text", text}` blocks (real transcripts observed carry both
/// shapes depending on the tool). Join text parts; ignore non-text blocks
/// (e.g. images) — nothing in the friction heuristics reads them.
fn tool_result_text(content: Option<&Value>) -> String {
    match content {
        Some(Value::String(s)) => s.clone(),
        Some(Value::Array(blocks)) => blocks
            .iter()
            .filter_map(|b| b.get("text").and_then(Value::as_str))
            .collect::<Vec<_>>()
            .join("\n"),
        _ => String::new(),
    }
}

/// Minimal `YYYY-MM-DDTHH:MM:SS[.fff]Z` → ms-since-epoch parser. No `chrono`
/// dependency (kept out deliberately — see the getrandom ban's neighboring
/// dependency-audit convention in `Cargo.toml`); Claude's transcript
/// timestamps are always this exact UTC/`Z` shape.
fn parse_iso8601_ms(s: &str) -> Option<u64> {
    let s = s.strip_suffix('Z')?;
    let (date, time) = s.split_once('T')?;
    let mut d = date.splitn(3, '-');
    let year: i64 = d.next()?.parse().ok()?;
    let month: i64 = d.next()?.parse().ok()?;
    let day: i64 = d.next()?.parse().ok()?;
    let (hms, frac) = time.split_once('.').unwrap_or((time, "0"));
    let mut t = hms.splitn(3, ':');
    let hour: i64 = t.next()?.parse().ok()?;
    let min: i64 = t.next()?.parse().ok()?;
    let sec: i64 = t.next()?.parse().ok()?;
    let millis: i64 = format!("{frac:0<3}").get(0..3)?.parse().ok()?;
    let days = days_from_civil(year, month, day);
    let total_ms = days * 86_400_000 + hour * 3_600_000 + min * 60_000 + sec * 1000 + millis;
    (total_ms >= 0).then_some(total_ms as u64)
}

/// Howard Hinnant's `days_from_civil` — days since the Unix epoch for a
/// proleptic-Gregorian civil date. Well-known, integer-only, no external date
/// crate needed for the one thing we use it for (chronological ts_ms).
fn days_from_civil(y: i64, m: i64, d: i64) -> i64 {
    let y = if m <= 2 { y - 1 } else { y };
    let era = if y >= 0 { y } else { y - 399 } / 400;
    let yoe = y - era * 400;
    let mp = (m + 9) % 12;
    let doy = (153 * mp + 2) / 5 + d - 1;
    let doe = yoe * 365 + yoe / 4 - yoe / 100 + doy;
    era * 146_097 + doe - 719_468
}

// ---------------------------------------------------------------------------
// Copilot session-state normalization
// ---------------------------------------------------------------------------

/// Parse a Copilot session's `session-state/<id>/` files into the same
/// normalized event stream Claude produces. Copilot keeps no per-turn
/// conversation log today (`workspace.yaml` records only session metadata;
/// `checkpoints/index.md` is a chronological title table, not a transcript —
/// confirmed against a real `~/.copilot/session-state/*` tree, structure
/// only) — so this is deliberately thin: the session title stands in for the
/// initial prompt, and each checkpoint title becomes one assistant `Text`
/// event. No `tool_call`/`tool_result`/`is_error` signal is available from
/// this source, so friction-window extraction over a Copilot digest will
/// find little to nothing — expected and acceptable; Claude is this
/// feature's deterministic primary (see the plan's risk section).
pub fn parse_copilot_session_events(workspace_yaml: &str, checkpoints_index_md: &str) -> Vec<TranscriptEvent> {
    let mut events = Vec::new();
    if let Some(title) = crate::sessions::yaml_field(workspace_yaml, "name") {
        if !title.is_empty() {
            events.push(TranscriptEvent { role: "user".into(), kind: EventKind::Text { text: title }, ts_ms: None });
        }
    }
    for (idx, title) in parse_checkpoint_titles(checkpoints_index_md) {
        events.push(TranscriptEvent {
            role: "assistant".into(),
            kind: EventKind::Text { text: format!("checkpoint {idx}: {title}") },
            ts_ms: None,
        });
    }
    events
}

/// Read the `| # | Title | File |` rows out of a checkpoints `index.md`.
/// Header/separator rows fail the leading-`#`-cell `usize` parse and are
/// skipped for free.
fn parse_checkpoint_titles(md: &str) -> Vec<(usize, String)> {
    let mut out = Vec::new();
    for line in md.lines() {
        let line = line.trim();
        if !line.starts_with('|') {
            continue;
        }
        let cells: Vec<&str> = line.trim_matches('|').split('|').map(str::trim).collect();
        if cells.len() < 2 {
            continue;
        }
        let Ok(idx) = cells[0].parse::<usize>() else { continue };
        if cells[1].is_empty() {
            continue;
        }
        out.push((idx, cells[1].to_string()));
    }
    out
}

// ---------------------------------------------------------------------------
// OpenCode SQLite normalization
// ---------------------------------------------------------------------------

/// Normalize one OpenCode session's stored messages and parts into the same
/// event stream Claude and Copilot produce. The rows come from
/// [`opencodedb::session_transcript`](crate::opencodedb::session_transcript) —
/// the group's read-only store, the ONE SQLite path — and this function stays
/// pure like its two siblings: documents in, events out, no disk.
///
/// **Where OpenCode differs from Claude's wire format**, since the mapping is
/// only obvious once that is said out loud (schema `SOURCE-VERIFIED` at
/// `anomalyco/opencode@f67e80c2`, tag `v1.18.11`,
/// `packages/schema/src/v1/session.ts`; see `docs/design/opencode.md`):
///
/// - **A message carries no text.** Both a user's prompt and an assistant's
///   reply live in `part` rows hanging off the message, so the message
///   document is read for exactly one thing — its `role` — and everything
///   else comes from the part.
/// - **One `tool` part carries the call AND its outcome.** Claude writes a
///   `tool_use` block and, a message later, a `tool_result` block; OpenCode
///   writes one row whose `state` is `pending | running | completed | error`.
///   So a completed or failed tool part expands to TWO events here — the
///   `ToolCall` every friction signature pairs against, then the `ToolResult`
///   carrying `output` (completed) or `error` (error). A `pending`/`running`
///   part emits the call and no result: that call genuinely has no outcome
///   yet, and inventing a clean one would erase a wall the session died on.
/// - **Both events carry the MESSAGE's role**, so a tool call and its result
///   are both `"assistant"` where Claude's result would be `"user"`. Nothing
///   reads `role` except `build_digest`'s "first user `Text`" prompt anchor,
///   and no friction signature does — so mirroring Claude's turn convention
///   would be a fiction with no reader.
///
/// Part types other than `text` and `tool` are skipped, and the full list is
/// worth naming rather than hiding behind a wildcard: `reasoning` (skipped
/// for the same reason `push_claude_block` skips `thinking` — it is the
/// model's scratchpad, not what it did), plus `step-start`, `step-finish`,
/// `snapshot`, `patch`, `file`, `agent`, `retry`, `compaction` and `subtask`,
/// none of which carry conversation content or a tool outcome.
pub fn parse_opencode_transcript_events(rows: &[crate::opencodedb::TranscriptRow]) -> Vec<TranscriptEvent> {
    let mut events = Vec::new();
    // One message's document repeats across every one of its parts, so it is
    // parsed once and reused until the id changes — the reason `message_id`
    // rides on the row at all.
    let mut cur_message: &str = "";
    let mut role: Option<String> = None;
    for row in rows {
        if row.message_id != cur_message {
            cur_message = row.message_id.as_str();
            role = serde_json::from_str::<Value>(&row.message_json)
                .ok()
                .and_then(|m| m.get("role").and_then(Value::as_str).map(str::to_string))
                // `Info` is a union of exactly `user` and `assistant` at the
                // pin. Anything else is a shape this normalizer has not been
                // read against — skip it rather than emit an event whose role
                // no consumer knows how to read.
                .filter(|r| r == "user" || r == "assistant");
        }
        let Some(role) = role.as_deref() else { continue };
        // Malformed JSON is skipped, not fatal — same posture as the Claude
        // arm's per-line skip. A digest of most of a session beats an error.
        let Ok(part) = serde_json::from_str::<Value>(&row.part_json) else { continue };
        let ts_ms = u64::try_from(row.time_created_ms).ok();
        push_opencode_part(&mut events, role, ts_ms, &part);
    }
    events
}

fn push_opencode_part(events: &mut Vec<TranscriptEvent>, role: &str, ts_ms: Option<u64>, p: &Value) {
    match p.get("type").and_then(Value::as_str) {
        Some("text") => {
            // `synthetic` text is scaffolding OpenCode injects on the model's
            // behalf (its own `SYNTHETIC_ATTACHMENT_PROMPT`, for one), and
            // `ignored` is text it has already decided not to feed the model.
            // Neither is anything an agent or a human said, and `initial_prompt`
            // is the first user `Text` in this stream — so letting one through
            // would put a machine-written string where the task brief goes.
            if p.get("synthetic").and_then(Value::as_bool).unwrap_or(false)
                || p.get("ignored").and_then(Value::as_bool).unwrap_or(false)
            {
                return;
            }
            if let Some(t) = p.get("text").and_then(Value::as_str) {
                if !t.is_empty() {
                    events.push(TranscriptEvent {
                        role: role.to_string(),
                        kind: EventKind::Text { text: truncate(t, TEXT_CAP) },
                        ts_ms,
                    });
                }
            }
        }
        Some("tool") => {
            let id = p.get("callID").and_then(Value::as_str).unwrap_or_default().to_string();
            let name = p.get("tool").and_then(Value::as_str).unwrap_or_default().to_string();
            let state = p.get("state");
            // Every `ToolState` arm carries `input`, including `pending` and
            // `running` — so a call's arguments are readable whatever became
            // of it.
            let input = state.and_then(|s| s.get("input"));
            let command = input.and_then(|i| i.get("command")).and_then(Value::as_str).map(str::to_string);
            // `filePath` first, then `path`: the pin ships two tools both
            // named `edit`, and they disagree on this key —
            // `packages/opencode/src/tool/edit.ts` (the v1 tool whose runner
            // writes these very part rows) takes `filePath`, while
            // `packages/core/src/tool/edit.ts` takes `path`. Reading only one
            // spelling would switch the reverted-edit signature off silently
            // the day the other tool wins, which is precisely the failure a
            // digest cannot report on itself.
            let file_path = input
                .and_then(|i| i.get("filePath").or_else(|| i.get("path")))
                .and_then(Value::as_str)
                .map(str::to_string);
            let old_string = input
                .and_then(|i| i.get("oldString"))
                .and_then(Value::as_str)
                .map(|s| truncate(s, TEXT_CAP));
            let new_string = input
                .and_then(|i| i.get("newString"))
                .and_then(Value::as_str)
                .map(|s| truncate(s, TEXT_CAP));
            let summary = command
                .clone()
                .or_else(|| file_path.clone())
                .unwrap_or_else(|| truncate(&input.map(Value::to_string).unwrap_or_default(), 120));
            events.push(TranscriptEvent {
                role: role.to_string(),
                kind: EventKind::ToolCall {
                    id: id.clone(),
                    name,
                    command,
                    file_path,
                    old_string,
                    new_string,
                    summary: truncate(&summary, 120),
                },
                ts_ms,
            });
            let (is_error, text) = match state.and_then(|s| s.get("status")).and_then(Value::as_str) {
                Some("completed") => (false, opencode_state_text(state.and_then(|s| s.get("output")))),
                Some("error") => (true, opencode_state_text(state.and_then(|s| s.get("error")))),
                // pending/running (or a status this reader has not been read
                // against): the call stands alone, no result event.
                _ => return,
            };
            events.push(TranscriptEvent {
                role: role.to_string(),
                kind: EventKind::ToolResult { tool_use_id: id, is_error, text: truncate(&text, TEXT_CAP) },
                ts_ms,
            });
        }
        _ => {}
    }
}

/// A completed tool's `output` and a failed one's `error` are both plain
/// strings at the pin (`ToolStateCompleted`/`ToolStateError`). Non-string
/// values are serialized rather than dropped: the friction key is built from
/// this text, and an empty error message would collapse every failure of one
/// tool into a single key.
fn opencode_state_text(v: Option<&Value>) -> String {
    match v {
        Some(Value::String(s)) => s.clone(),
        Some(other) => other.to_string(),
        None => String::new(),
    }
}

// ---------------------------------------------------------------------------
// Friction-window extraction (Stage-1 mechanical reduction, no LLM)
// ---------------------------------------------------------------------------

#[derive(Debug, Clone, Copy, PartialEq, Serialize)]
#[serde(rename_all = "snake_case")]
pub enum FrictionSignature {
    /// (a) a `tool_result` flagged `is_error:true`, and the `tool_use` that
    /// preceded it.
    ToolError,
    /// (b) the same shell-like tool re-run with a one-token-substituted
    /// command shortly after (the "tried npm, this repo is pnpm" shape).
    NearDuplicateCommand,
    /// (c) a test invocation that failed, followed later by one that passed.
    TestRedToGreen,
    /// (d) an `Edit` call whose `new_string` a LATER `Edit` call to the same
    /// file names as its own `old_string` — i.e. the second edit operates on
    /// exactly the text the first one just wrote (undoing it, or replacing
    /// it with something else). Tighter than "same file touched twice" on
    /// purpose (review finding NB2, #250/#324 slice B): two unrelated edits
    /// landing in one file are routine, not friction.
    RevertedEdit,
}

#[derive(Debug, Clone, PartialEq, Serialize)]
pub struct FrictionWindow {
    pub signature: FrictionSignature,
    /// Index into the event slice the window was extracted from (inclusive).
    pub start: usize,
    pub end: usize,
    /// Short human-readable description of the wall + (if resolved) the fix.
    pub summary: String,
    /// A deliberately COARSE, cross-session-stable identifier for *the wall*
    /// (#324 recurrence): the same key means "two sessions hit the same thing",
    /// which is the only evidence that separates a durable lesson from a
    /// one-off. See `friction_key`'s module section for the normalization and
    /// what it deliberately throws away.
    pub key: String,
    /// How many OTHER sessions in this group produced a window with this same
    /// `key`. `0` means "seen only in this session" — a one-off, and the whole
    /// point of the field: it is the mechanical answer to the process-pro's
    /// filter question ("would a fresh worker hit the same wall?"), which it
    /// otherwise has to answer from its own impression of a single session.
    ///
    /// The pure extractor always leaves this `0`; only
    /// `OrchRegistry::session_digest`, which can read the group's other
    /// transcripts, fills it in via `apply_recurrence`.
    pub recurrence: usize,
    /// Which sessions corroborated it (agent ids), capped at
    /// `MAX_CORROBORATED_BY`. `recurrence` is the FULL count and is never
    /// capped, so a truncated list can't read as a smaller number — same
    /// count-vs-content discipline as `SessionDigest::dropped_windows`.
    pub corroborated_by: Vec<String>,
}

impl FrictionWindow {
    fn new(signature: FrictionSignature, start: usize, end: usize, summary: String, key: String) -> Self {
        FrictionWindow { signature, start, end, summary, key, recurrence: 0, corroborated_by: Vec::new() }
    }
}

/// Whether a tool name is a file-mutating edit, for the reverted-edit
/// signature.
///
/// **Case-insensitive deliberately, and shared across every CLI** (#722 slice
/// B2): Claude names these tools `Edit`/`Write`/`MultiEdit`, OpenCode names
/// the same two `edit`/`write`. Normalizing OpenCode's names to Claude's
/// inside the normalizer was the alternative and is worse — it would put a
/// tool name in the event stream that the transcript does not contain, for
/// every consumer downstream, to satisfy one predicate.
///
/// The widening is safe in both directions rather than merely convenient for
/// OpenCode. Claude's tool names are a fixed set and none of them differs
/// from these three only by case, so no Claude tool changes classification;
/// Copilot's normalizer emits no `ToolCall` events at all
/// (`parse_copilot_session_events`), so this predicate is unreachable there.
/// Pinned by `the_edit_tool_predicate_spans_clis_without_widening_past_them`.
fn is_edit_tool(name: &str) -> bool {
    matches!(name.to_ascii_lowercase().as_str(), "edit" | "write" | "multiedit")
}

// ---------------------------------------------------------------------------
// Friction keys — the cross-session identity of a wall (#324 recurrence)
// ---------------------------------------------------------------------------
//
// A friction window's `summary` is written for a human to read, so it is full
// of the things that make two hits of the SAME wall look different: absolute
// worktree paths, line numbers, byte counts, a branch name. `key` is the
// opposite — the smallest string that still says "this is that wall", so the
// same wall in two sessions produces one key and recurrence is countable
// without an LLM.
//
// The bias is deliberately toward UNDER-matching being visible and
// OVER-matching being invisible: a key that is too specific shows up as
// `recurrence: 0` on something that did recur (the agent then treats a real
// lesson as a one-off — a miss, and the status quo, which is what today's
// n=1 digest already forces on every window). A key that is too loose shows
// up as a confident count for two unrelated walls, which is worse: it
// manufactures evidence. So every normalization below drops a field only when
// that field is a per-session accident (a path, a line number), never when it
// is what distinguishes one failure from another (an error code, a
// subcommand).

/// How many leading tokens of an error message make up its key shape. Enough
/// to carry a compiler's error code and the head of its message
/// (`error[E0433]: failed to resolve: use of undeclared crate`), short enough
/// that the part that varies per session (a path, a symbol name) usually
/// falls outside it.
const KEY_ERROR_TOKENS: usize = 6;

/// Last path component, lowercased. A key must survive the same file being
/// edited from two different worktrees — the whole point of corroboration is
/// comparing sessions, and two loomux workers on one repo have DIFFERENT
/// absolute paths for the identical file (`…/worktrees/feat-a/src/x.rs` vs
/// `…/worktrees/feat-b/src/x.rs`). Keeping any leading directory would make
/// cross-worktree recurrence structurally uncountable.
fn path_basename(p: &str) -> String {
    p.rsplit(['/', '\\']).next().unwrap_or(p).trim().to_lowercase()
}

/// The program a shell-like command invokes: first whitespace token, reduced
/// to its basename so `/usr/bin/npm` and `npm` are one program.
fn command_program(cmd: &str) -> String {
    cmd.split_whitespace().next().map(path_basename).unwrap_or_default()
}

/// Reduce one token of an error message to a cross-session-stable form.
///
/// Two classes get replaced, and only two:
/// - anything path-shaped (contains a separator) → `<path>`, because worktree
///   roots differ per session by construction;
/// - a purely numeric token (line numbers, counts, durations, `1,234`,
///   `12:34`) → `#`.
///
/// Everything else is kept verbatim (lowercased). In particular a token that
/// MIXES digits and letters — `error[e0433]`, `ts2345`, `0xc0000139` — is kept
/// whole, because that is precisely the token that distinguishes one failure
/// from another. Blanking digits wholesale would collapse `E0433` and `E0599`
/// into one key and count two unrelated compile errors as a recurrence.
fn normalize_key_token(t: &str) -> String {
    let t = t.trim_matches(|c: char| matches!(c, '"' | '\'' | '`' | '(' | ')' | '[' | ']' | ',' | ';'));
    if t.is_empty() {
        return String::new();
    }
    if t.contains('/') || t.contains('\\') {
        return "<path>".into();
    }
    if t.chars().any(|c| c.is_ascii_digit()) && t.chars().all(|c| c.is_ascii_digit() || matches!(c, '.' | ':' | ',' | '-' | '#' | '%' | '+')) {
        return "#".into();
    }
    t.to_lowercase()
}

/// The key shape of an error message: its first `KEY_ERROR_TOKENS` meaningful
/// tokens, each normalized.
fn normalize_error_shape(text: &str) -> String {
    text.split_whitespace()
        .map(normalize_key_token)
        .filter(|t| !t.is_empty())
        .take(KEY_ERROR_TOKENS)
        .collect::<Vec<_>>()
        .join(" ")
}

fn looks_like_test_command(cmd: &str) -> bool {
    let lc = cmd.to_lowercase();
    lc.contains("test")
}

/// Two commands are a "near-duplicate rerun" when they're the same tool
/// invoked with the same token count and every token but the first
/// (typically the runner name — `npm` vs `pnpm`) is identical.
fn is_near_duplicate_command(a: &str, b: &str) -> bool {
    if a == b {
        return false;
    }
    let ta: Vec<&str> = a.split_whitespace().collect();
    let tb: Vec<&str> = b.split_whitespace().collect();
    ta.len() > 1 && ta.len() == tb.len() && ta[0] != tb[0] && ta[1..] == tb[1..]
}

/// (a) tool_result is_error:true + preceding tool_use. The window closes at
/// the next successful result for the SAME tool (the recovery), else at the
/// end of the transcript (never recovered, at least not mechanically).
fn detect_tool_error_windows(events: &[TranscriptEvent]) -> Vec<FrictionWindow> {
    let mut windows = Vec::new();
    for (i, e) in events.iter().enumerate() {
        let EventKind::ToolResult { tool_use_id, is_error: true, text } = &e.kind else { continue };
        let Some(call_idx) = events[..i].iter().rposition(|c| matches!(&c.kind, EventKind::ToolCall { id, .. } if id == tool_use_id))
        else {
            continue;
        };
        let EventKind::ToolCall { name, command, file_path, .. } = &events[call_idx].kind else { unreachable!() };
        // The key names WHAT failed and HOW, not where: the tool, the program
        // it ran (or the file it touched — a `Read`/`Edit` error has no
        // command), and the normalized head of the error text.
        let subject = command
            .as_deref()
            .map(command_program)
            .or_else(|| file_path.as_deref().map(path_basename))
            .unwrap_or_default();
        let key = format!("tool_error:{name}:{subject}:{}", normalize_error_shape(text));
        let mut end = events.len() - 1;
        for (j, e2) in events.iter().enumerate().skip(i + 1) {
            let EventKind::ToolResult { tool_use_id: id2, is_error: false, .. } = &e2.kind else { continue };
            let Some(call2) = events[..j].iter().rposition(|c| matches!(&c.kind, EventKind::ToolCall { id, .. } if id == id2))
            else {
                continue;
            };
            let EventKind::ToolCall { name: name2, .. } = &events[call2].kind else { unreachable!() };
            if name2 == name {
                end = j;
                break;
            }
        }
        windows.push(FrictionWindow::new(
            FrictionSignature::ToolError,
            call_idx,
            end,
            format!("{name} failed: {}", truncate(text, 120)),
            key,
        ));
    }
    windows
}

/// (b) near-duplicate command re-runs among consecutive tool calls (text/
/// tool-result events in between don't break adjacency — only other tool
/// calls do).
fn detect_near_duplicate_commands(events: &[TranscriptEvent]) -> Vec<FrictionWindow> {
    let calls: Vec<(usize, &str, &str)> = events
        .iter()
        .enumerate()
        .filter_map(|(i, e)| match &e.kind {
            EventKind::ToolCall { name, command: Some(cmd), .. } => Some((i, name.as_str(), cmd.as_str())),
            _ => None,
        })
        .collect();
    calls
        .windows(2)
        .filter(|w| w[0].1 == w[1].1 && is_near_duplicate_command(w[0].2, w[1].2))
        .map(|w| {
            // The substitution itself IS the lesson ("tried npm, this repo is
            // pnpm"), so the key is the ordered pair plus the subcommand that
            // stayed the same — `npm->pnpm:install` and `npm->pnpm:run` are
            // different walls with the same fix, and both recur on their own.
            let sub = w[1].2.split_whitespace().nth(1).unwrap_or("").to_lowercase();
            let key = format!(
                "near_duplicate:{}->{}:{sub}",
                command_program(w[0].2),
                command_program(w[1].2)
            );
            FrictionWindow::new(
                FrictionSignature::NearDuplicateCommand,
                w[0].0,
                w[1].0,
                format!("re-ran with a substituted first token: {:?} then {:?}", w[0].2, w[1].2),
                key,
            )
        })
        .collect()
}

/// (c) a test invocation's result comes back an error, and a LATER test
/// invocation's result comes back clean.
fn detect_test_red_to_green(events: &[TranscriptEvent]) -> Vec<FrictionWindow> {
    let mut windows = Vec::new();
    // The failing call's index AND its key material — a red-to-green key has
    // to name WHICH test failure, not merely "tests went red here", or every
    // session in the group corroborates every other one and the count stops
    // meaning anything (see the over-matching note on the key section).
    let mut pending_fail: Option<(usize, String, String)> = None;
    for (i, e) in events.iter().enumerate() {
        let EventKind::ToolCall { id, command: Some(cmd), .. } = &e.kind else { continue };
        if !looks_like_test_command(cmd) {
            continue;
        }
        let result = events[i + 1..].iter().enumerate().find_map(|(k, e2)| match &e2.kind {
            EventKind::ToolResult { tool_use_id, is_error, text, .. } if tool_use_id == id => {
                Some((i + 1 + k, *is_error, text.as_str()))
            }
            _ => None,
        });
        let Some((ridx, is_error, rtext)) = result else { continue };
        if is_error {
            pending_fail = Some((i, command_program(cmd), normalize_error_shape(rtext)));
        } else if let Some((fail_idx, program, shape)) = pending_fail.take() {
            windows.push(FrictionWindow::new(
                FrictionSignature::TestRedToGreen,
                fail_idx,
                ridx,
                "a test run failed, then a later run passed".into(),
                format!("test_red_to_green:{program}:{shape}"),
            ));
        }
    }
    windows
}

/// "Evidence of restoration" (review finding NB2) — cheap and deterministic,
/// no file access: the second edit's `old_string` is exactly the first
/// edit's `new_string`, so the second call operates on the exact text the
/// first one just introduced. Not "some other edit happened to land in the
/// same file" — the original, false-positive-heavy check this replaces.
fn edit_overlaps(first_new: Option<&str>, second_old: Option<&str>) -> bool {
    matches!((first_new, second_old), (Some(a), Some(b)) if !a.is_empty() && a == b)
}

/// (d) an `Edit` call's `new_string` overlaps a LATER same-file `Edit`
/// call's `old_string` (in the tool-call stream — other files' edits in
/// between don't break adjacency). `Write`/`MultiEdit` calls carry no
/// `old_string`/`new_string` (see the field doc on `EventKind::ToolCall`),
/// so they never match here — this signature only fires where the evidence
/// is cheaply checkable, never on a same-file guess.
fn detect_reverted_edits(events: &[TranscriptEvent]) -> Vec<FrictionWindow> {
    let edits: Vec<(usize, &str, Option<&str>, Option<&str>)> = events
        .iter()
        .enumerate()
        .filter_map(|(i, e)| match &e.kind {
            EventKind::ToolCall { name, file_path: Some(fp), old_string, new_string, .. } if is_edit_tool(name) => {
                Some((i, fp.as_str(), old_string.as_deref(), new_string.as_deref()))
            }
            _ => None,
        })
        .collect();
    edits
        .windows(2)
        .filter(|w| w[0].1 == w[1].1 && edit_overlaps(w[0].3, w[1].2))
        .map(|w| {
            FrictionWindow::new(
                FrictionSignature::RevertedEdit,
                w[0].0,
                w[1].0,
                format!("{} edited again, touching the exact text the previous edit wrote", w[0].1),
                // Basename, not the recorded path: the same file is edited
                // from a different worktree in every session (see
                // `path_basename`).
                format!("reverted_edit:{}", path_basename(w[0].1)),
            )
        })
        .collect()
}

/// Run every friction signature over one normalized event stream and return
/// the windows in transcript order. Windows can overlap across signatures
/// (e.g. a failing test run is both a `ToolError` and half of a
/// `TestRedToGreen` pair) — deliberately: each signature is an independent,
/// cheap, mechanical lens, and de-duplicating them is exactly the kind of
/// judgment call left to the LLM stage that reads these windows, not this
/// deterministic one.
pub fn extract_friction_windows(events: &[TranscriptEvent]) -> Vec<FrictionWindow> {
    let mut windows = detect_tool_error_windows(events);
    windows.extend(detect_near_duplicate_commands(events));
    windows.extend(detect_test_red_to_green(events));
    windows.extend(detect_reverted_edits(events));
    windows.sort_by_key(|w| w.start);
    windows
}

// ---------------------------------------------------------------------------
// Session digest — friction windows + cheap anchors
// ---------------------------------------------------------------------------

/// Cap on the number of friction windows a `SessionDigest` carries (review
/// finding NB1): per-window text is already capped (`TEXT_CAP`/120 chars),
/// but the WINDOW COUNT was not — a long, flailing session could still emit
/// hundreds of them into an agent's context, exactly what this module exists
/// to avoid. A generous handful; see `cap_windows`.
const MAX_WINDOWS: usize = 20;

/// Keep the `max` most RECENT windows (highest `start`, i.e. closest to
/// however the session ended — the freshest friction is the most likely to
/// still matter) and report how many older ones were dropped, so a consumer
/// can tell "a clean session" from "a truncated digest" instead of silently
/// losing the tail. Windows are re-sorted chronologically on the way out —
/// only the SELECTION is recency-biased, not the order a reader sees them in.
fn cap_windows(mut windows: Vec<FrictionWindow>, max: usize) -> (Vec<FrictionWindow>, usize) {
    if windows.len() <= max {
        return (windows, 0);
    }
    windows.sort_by_key(|w| w.start);
    let dropped = windows.len() - max;
    let kept = windows.split_off(dropped);
    (kept, dropped)
}

// `is_safe_session_id` used to live here (review finding NB4). #925 deleted it
// rather than strengthening it in place, and the deletion is the point: it was
// a *predicate*, so its guarantee lasted exactly as long as the one call that
// invoked it, and its rule set — reject `/`, `\`, `.` and `..`, nothing else —
// admitted `"C:"`, `"CON"`, a leading `-`, an unbounded length, NUL and every
// non-ASCII byte straight through to `Path::join`.
//
// The replacement is `loomux_engine::pathseg::PathSegment`, parsed once in
// `OrchRegistry::read_session_transcript_events` and threaded to both path arms,
// so the property now travels with the value instead of being re-asserted (or
// forgotten) per call site. There is deliberately no `is_safe_session_id`
// shim left behind for a future caller to reach for.

/// The reduced signal handed to an agent (process-pro) in place of a raw
/// transcript: the friction windows plus three anchors — what the worker was
/// asked to do, what its work resolved to, and how that turned out. The last
/// two are pass-through: this module has no git/gh access, so
/// `OrchRegistry::session_digest` supplies them from the task board (PR ref,
/// status) it already holds, never by shelling out here.
#[derive(Debug, Clone, PartialEq, Serialize)]
pub struct SessionDigest {
    pub initial_prompt: Option<String>,
    pub final_diff_ref: Option<String>,
    pub outcome: Option<String>,
    pub windows: Vec<FrictionWindow>,
    /// How many older windows `cap_windows` cut to stay under `MAX_WINDOWS`
    /// — 0 for an uncapped digest. Always present, never silent (review
    /// finding NB1): a consumer can tell a clean session from a truncated one.
    pub dropped_windows: usize,
    /// How many OTHER sessions in this group were read to compute the
    /// `recurrence` counts on the windows above (#324). `0` means nothing was
    /// available to compare against — a *young group*, not a group of
    /// one-offs, and the difference is the whole reason this is reported
    /// rather than inferred from `recurrence: 0` everywhere.
    ///
    /// Always present. The pure builder leaves it `0`;
    /// `OrchRegistry::session_digest` sets it.
    pub sessions_scanned: usize,
    /// `true` when the group had MORE comparable sessions than
    /// `MAX_CORROBORATION_SESSIONS` allows and the oldest were not read. A
    /// `recurrence` count is then a floor, not a total — say so rather than
    /// let a capped scan read as an exhaustive one (same discipline as
    /// `dropped_windows`).
    pub corroboration_capped: bool,
}

/// How many corroborating session ids a window carries. The `recurrence`
/// COUNT is never capped — only this list is — so truncation can never
/// understate how often a wall recurred.
pub const MAX_CORROBORATED_BY: usize = 5;

/// Attach cross-session recurrence to a digest's windows (#324).
///
/// `others` is one entry per OTHER session read from the same group: a label
/// (the agent id, which is what a human or an agent can actually go look at)
/// and that session's deduped friction keys. Pure and total — the I/O of
/// finding and reading those sessions belongs to
/// `OrchRegistry::session_digest`, mirroring this module's existing
/// pure/impure split.
///
/// Counting is per SESSION, not per window: a single session that hit the
/// same wall nine times contributes 1, because the question the count answers
/// is "did anyone ELSE hit this?", not "how noisy was one transcript?". That
/// is also what keeps a single flailing session from manufacturing its own
/// evidence.
pub fn apply_recurrence(digest: &mut SessionDigest, others: &[(String, Vec<String>)]) {
    for w in digest.windows.iter_mut() {
        let mut hits: Vec<String> =
            others.iter().filter(|(_, keys)| keys.iter().any(|k| k == &w.key)).map(|(label, _)| label.clone()).collect();
        w.recurrence = hits.len();
        hits.truncate(MAX_CORROBORATED_BY);
        w.corroborated_by = hits;
    }
}

/// Every distinct friction key in one session's event stream — the compact
/// form `apply_recurrence` compares against. Deduped, so a session that hit
/// one wall repeatedly counts once (see `apply_recurrence`), and sorted so
/// the value is stable for tests and cheap to eyeball.
pub fn session_friction_keys(events: &[TranscriptEvent]) -> Vec<String> {
    let mut keys: Vec<String> = extract_friction_windows(events).into_iter().map(|w| w.key).collect();
    keys.sort();
    keys.dedup();
    keys
}

/// Build a digest from a normalized event stream. `final_diff_ref`/`outcome`
/// are supplied by the caller (see the struct doc); `initial_prompt` is the
/// first user `Text` event in the stream, falling back to
/// `initial_prompt_fallback` (e.g. the task's title) when the transcript
/// itself has none — Copilot's thin normalization commonly hits that case.
pub fn build_digest(
    events: &[TranscriptEvent],
    final_diff_ref: Option<String>,
    outcome: Option<String>,
    initial_prompt_fallback: Option<String>,
) -> SessionDigest {
    let initial_prompt = events
        .iter()
        .find_map(|e| match (&e.role[..], &e.kind) {
            ("user", EventKind::Text { text }) => Some(text.clone()),
            _ => None,
        })
        .or(initial_prompt_fallback);
    let (windows, dropped_windows) = cap_windows(extract_friction_windows(events), MAX_WINDOWS);
    // `sessions_scanned`/`corroboration_capped` stay 0/false here and every
    // window's `recurrence` stays 0: this builder sees exactly ONE session by
    // construction. The registry fills them in via `apply_recurrence` once it
    // has read the group's other transcripts.
    SessionDigest {
        initial_prompt,
        final_diff_ref,
        outcome,
        windows,
        dropped_windows,
        sessions_scanned: 0,
        corroboration_capped: false,
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use serde_json::json;

    fn claude_line(v: Value) -> String {
        v.to_string()
    }

    // ---- step 1: normalization ----

    #[test]
    fn claude_and_copilot_normalize_to_the_same_event_shape() {
        let claude_text = include_str!("../../tests/fixtures/digest/claude_sample.jsonl");
        let claude_events = parse_claude_transcript_events(claude_text);
        assert!(!claude_events.is_empty(), "fixture should yield at least one event");
        assert!(
            claude_events.iter().any(|e| matches!(e.kind, EventKind::Text { .. })),
            "fixture should include a text event"
        );
        assert!(
            claude_events.iter().any(|e| matches!(e.kind, EventKind::ToolCall { .. })),
            "fixture should include a tool_call event"
        );
        assert!(
            claude_events.iter().any(|e| matches!(e.kind, EventKind::ToolResult { .. })),
            "fixture should include a tool_result event"
        );

        let workspace = include_str!("../../tests/fixtures/digest/copilot/workspace.yaml");
        let checkpoints = include_str!("../../tests/fixtures/digest/copilot/checkpoints_index.md");
        let copilot_events = parse_copilot_session_events(workspace, checkpoints);
        assert!(!copilot_events.is_empty(), "fixture should yield at least one event");

        // Same Rust type on both sides (this compiles only if true) — and
        // every field the friction detectors read is present on both.
        for e in claude_events.iter().chain(copilot_events.iter()) {
            assert!(e.role == "user" || e.role == "assistant");
        }
    }

    #[test]
    fn claude_transcript_skips_non_conversation_line_types() {
        let text = format!(
            "{}\n{}\n",
            claude_line(json!({"type":"mode","mode":"default","sessionId":"s1"})),
            claude_line(json!({"type":"user","timestamp":"2026-07-15T10:00:00.000Z","message":{"role":"user","content":"hello"}})),
        );
        let events = parse_claude_transcript_events(&text);
        assert_eq!(events.len(), 1);
        assert_eq!(events[0].role, "user");
        assert_eq!(events[0].ts_ms, Some(1_784_109_600_000));
    }

    #[test]
    fn claude_transcript_reads_tool_use_and_tool_result_blocks() {
        let text = format!(
            "{}\n{}\n",
            claude_line(json!({"type":"assistant","message":{"role":"assistant","content":[
                {"type":"tool_use","id":"t1","name":"Bash","input":{"command":"npm test"}}
            ]}})),
            claude_line(json!({"type":"user","message":{"role":"user","content":[
                {"type":"tool_result","tool_use_id":"t1","is_error":true,"content":"FAIL"}
            ]}})),
        );
        let events = parse_claude_transcript_events(&text);
        assert_eq!(events.len(), 2);
        assert!(matches!(&events[0].kind, EventKind::ToolCall{name, command, ..} if name=="Bash" && command.as_deref()==Some("npm test")));
        assert!(matches!(&events[1].kind, EventKind::ToolResult{is_error: true, text, ..} if text=="FAIL"));
    }

    // ---- step 2: friction-window extraction, one test per signature, red-before-green ----

    fn tool_call(idx: usize, id: &str, name: &str, command: Option<&str>, file_path: Option<&str>) -> TranscriptEvent {
        let _ = idx;
        TranscriptEvent {
            role: "assistant".into(),
            kind: EventKind::ToolCall {
                id: id.into(),
                name: name.into(),
                command: command.map(str::to_string),
                file_path: file_path.map(str::to_string),
                old_string: None,
                new_string: None,
                summary: command.or(file_path).unwrap_or_default().into(),
            },
            ts_ms: None,
        }
    }

    /// An `Edit`-tool call carrying `old_string`/`new_string` — the shape
    /// `detect_reverted_edits` actually needs evidence from.
    fn edit_call(id: &str, file_path: &str, old_string: &str, new_string: &str) -> TranscriptEvent {
        TranscriptEvent {
            role: "assistant".into(),
            kind: EventKind::ToolCall {
                id: id.into(),
                name: "Edit".into(),
                command: None,
                file_path: Some(file_path.into()),
                old_string: Some(old_string.into()),
                new_string: Some(new_string.into()),
                summary: file_path.into(),
            },
            ts_ms: None,
        }
    }

    fn tool_result(id: &str, is_error: bool, text: &str) -> TranscriptEvent {
        TranscriptEvent { role: "user".into(), kind: EventKind::ToolResult { tool_use_id: id.into(), is_error, text: text.into() }, ts_ms: None }
    }

    #[test]
    fn signature_a_tool_error_windows_the_call_and_its_recovery() {
        let events = vec![
            tool_call(0, "t1", "Bash", Some("cargo build"), None),
            tool_result("t1", true, "error[E0433]: unresolved import"),
            tool_call(2, "t2", "Bash", Some("cargo build"), None),
            tool_result("t2", false, "Compiling loomux v0.10.0"),
        ];
        let windows = extract_friction_windows(&events);
        let w = windows.iter().find(|w| w.signature == FrictionSignature::ToolError).expect("a ToolError window");
        assert_eq!((w.start, w.end), (0, 3), "window spans the failing call through the same tool's next success");
    }

    #[test]
    fn signature_b_near_duplicate_command_reruns() {
        let events = vec![
            tool_call(0, "t1", "Bash", Some("npm install"), None),
            tool_result("t1", true, "npm: command not found"),
            tool_call(2, "t2", "Bash", Some("pnpm install"), None),
            tool_result("t2", false, "done"),
        ];
        let windows = extract_friction_windows(&events);
        let w = windows.iter().find(|w| w.signature == FrictionSignature::NearDuplicateCommand).expect("a NearDuplicateCommand window");
        assert_eq!((w.start, w.end), (0, 2));
    }

    #[test]
    fn signature_c_test_red_to_green() {
        let events = vec![
            tool_call(0, "t1", "Bash", Some("cargo test orchestration"), None),
            tool_result("t1", true, "FAILED tests::foo"),
            tool_call(2, "t2", "Edit", None, Some("src/orchestration/mod.rs")),
            tool_result("t2", false, "ok"),
            tool_call(4, "t3", "Bash", Some("cargo test orchestration"), None),
            tool_result("t3", false, "test result: ok"),
        ];
        let windows = extract_friction_windows(&events);
        let w = windows.iter().find(|w| w.signature == FrictionSignature::TestRedToGreen).expect("a TestRedToGreen window");
        assert_eq!((w.start, w.end), (0, 5));
    }

    #[test]
    fn signature_d_reverted_edit_requires_evidence_of_restoration() {
        let events = vec![
            edit_call("t1", "src/foo.rs", "let x = 1;", "let x = 2;"),
            tool_result("t1", false, "ok"),
            // t2's old_string is exactly t1's new_string: it's undoing t1.
            edit_call("t2", "src/foo.rs", "let x = 2;", "let x = 1;"),
            tool_result("t2", false, "ok"),
        ];
        let windows = extract_friction_windows(&events);
        let w = windows.iter().find(|w| w.signature == FrictionSignature::RevertedEdit).expect("a RevertedEdit window");
        assert_eq!((w.start, w.end), (0, 2));
    }

    /// Review finding NB2: the original check fired on ANY two edits to the
    /// same file, which is routine incremental work, not friction.
    #[test]
    fn signature_d_ignores_unrelated_edits_to_the_same_file() {
        let events = vec![
            edit_call("t1", "src/foo.rs", "fn a() {}", "fn a() { println!(\"a\"); }"),
            tool_result("t1", false, "ok"),
            edit_call("t2", "src/foo.rs", "fn b() {}", "fn b() { println!(\"b\"); }"),
            tool_result("t2", false, "ok"),
        ];
        let windows = extract_friction_windows(&events);
        assert!(
            !windows.iter().any(|w| w.signature == FrictionSignature::RevertedEdit),
            "unrelated edits to the same file must not be flagged: {windows:?}"
        );
    }

    /// `Write`/`MultiEdit` calls carry no old_string/new_string, so two
    /// same-file `Write`s never trigger the signature either — conservative
    /// under-detection where the evidence isn't cheaply available.
    #[test]
    fn signature_d_ignores_same_file_writes_with_no_old_new_evidence() {
        let events = vec![
            tool_call(0, "t1", "Write", None, Some("src/foo.rs")),
            tool_result("t1", false, "ok"),
            tool_call(2, "t2", "Write", None, Some("src/foo.rs")),
            tool_result("t2", false, "ok"),
        ];
        let windows = extract_friction_windows(&events);
        assert!(!windows.iter().any(|w| w.signature == FrictionSignature::RevertedEdit));
    }

    #[test]
    fn no_friction_signatures_means_no_windows() {
        let events = vec![
            tool_call(0, "t1", "Bash", Some("cargo check"), None),
            tool_result("t1", false, "ok"),
        ];
        assert!(extract_friction_windows(&events).is_empty());
    }

    // ---- window count cap (review finding NB1) ----

    #[test]
    fn build_digest_caps_windows_and_reports_how_many_were_dropped() {
        let total_pairs = MAX_WINDOWS + 5;
        let mut events = Vec::new();
        for i in 0..total_pairs {
            // Distinct tool name per pair so signature (a)'s "next success
            // for the SAME tool" search can't accidentally bridge pairs.
            let name = format!("Tool{i}");
            events.push(tool_call(0, &format!("{i}a"), &name, Some("run"), None));
            events.push(tool_result(&format!("{i}a"), true, "boom"));
            events.push(tool_call(0, &format!("{i}b"), &name, Some("run"), None));
            events.push(tool_result(&format!("{i}b"), false, "ok"));
        }
        let digest = build_digest(&events, None, None, None);
        assert_eq!(digest.windows.len(), MAX_WINDOWS);
        assert_eq!(digest.dropped_windows, 5);
        // The oldest 5 pairs were dropped; the kept windows start at pair 5's
        // failing call (index 5*4 = 20) — recency-biased selection, still
        // returned in chronological order.
        assert_eq!(digest.windows[0].start, 20);
        assert_eq!(digest.windows.last().unwrap().start, 4 * (total_pairs - 1));
    }

    #[test]
    fn build_digest_does_not_report_a_drop_when_under_the_cap() {
        let events = vec![
            tool_call(0, "t1", "Bash", Some("cargo build"), None),
            tool_result("t1", true, "boom"),
        ];
        let digest = build_digest(&events, None, None, None);
        assert_eq!(digest.dropped_windows, 0);
    }

    // The session-id path-safety unit tests that lived here (review finding
    // NB4) moved with the rule they covered: the family is now validated by
    // `loomux_engine::pathseg::PathSegment`, and its refusal/acceptance suite —
    // including every shape the old predicate let through — is in
    // `src-tauri/tests/pathseg.rs` (#925).

    // ---- build_digest anchors ----

    #[test]
    fn build_digest_takes_initial_prompt_from_the_first_user_text_event() {
        let events = vec![
            TranscriptEvent { role: "user".into(), kind: EventKind::Text { text: "fix the flaky test".into() }, ts_ms: None },
            tool_call(1, "t1", "Bash", Some("cargo test"), None),
        ];
        let digest = build_digest(&events, Some("#42".into()), Some("pr".into()), None);
        assert_eq!(digest.initial_prompt.as_deref(), Some("fix the flaky test"));
        assert_eq!(digest.final_diff_ref.as_deref(), Some("#42"));
        assert_eq!(digest.outcome.as_deref(), Some("pr"));
    }

    #[test]
    fn build_digest_falls_back_to_the_task_title_when_the_transcript_has_no_user_text() {
        let events = vec![tool_call(0, "t1", "Bash", Some("cargo test"), None)];
        let digest = build_digest(&events, None, None, Some("fix the flaky test".into()));
        assert_eq!(digest.initial_prompt.as_deref(), Some("fix the flaky test"));
    }

    // ---- iso8601 parsing ----

    #[test]
    fn iso8601_parses_the_unix_epoch() {
        assert_eq!(parse_iso8601_ms("1970-01-01T00:00:00.000Z"), Some(0));
    }

    #[test]
    fn iso8601_parses_a_known_date() {
        // 2024-01-01T00:00:00Z is 1704067200 seconds after the epoch.
        assert_eq!(parse_iso8601_ms("2024-01-01T00:00:00.000Z"), Some(1_704_067_200_000));
    }

    #[test]
    fn iso8601_rejects_a_non_utc_shape() {
        assert_eq!(parse_iso8601_ms("2024-01-01T00:00:00+02:00"), None);
    }

    // ---- #324: friction keys and cross-session recurrence ----
    //
    // Two failure modes are being guarded against here, and they are not
    // symmetric. A key that is too SPECIFIC under-counts (a real recurrence
    // reads as a one-off) — bad, but no worse than the n=1 status quo. A key
    // that is too LOOSE over-counts, which manufactures evidence for a lesson
    // nobody actually hit twice. So there is a test for each direction.

    /// The single most load-bearing normalization: two loomux workers on one
    /// repo run in DIFFERENT worktrees, so the identical wall carries a
    /// different absolute path in each transcript. If the key kept the path,
    /// cross-session recurrence would be structurally uncountable — every
    /// count would be 0 and the feature would silently do nothing.
    #[test]
    fn the_same_wall_from_two_worktrees_produces_one_key() {
        let mk = |root: &str| {
            let cmd = format!("cargo test --manifest-path {root}/src-tauri/Cargo.toml");
            let err = format!("error[E0433]: failed to resolve at {root}/src/lib.rs:12:5");
            vec![tool_call(0, "t1", "Bash", Some(cmd.as_str()), None), tool_result("t1", true, &err)]
        };
        let a = extract_friction_windows(&mk("C:/wt/feat-a"));
        let b = extract_friction_windows(&mk("C:/wt/feat-b"));
        assert_eq!(a.len(), 1, "{a:?}");
        assert_eq!(b.len(), 1, "{b:?}");
        assert_eq!(a[0].key, b[0].key, "the same wall in two worktrees must key the same");
    }

    /// The over-matching guard. Two different compile errors are two
    /// different walls; collapsing them would report a recurrence that never
    /// happened.
    #[test]
    fn two_different_error_codes_do_not_share_a_key() {
        let mk = |code: &str| {
            let err = format!("error[{code}]: something went wrong");
            vec![tool_call(0, "t1", "Bash", Some("cargo test"), None), tool_result("t1", true, &err)]
        };
        let a = extract_friction_windows(&mk("E0433"));
        let b = extract_friction_windows(&mk("E0599"));
        assert_ne!(a[0].key, b[0].key, "distinct error codes must stay distinct: {}", a[0].key);
    }

    /// …and the under-matching guard on the other side of the same
    /// normalizer: a line number is a per-session accident, not part of the
    /// wall's identity.
    #[test]
    fn line_numbers_do_not_split_a_key() {
        let mk = |line: &str| {
            let err = format!("assertion failed at line {line} of the fixture");
            vec![tool_call(0, "t1", "Bash", Some("cargo test"), None), tool_result("t1", true, &err)]
        };
        assert_eq!(extract_friction_windows(&mk("12"))[0].key, extract_friction_windows(&mk("4071"))[0].key);
    }

    #[test]
    fn a_reverted_edit_keys_on_the_file_not_its_worktree_path() {
        let mk = |root: &str| {
            let p = format!("{root}/src/layout.ts");
            vec![edit_call("e1", &p, "old", "mid"), edit_call("e2", &p, "mid", "new")]
        };
        let a = extract_friction_windows(&mk("C:/wt/feat-a"));
        let b = extract_friction_windows(&mk("/home/x/wt/feat-b"));
        assert_eq!(a[0].key, b[0].key);
        assert_eq!(a[0].key, "reverted_edit:layout.ts");
    }

    #[test]
    fn a_near_duplicate_rerun_keys_on_the_substitution_that_fixed_it() {
        let events = vec![
            tool_call(0, "t1", "Bash", Some("npm install"), None),
            tool_result("t1", true, "npm: command not found"),
            tool_call(2, "t2", "Bash", Some("pnpm install"), None),
            tool_result("t2", false, "done"),
        ];
        let w = extract_friction_windows(&events);
        let nd = w.iter().find(|w| w.signature == FrictionSignature::NearDuplicateCommand).unwrap();
        assert_eq!(nd.key, "near_duplicate:npm->pnpm:install");
    }

    fn digest_of(events: &[TranscriptEvent]) -> SessionDigest {
        build_digest(events, None, None, None)
    }

    fn one_wall() -> Vec<TranscriptEvent> {
        vec![
            tool_call(0, "t1", "Bash", Some("cargo test"), None),
            tool_result("t1", true, "error[E0433]: failed to resolve"),
        ]
    }

    /// The builder sees exactly one session, so it must never invent a
    /// recurrence — the registry is the only thing that can fill these in.
    #[test]
    fn the_pure_builder_reports_no_recurrence_and_no_scan() {
        let d = digest_of(&one_wall());
        assert_eq!(d.windows[0].recurrence, 0);
        assert!(d.windows[0].corroborated_by.is_empty());
        assert_eq!(d.sessions_scanned, 0);
        assert!(!d.corroboration_capped);
    }

    #[test]
    fn a_wall_no_other_session_hit_stays_a_one_off() {
        let mut d = digest_of(&one_wall());
        apply_recurrence(&mut d, &[("w-9".into(), vec!["tool_error:Bash:cargo:something else".into()])]);
        assert_eq!(d.windows[0].recurrence, 0, "an unrelated key must not corroborate");
        assert!(d.windows[0].corroborated_by.is_empty());
    }

    #[test]
    fn a_wall_another_session_also_hit_is_corroborated_and_named() {
        let mut d = digest_of(&one_wall());
        let key = d.windows[0].key.clone();
        apply_recurrence(&mut d, &[("w-9".into(), vec![key.clone()]), ("w-4".into(), vec!["other".into()])]);
        assert_eq!(d.windows[0].recurrence, 1);
        assert_eq!(d.windows[0].corroborated_by, vec!["w-9".to_string()]);
    }

    /// Counting is per SESSION: one flailing transcript that hit the same
    /// wall repeatedly is still one voice, or a single bad session could
    /// manufacture its own corroboration.
    #[test]
    fn one_sessions_repeats_count_once_not_once_per_hit() {
        let mut d = digest_of(&one_wall());
        let key = d.windows[0].key.clone();
        apply_recurrence(&mut d, &[("w-9".into(), vec![key.clone(), key.clone(), key])]);
        assert_eq!(d.windows[0].recurrence, 1, "three hits in ONE session is one corroborating session");
    }

    /// `session_friction_keys` is what makes the rule above hold at the
    /// source: a session's key set is deduped before it is ever compared.
    #[test]
    fn a_sessions_key_set_is_deduped() {
        let mut events = one_wall();
        events.extend(one_wall());
        assert!(extract_friction_windows(&events).len() >= 2, "two hits should yield two windows");
        assert_eq!(session_friction_keys(&events).len(), 1, "…but one key");
    }

    /// The id list is capped; the COUNT never is. A reader that trusted the
    /// list's length would understate a widely-recurring wall.
    #[test]
    fn the_corroborating_id_list_caps_but_the_count_does_not() {
        let mut d = digest_of(&one_wall());
        let key = d.windows[0].key.clone();
        let others: Vec<(String, Vec<String>)> =
            (0..MAX_CORROBORATED_BY + 3).map(|i| (format!("w-{i}"), vec![key.clone()])).collect();
        apply_recurrence(&mut d, &others);
        assert_eq!(d.windows[0].recurrence, MAX_CORROBORATED_BY + 3);
        assert_eq!(d.windows[0].corroborated_by.len(), MAX_CORROBORATED_BY);
    }

    // ---- OpenCode normalization (#722 slice B2) ----
    //
    // Every fixture below is the row shape OpenCode's own store holds:
    // `message.data` / `part.data` as JSON documents, per
    // `packages/{core/src/session/sql.ts,schema/src/v1/session.ts}` at
    // `anomalyco/opencode@f67e80c2` (tag `v1.18.11`). No opencode process is
    // ever started to produce them (CLAUDE.md constraint 3).

    fn oc_row(message_id: &str, role: &str, ts: i64, part: Value) -> crate::opencodedb::TranscriptRow {
        crate::opencodedb::TranscriptRow {
            message_id: message_id.into(),
            time_created_ms: ts,
            // The real document carries far more (agent, model, path, tokens…);
            // `role` is the only field this normalizer reads, and the extra
            // key is here so the fixture is a subset of the real shape rather
            // than a two-field invention.
            message_json: json!({ "role": role, "agent": "build" }).to_string(),
            part_json: part.to_string(),
        }
    }

    fn oc_text(text: &str) -> Value {
        json!({ "type": "text", "text": text })
    }

    /// A completed `bash` part, the exact `ToolPart`+`ToolStateCompleted`
    /// shape: `callID`/`tool` on the part, `input`/`output` on the state.
    fn oc_bash(call: &str, command: &str, output: &str) -> Value {
        json!({ "type": "tool", "callID": call, "tool": "bash",
                "state": { "status": "completed", "input": { "command": command },
                           "output": output, "title": command, "metadata": {},
                           "time": { "start": 1, "end": 2 } } })
    }

    fn oc_bash_error(call: &str, command: &str, error: &str) -> Value {
        json!({ "type": "tool", "callID": call, "tool": "bash",
                "state": { "status": "error", "input": { "command": command },
                           "error": error, "time": { "start": 1, "end": 2 } } })
    }

    /// An `edit` part. `path_key` is the input key the edit tool spells its
    /// target with — the pin ships two tools named `edit` that disagree
    /// (`filePath` vs `path`), which is why the normalizer reads both.
    fn oc_edit(call: &str, path_key: &str, file: &str, old: &str, new: &str) -> Value {
        json!({ "type": "tool", "callID": call, "tool": "edit",
                "state": { "status": "completed",
                           "input": { path_key: file, "oldString": old, "newString": new },
                           "output": "ok", "title": file, "metadata": {},
                           "time": { "start": 1, "end": 2 } } })
    }

    #[test]
    fn opencode_rows_normalize_to_the_same_event_shape_as_the_other_clis() {
        let rows = vec![
            oc_row("msg_1", "user", 1_785_703_307_950, oc_text("fix the flaky test")),
            oc_row("msg_2", "assistant", 1_785_703_308_000, oc_text("running the suite")),
            oc_row("msg_2", "assistant", 1_785_703_308_000, oc_bash("c1", "npm test", "1 passing")),
        ];
        let events = parse_opencode_transcript_events(&rows);
        // One text + one text + (call, result) — the tool part is TWO events.
        assert_eq!(events.len(), 4, "{events:?}");
        assert!(events.iter().all(|e| e.role == "user" || e.role == "assistant"));
        assert!(matches!(&events[0].kind, EventKind::Text { text } if text == "fix the flaky test"));
        assert_eq!(events[0].role, "user");
        assert_eq!(events[0].ts_ms, Some(1_785_703_307_950));
        assert!(matches!(&events[2].kind, EventKind::ToolCall { id, name, command: Some(c), .. }
            if id == "c1" && name == "bash" && c == "npm test"));
        assert!(matches!(&events[3].kind, EventKind::ToolResult { tool_use_id, is_error: false, text }
            if tool_use_id == "c1" && text == "1 passing"));
    }

    /// The mapping this slice exists for: OpenCode stores a call and its
    /// outcome in ONE row, so the pairing every friction signature depends on
    /// has to be manufactured here or no opencode session ever yields a
    /// window.
    #[test]
    fn an_opencode_tool_part_expands_into_a_call_and_its_outcome() {
        let rows = vec![oc_row("msg_1", "assistant", 1, oc_bash_error("c1", "cargo check", "error[E0433]: failed to resolve"))];
        let events = parse_opencode_transcript_events(&rows);
        assert_eq!(events.len(), 2, "an errored tool part is a call AND a failed result: {events:?}");
        let EventKind::ToolResult { tool_use_id, is_error, text } = &events[1].kind else {
            panic!("expected a ToolResult, got {:?}", events[1].kind)
        };
        assert_eq!(tool_use_id, "c1", "the result must pair with the call's callID");
        assert!(is_error, "state.status == \"error\" is the is_error signal");
        assert_eq!(text, "error[E0433]: failed to resolve", "the error text is the state's `error`, not its `output`");
    }

    /// A tool that never finished has no outcome to report. Emitting a clean
    /// result would erase the wall a session may have died on — the one place
    /// a fabricated event would silently *remove* friction from the digest.
    #[test]
    fn an_unfinished_opencode_tool_part_emits_the_call_and_no_result() {
        for status in ["pending", "running"] {
            let part = json!({ "type": "tool", "callID": "c1", "tool": "bash",
                               "state": { "status": status, "input": { "command": "npm test" } } });
            let events = parse_opencode_transcript_events(&[oc_row("msg_1", "assistant", 1, part)]);
            assert_eq!(events.len(), 1, "{status}: {events:?}");
            assert!(matches!(&events[0].kind, EventKind::ToolCall { command: Some(c), .. } if c == "npm test"),
                    "{status}: the call's input is still readable");
        }
    }

    #[test]
    fn an_opencode_failed_command_becomes_a_tool_error_window() {
        let rows = vec![
            oc_row("msg_1", "user", 1, oc_text("build it")),
            oc_row("msg_2", "assistant", 2, oc_bash_error("c1", "npm test", "npm: command not found")),
            oc_row("msg_3", "assistant", 3, oc_bash("c2", "pnpm test", "1 passing")),
        ];
        let events = parse_opencode_transcript_events(&rows);
        let windows = extract_friction_windows(&events);
        assert!(
            windows.iter().any(|w| w.signature == FrictionSignature::ToolError),
            "a failed opencode tool must reach the extractor: {windows:?}"
        );
        assert!(
            windows.iter().any(|w| w.signature == FrictionSignature::NearDuplicateCommand),
            "npm->pnpm is the same wall it is for claude: {windows:?}"
        );
    }

    /// The reverted-edit signature over opencode's lowercase tool names —
    /// dead without the `is_edit_tool` widening, and the `filePath` spelling
    /// the v1 edit tool (the one whose runner writes these rows) uses.
    #[test]
    fn an_opencode_edit_that_rewrites_its_own_new_string_is_a_reverted_edit() {
        let rows = vec![
            oc_row("msg_1", "assistant", 1, oc_edit("c1", "filePath", "C:/w/src/foo.rs", "let x = 1;", "let x = 2;")),
            oc_row("msg_2", "assistant", 2, oc_edit("c2", "filePath", "C:/w/src/foo.rs", "let x = 2;", "let x = 1;")),
        ];
        let windows = extract_friction_windows(&parse_opencode_transcript_events(&rows));
        let w = windows.iter().find(|w| w.signature == FrictionSignature::RevertedEdit).expect("a RevertedEdit window");
        assert_eq!(w.key, "reverted_edit:foo.rs");
    }

    /// The same session, had the core edit tool written it: `path` instead of
    /// `filePath`. Reading one spelling only would make this window vanish
    /// with no error anywhere.
    #[test]
    fn an_opencode_edit_spelled_with_the_core_tools_path_key_is_still_a_reverted_edit() {
        let rows = vec![
            oc_row("msg_1", "assistant", 1, oc_edit("c1", "path", "C:/w/src/foo.rs", "let x = 1;", "let x = 2;")),
            oc_row("msg_2", "assistant", 2, oc_edit("c2", "path", "C:/w/src/foo.rs", "let x = 2;", "let x = 1;")),
        ];
        let windows = extract_friction_windows(&parse_opencode_transcript_events(&rows));
        assert!(
            windows.iter().any(|w| w.signature == FrictionSignature::RevertedEdit),
            "the `path` spelling must be read too: {windows:?}"
        );
    }

    /// `is_edit_tool` is shared by every CLI's event stream, so widening it
    /// for opencode has to leave Claude's classification exactly as it was.
    /// Both directions are asserted: what must now match, and what must still
    /// miss — `NotebookEdit` is the near-miss that keeps the widening from
    /// being "any name containing edit".
    #[test]
    fn the_edit_tool_predicate_spans_clis_without_widening_past_them() {
        for name in ["Edit", "Write", "MultiEdit", "edit", "write", "multiedit"] {
            assert!(is_edit_tool(name), "{name} must classify as an edit tool");
        }
        for name in ["NotebookEdit", "Read", "Bash", "bash", "read", "editor", "webfetch", "todowrite"] {
            assert!(!is_edit_tool(name), "{name} must NOT classify as an edit tool");
        }
    }

    /// The claude-side half of the same guarantee, at the signature level
    /// rather than the predicate's: a Claude transcript's reverted edit still
    /// fires, and a Claude `NotebookEdit` pair still does not.
    #[test]
    fn widening_the_edit_predicate_leaves_claude_transcripts_classified_as_before() {
        let reverted = vec![
            edit_call("t1", "src/foo.rs", "let x = 1;", "let x = 2;"),
            tool_result("t1", false, "ok"),
            edit_call("t2", "src/foo.rs", "let x = 2;", "let x = 1;"),
            tool_result("t2", false, "ok"),
        ];
        assert!(
            extract_friction_windows(&reverted).iter().any(|w| w.signature == FrictionSignature::RevertedEdit),
            "claude's `Edit` must still be detected"
        );

        let notebook: Vec<TranscriptEvent> = reverted
            .iter()
            .map(|e| match &e.kind {
                EventKind::ToolCall { id, command, file_path, old_string, new_string, summary, .. } => TranscriptEvent {
                    role: e.role.clone(),
                    kind: EventKind::ToolCall {
                        id: id.clone(),
                        name: "NotebookEdit".into(),
                        command: command.clone(),
                        file_path: file_path.clone(),
                        old_string: old_string.clone(),
                        new_string: new_string.clone(),
                        summary: summary.clone(),
                    },
                    ts_ms: e.ts_ms,
                },
                _ => e.clone(),
            })
            .collect();
        assert!(
            !extract_friction_windows(&notebook).iter().any(|w| w.signature == FrictionSignature::RevertedEdit),
            "a tool name that only CONTAINS `edit` must stay unclassified"
        );
    }

    /// `synthetic`/`ignored` text is scaffolding OpenCode injects, not
    /// anything anyone said — and `initial_prompt` is the first user `Text`,
    /// so letting one through would put a machine-written string where the
    /// task brief goes.
    #[test]
    fn synthetic_and_ignored_opencode_text_never_becomes_the_initial_prompt() {
        let rows = vec![
            oc_row("msg_1", "user", 1, json!({ "type": "text", "text": "Attached media from tool result:", "synthetic": true })),
            oc_row("msg_1", "user", 1, json!({ "type": "text", "text": "stale draft", "ignored": true })),
            oc_row("msg_1", "user", 1, oc_text("fix the flaky test")),
        ];
        let events = parse_opencode_transcript_events(&rows);
        assert_eq!(events.len(), 1, "{events:?}");
        let d = build_digest(&events, None, None, None);
        assert_eq!(d.initial_prompt.as_deref(), Some("fix the flaky test"));
    }

    /// Reasoning is the model's scratchpad, exactly like Claude's `thinking`
    /// blocks, and the remaining part types carry no conversation content —
    /// none of them may become an event.
    ///
    /// The `text` part is load-bearing, not scenery: an assertion that a list
    /// is EMPTY passes just as well when the normalizer does nothing at all,
    /// so on its own this would be a test that cannot fail. Surrounding the
    /// skipped types with one part that must survive makes it fail in both
    /// directions — if a skipped type starts emitting, and if the normalizer
    /// stops emitting.
    #[test]
    fn opencode_part_types_with_no_conversation_content_are_skipped() {
        let rows = vec![
            oc_row("msg_1", "assistant", 1, json!({ "type": "reasoning", "text": "hmm", "time": { "start": 1 } })),
            oc_row("msg_1", "assistant", 1, json!({ "type": "step-start" })),
            oc_row("msg_1", "assistant", 1, json!({ "type": "step-finish", "reason": "stop", "cost": 0.0,
                                                    "tokens": { "input": 1, "output": 1, "reasoning": 0, "cache": { "read": 0, "write": 0 } } })),
            oc_row("msg_1", "assistant", 1, oc_text("the one part that carries content")),
            oc_row("msg_1", "assistant", 1, json!({ "type": "snapshot", "snapshot": "abc" })),
            oc_row("msg_1", "assistant", 1, json!({ "type": "patch", "hash": "abc", "files": ["src/foo.rs"] })),
            oc_row("msg_1", "assistant", 1, json!({ "type": "compaction", "auto": true })),
        ];
        let events = parse_opencode_transcript_events(&rows);
        assert_eq!(events.len(), 1, "only the text part may survive: {events:?}");
        assert!(matches!(&events[0].kind, EventKind::Text { text } if text == "the one part that carries content"));
    }

    /// A store read mid-write, a row this reader has not been read against, a
    /// message role that is neither: skipped, never fatal. The digest of most
    /// of a session beats an error — the same posture as the Claude arm's
    /// per-line skip.
    #[test]
    fn malformed_or_unknown_opencode_rows_are_skipped_not_fatal() {
        let mut rows = vec![
            crate::opencodedb::TranscriptRow {
                message_id: "msg_0".into(),
                time_created_ms: 1,
                message_json: "{not json".into(),
                part_json: oc_text("invisible").to_string(),
            },
            crate::opencodedb::TranscriptRow {
                message_id: "msg_1".into(),
                time_created_ms: 1,
                message_json: json!({ "role": "system" }).to_string(),
                part_json: oc_text("also invisible").to_string(),
            },
            crate::opencodedb::TranscriptRow {
                message_id: "msg_2".into(),
                time_created_ms: 1,
                message_json: json!({ "role": "user" }).to_string(),
                part_json: "{not json".into(),
            },
        ];
        assert!(parse_opencode_transcript_events(&rows).is_empty(), "nothing readable, nothing emitted");
        rows.push(oc_row("msg_3", "user", 2, oc_text("survivor")));
        let events = parse_opencode_transcript_events(&rows);
        assert_eq!(events.len(), 1, "the readable row still lands: {events:?}");
        assert!(matches!(&events[0].kind, EventKind::Text { text } if text == "survivor"));
    }

    /// A message's document is parsed once and reused across its parts. If
    /// that cache ever outlived its message id, every part of the session
    /// would inherit the first message's role — and `initial_prompt` would
    /// pick up an assistant's reply.
    #[test]
    fn each_opencode_messages_role_applies_only_to_its_own_parts() {
        let rows = vec![
            oc_row("msg_1", "assistant", 1, oc_text("I will start by reading the code")),
            oc_row("msg_2", "user", 2, oc_text("no, fix the flaky test first")),
            oc_row("msg_2", "user", 2, oc_text("and only that")),
        ];
        let events = parse_opencode_transcript_events(&rows);
        assert_eq!(
            events.iter().map(|e| e.role.as_str()).collect::<Vec<_>>(),
            vec!["assistant", "user", "user"],
        );
        let d = build_digest(&events, None, None, None);
        assert_eq!(d.initial_prompt.as_deref(), Some("no, fix the flaky test first"));
    }
}
