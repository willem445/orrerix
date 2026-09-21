//! Agent CLI probing: is a program on PATH, and which models does it offer?
//!
//! Most agent CLIs have no models API, but they document their model strings
//! in the `--model` section of their help text, so we run `<program> --help`
//! once (hidden, with a timeout), parse that section, and cache the result for
//! the app's lifetime.
//!
//! A CLI that can *enumerate* its models beats any parse of its own prose,
//! because it reports what the machine in front of the human is actually
//! configured for rather than what the vendor wrote in a help page. opencode
//! has one — `opencode models`, "List all available models from configured
//! providers" (<https://opencode.ai/docs/cli/>) — so that lives in
//! `ENUMERATORS` as DATA (the `CLI_CAPS` pattern): a second CLI gaining a list
//! command is a row there, not another branch in `probe_with`.
//!
//! The launcher merges whatever comes back with curated fallbacks, so a parse
//! miss degrades to suggestions rather than an empty dropdown.

use serde::Serialize;
use std::collections::HashMap;
use std::io::Read;
use std::process::{Command, Stdio};
use std::sync::{Mutex, OnceLock};
use std::time::{Duration, Instant};

const HELP_TIMEOUT: Duration = Duration::from_secs(8);

#[derive(Clone, Serialize)]
pub struct CliProbe {
    /// The program ran and produced help output.
    pub available: bool,
    /// Model ids the CLI reported: its own enumeration where it has one
    /// (`ENUMERATORS`), otherwise parsed from the `--model` help section. May
    /// be empty, and the launcher merges curated suggestions either way.
    pub models: Vec<String>,
    /// Human-readable failure reason when not available.
    pub error: Option<String>,
}

fn cache() -> &'static Mutex<HashMap<String, CliProbe>> {
    static CACHE: OnceLock<Mutex<HashMap<String, CliProbe>>> = OnceLock::new();
    CACHE.get_or_init(|| Mutex::new(HashMap::new()))
}

/// Extract model ids from a CLI's help text. Strategy: isolate the `--model`
/// option's description block, then collect quoted tokens plus bare tokens
/// that look like model ids (contain a digit, e.g. `gpt-5.2`,
/// `claude-sonnet-4.6`) and the literal `auto`.
pub fn parse_models_from_help(help: &str) -> Vec<String> {
    let Some(idx) = help.find("--model") else {
        return vec![];
    };
    // The block ends at the next option definition (a line whose first
    // non-space char is '-'), skipping the `--model` line itself.
    let mut block = String::new();
    for (i, line) in help[idx..].lines().enumerate() {
        if i > 0 && line.trim_start().starts_with('-') {
            break;
        }
        block.push_str(line);
        block.push('\n');
        if i > 14 {
            break;
        }
    }

    let mut out: Vec<String> = Vec::new();
    let mut push = |s: &str| {
        let s = s.trim();
        let ok = !s.is_empty()
            && s.len() <= 48
            && s.chars().all(|c| c.is_ascii_alphanumeric() || matches!(c, '-' | '.' | '_'))
            && (s == "auto" || s.chars().any(|c| c.is_ascii_digit()) || !s.contains(' '));
        if ok && !out.iter().any(|x| x == s) {
            out.push(s.to_string());
        }
    };

    // Quoted tokens: 'fable', "gpt-5.3-codex".
    for quote in ['\'', '"'] {
        let mut rest = block.as_str();
        while let Some(start) = rest.find(quote) {
            let after = &rest[start + 1..];
            let Some(end) = after.find(quote) else { break };
            push(&after[..end]);
            rest = &after[end + 1..];
        }
    }
    // Bare model-ish tokens (digit + dash, so prose words don't match) and
    // the literal `auto` (copilot's pick-for-me value).
    for token in block.split(|c: char| c.is_whitespace() || matches!(c, ',' | '(' | ')' | ':' | ';')) {
        let t = token.trim_matches(|c: char| !c.is_ascii_alphanumeric());
        if t == "auto" || (t.chars().any(|c| c.is_ascii_digit()) && t.contains('-')) {
            push(t);
        }
    }
    out
}

/// How one CLI enumerates its own models. Per-CLI differences live here as
/// DATA, the way `CLI_CAPS` carries the rest of them: adding a CLI that gained
/// a list command is a row, not a new code path.
struct Enumerator {
    /// The program name as probed (`probe_agent_cli` lower-cases before it
    /// looks anything up).
    program: &'static str,
    /// Arguments appended to the program. Constants only — never anything a
    /// caller supplied; see `run_cli`.
    args: &'static str,
    /// Parser for that command's stdout.
    parse: fn(&str) -> Vec<String>,
}

/// `opencode models` — "List all available models from configured providers"
/// (<https://opencode.ai/docs/cli/>). Deliberately WITHOUT `--refresh`: that
/// flag "[r]efresh[es] the models cache from models.dev" (same page), and a
/// background probe must not re-pull a remote catalog on the human's behalf —
/// the cached list is the one their own CLI would use anyway.
///
/// `pi --list-models [search]` (`SOURCE` `args.ts:196` at the pin in
/// `docs/design/pi.md`) is the second row. **HELP_TIMEOUT is 8 s; pi runs this
/// command under its own `AbortSignal.timeout(15_000)`** (`SOURCE`
/// `main.ts:864`) — its internal budget for a cold models.json refresh, not
/// ours. When a cold refresh loses our 8 s race the probe is killed mid-list,
/// the parse yields nothing, `probe_with` marks the answer incomplete and
/// `probe_cached` declines to cache it — so the picker keeps rendering only the
/// curated `[INHERIT_MODEL]` row and the NEXT probe retries, now against a
/// catalog pi has finished refreshing. Caching the miss would pin the worst
/// moment of the session for the rest of it, which is the same reason an
/// opencode `models` failure is never cached.
const ENUMERATORS: &[Enumerator] = &[
    Enumerator {
        program: "opencode",
        args: "models",
        parse: parse_models_from_list,
    },
    Enumerator {
        program: "pi",
        args: "--list-models",
        parse: parse_models_from_table,
    },
];

fn enumerator_for(program: &str) -> Option<&'static Enumerator> {
    ENUMERATORS.iter().find(|e| e.program == program)
}

/// Replace every ANSI escape sequence and control byte in one line with a
/// SPACE, so what is left is printable text with the removals still acting as
/// boundaries.
///
/// **Removing must never JOIN.** A tab is a control byte and a column
/// separator at the same time: delete it and `id<TAB>Human Name` becomes
/// `idHuman Name`, whose first token is `anthropic/claude-sonnet-4-5Claude` —
/// id-SHAPED but not an id, non-empty, and therefore promoted over the
/// help-parsed list and to the head of the human's picker (#939 review). The
/// same hazard applies to an escape sequence sitting mid-token. Substituting a
/// space instead makes one property structural: every id this module emits is a
/// verbatim whitespace-delimited token of the CLI's own output, never a
/// splice of two. The cost is the safe direction — a token interrupted by a
/// sequence splits into two unrecognisable halves and the line yields nothing.
fn plain_line(line: &str) -> String {
    let mut out = String::with_capacity(line.len());
    let mut chars = line.chars();
    while let Some(c) = chars.next() {
        if c == '\u{1b}' {
            // Swallow the sequence up to its terminating letter (CSI `m`, `K`,
            // …). An OSC string ends at BEL instead.
            for n in chars.by_ref() {
                if n.is_ascii_alphabetic() || n == '\u{7}' {
                    break;
                }
            }
            out.push(' ');
            continue;
        }
        out.push(if c.is_control() { ' ' } else { c });
    }
    out
}

/// The id shape every parser in this module emits: every `/`-separated segment
/// non-empty and made of id characters only. The empty segment is what rejects
/// a URL's `https://`, and a second `/` is accepted — an OpenRouter-style id
/// `openrouter/z-ai/glm-5.3-flash` is one id, not a prefix of one.
fn is_id_shaped(token: &str) -> bool {
    token.split('/').all(|seg| {
        !seg.is_empty() && seg.chars().all(|c| c.is_ascii_alphanumeric() || matches!(c, '-' | '.' | '_' | ':'))
    })
}

/// Parse a listing command's stdout into model ids: one `provider/model` id
/// per line, which is the shape opencode documents ("displays all models
/// available across your configured providers in the form of
/// `provider/model`" — <https://opencode.ai/docs/cli/>).
///
/// The docs state the id format but not the surrounding layout, so this models
/// no layout at all: each line is reduced to printable text (`plain_line`), its
/// first token is taken, and that token is kept only if it *is* an id.
/// Headings, spinners and progress chatter it has never seen are dropped, and a
/// wholly unfamiliar layout yields nothing — `probe_with` then leaves the
/// help-parsed list alone.
///
/// What this guarantees, and what it does not: **every id returned is a
/// verbatim whitespace-delimited token of the CLI's own output** — this cannot
/// splice two fields together, invent characters, or repair a broken one. It is
/// not a promise that every token it accepts is a model: a column header
/// literally reading `provider/model` would be accepted as one, because at that
/// point it is indistinguishable from an id, and the human sees it in a picker
/// beside real ids with the `custom…` escape still there. Erring that way is
/// deliberate — the parser is written against an unobserved layout, so it may
/// under-recognise, but it must never manufacture.
///
/// A CLI that listed bare ids instead would carry its own parser in its
/// `ENUMERATORS` row.
pub fn parse_models_from_list(out: &str) -> Vec<String> {
    let mut models: Vec<String> = Vec::new();
    for raw in out.lines() {
        let line = plain_line(raw);
        let line = line.trim().trim_start_matches(|c: char| matches!(c, '-' | '*' | '\u{2022}' | ' ' | '\t'));
        let Some(token) = line.split_whitespace().next() else { continue };
        if token.len() > 96 || !token.contains('/') {
            continue;
        }
        let is_id = is_id_shaped(token);
        if is_id && !models.iter().any(|m| m == token) {
            models.push(token.to_string());
        }
    }
    models
}

/// Split one already-`plain_line`d table row into its columns: a run of two or
/// more spaces separates columns, and a SINGLE space never does — pi pads every
/// column to its width with `padEnd` before joining with two spaces
/// (`SOURCE` `list-models.ts:93-114`), so the run between two columns is two
/// spaces or more, and any shorter gap is part of a column's own value.
fn two_space_columns(line: &str) -> Vec<&str> {
    let bytes = line.as_bytes();
    let mut cols: Vec<&str> = Vec::new();
    let mut start = 0usize;
    let mut i = 0usize;
    while i < line.len() {
        if bytes[i] == b' ' && i + 1 < line.len() && bytes[i + 1] == b' ' {
            if i > start {
                cols.push(&line[start..i]);
            }
            while i < line.len() && bytes[i] == b' ' {
                i += 1;
            }
            start = i;
        } else {
            i += 1;
        }
    }
    if start < line.len() {
        cols.push(&line[start..]);
    }
    cols
}

/// Parse `pi --list-models` stdout into model ids (#2126 P4).
///
/// pi prints a two-space-padded column table — a header line
/// `provider  model  context  max-out  thinking  images`, then one row per
/// model sorted by provider then id, with `provider` and `model` as SEPARATE
/// columns (`SOURCE` `src/cli/list-models.ts` at the pin in `docs/design/pi.md`).
/// So the id is ASSEMBLED from the row's first two columns as
/// `{provider}/{model}` — what pi's own `--model` takes — rather than read out
/// of one token the way [`parse_models_from_list`] does.
///
/// Rule: the header is the first line whose first two whitespace tokens are
/// `provider` and `model`; every line AFTER it is `plain_line`d, split with
/// [`two_space_columns`], and kept only if both of its first two columns are
/// id-shaped ([`is_id_shaped`]). Lines before the header — pi's chalk-coloured
/// `Warning: errors loading models.json:` line above all — and the
/// `No models matching "…"` and `No models available. …` messages never reach a
/// column split at all, so they yield nothing; so does any post-header line
/// whose first two columns are not both ids.
///
/// The degrade direction is the module's own: under-recognise, never
/// manufacture. An unfamiliar line after the header is dropped, and an
/// unrecognised layout as a whole yields nothing, which `probe_with` treats as
/// an incomplete answer and leaves the help-parsed list alone.
pub fn parse_models_from_table(out: &str) -> Vec<String> {
    let mut models: Vec<String> = Vec::new();
    let mut header_seen = false;
    for raw in out.lines() {
        let line = plain_line(raw);
        if !header_seen {
            let mut tokens = line.split_whitespace();
            if tokens.next() == Some("provider") && tokens.next() == Some("model") {
                header_seen = true;
            }
            continue;
        }
        let cols = two_space_columns(&line);
        let (Some(provider), Some(model)) = (cols.first().copied(), cols.get(1).copied()) else {
            continue;
        };
        if is_id_shaped(provider) && is_id_shaped(model) {
            let id = format!("{provider}/{model}");
            if !models.iter().any(|m| *m == id) {
                models.push(id);
            }
        }
    }
    models
}

/// Run `<program> <args>` without a console window, bounded by a timeout.
///
/// `stdin` is `None` for a probe that only reads the CLI's output, and
/// `Some(line)` for one that has to ask a question first — `modelwire.rs`'s
/// list-models control request is the only caller that does, and it is why this
/// is `pub(crate)` rather than private. Sharing it rather than copying it is
/// deliberate: the fresh-PATH resolution, the hidden-window creation flag, the
/// two drain threads and the deadline poll are the parts that are easy to get
/// subtly wrong on Windows, and a second copy would be a second place to fix
/// each of them.
///
/// The payload is written and stdin is then CLOSED, which is what tells a CLI
/// reading a `stream-json` input stream that no more requests are coming. It is
/// written after the drain threads are already running, so a CLI that answers
/// before it has read the whole request cannot deadlock against a full stdout
/// pipe — though in practice the payload is a single short line, far inside the
/// pipe buffer.
pub(crate) fn run_cli(program: &str, args: &str, stdin: Option<&str>) -> Result<String, String> {
    // The program name is interpolated into a shell line on Windows (npm
    // shims are .cmd files that CreateProcess can't exec directly).
    if !program.chars().all(|c| c.is_ascii_alphanumeric() || c == '-' || c == '_') {
        return Err("invalid program name".into());
    }
    // `args` is only ever a literal (`--help`) or an `ENUMERATORS` row, both
    // compile-time constants — this checks that rather than trusting it, so
    // the shell line above stays obviously safe if a row is ever added.
    if !args.chars().all(|c| c.is_ascii_alphanumeric() || matches!(c, '-' | '_' | ' ')) {
        return Err("invalid probe arguments".into());
    }
    #[cfg(target_os = "windows")]
    let mut cmd = {
        use std::os::windows::process::CommandExt;
        const CREATE_NO_WINDOW: u32 = 0x0800_0000;
        let mut c = Command::new("cmd");
        c.args(["/C", &format!("{program} {args}")]).creation_flags(CREATE_NO_WINDOW);
        c
    };
    #[cfg(not(target_os = "windows"))]
    let mut cmd = {
        let mut c = Command::new("sh");
        c.args(["-lc", &format!("{program} {args}")]);
        c
    };
    // Fresh PATH: a CLI installed after loomux started must still probe as
    // available (its dir is already in the registry PATH).
    if let Some(path) = crate::winpath::fresh_path() {
        cmd.env("PATH", path);
    }
    let mut child = cmd
        .stdin(if stdin.is_some() { Stdio::piped() } else { Stdio::null() })
        .stdout(Stdio::piped())
        .stderr(Stdio::piped())
        .spawn()
        .map_err(|e| e.to_string())?;

    // Drain both pipes on threads (help can exceed the pipe buffer) while
    // we poll for exit with a deadline. Stderr matters for diagnosis: the
    // shell's "not recognized" complaint lands there.
    let mut stdout = child.stdout.take().unwrap();
    let reader = std::thread::spawn(move || {
        let mut buf = String::new();
        let _ = stdout.read_to_string(&mut buf);
        buf
    });
    let mut stderr = child.stderr.take().unwrap();
    let err_reader = std::thread::spawn(move || {
        let mut buf = String::new();
        let _ = stderr.read_to_string(&mut buf);
        buf
    });
    // After the drains are live, never before: a write that blocked on a full
    // stdout pipe with nobody reading it would hang until the deadline.
    // Dropping the handle closes stdin, which is the EOF a stream-json reader
    // waits for before it will exit.
    if let Some(payload) = stdin {
        if let Some(mut pipe) = child.stdin.take() {
            use std::io::Write;
            // A failed write is not fatal on its own — the CLI may have exited
            // first, and the reply (or the absence of one) on stdout is what
            // the caller actually reads.
            let _ = pipe.write_all(payload.as_bytes());
            let _ = pipe.write_all(b"\n");
            let _ = pipe.flush();
        }
    }
    let deadline = Instant::now() + HELP_TIMEOUT;
    loop {
        match child.try_wait() {
            Ok(Some(status)) => {
                let out = reader.join().unwrap_or_default();
                if out.trim().is_empty() && !status.success() {
                    let err = err_reader.join().unwrap_or_default();
                    let first = err.lines().find(|l| !l.trim().is_empty()).unwrap_or("").trim();
                    if first.contains("not recognized") || first.contains("not found") {
                        return Err(format!("'{program}' was not found on PATH"));
                    }
                    return Err(format!(
                        "`{program} {args}` failed (exit {:?}){}",
                        status.code(),
                        if first.is_empty() { String::new() } else { format!(": {first}") }
                    ));
                }
                return Ok(out);
            }
            Ok(None) => {
                if Instant::now() >= deadline {
                    let _ = child.kill();
                    return Err(format!("`{program} {args}` timed out"));
                }
                std::thread::sleep(Duration::from_millis(60));
            }
            Err(e) => return Err(e.to_string()),
        }
    }
}

/// The probe itself, with process spawning factored out behind `run(program,
/// args) -> stdout` so the strategy can be tested without spawning an agent
/// CLI (constraint 3 — a real spawn burns the human's credits, and tests never
/// get to make that trade).
///
/// Two properties are structural here rather than asserted at a call site:
///
/// - **`--help` alone decides availability.** An enumerator that fails, times
///   out, or prints something unrecognisable must never turn an installed CLI
///   into a missing one — the launcher refuses a whole launch on `available:
///   false`.
/// - **Only a non-empty enumeration replaces the help-parsed list.** So the
///   failure path is exactly today's behaviour, not a worse one.
///
/// Returns the probe and whether it is COMPLETE: false when a CLI that has an
/// enumerator got nothing out of it, which is a degraded answer the caller
/// declines to cache — see `probe_agent_cli`. The `CliProbe` handed to the
/// frontend is unchanged either way; completeness is a caching fact, not a
/// wire field.
fn probe_with(program: &str, run: impl Fn(&str, &str) -> Result<String, String>) -> (CliProbe, bool) {
    let help = match run(program, "--help") {
        Ok(help) => help,
        Err(e) => {
            let probe = CliProbe {
                available: false,
                models: vec![],
                error: Some(if e.contains("cannot find") || e.contains("not found") || e.contains("os error 2") {
                    format!("'{program}' was not found on PATH")
                } else {
                    e
                }),
            };
            return (probe, false);
        }
    };
    let mut models = parse_models_from_help(&help);
    let mut complete = true;
    if let Some(en) = enumerator_for(program) {
        // A second subprocess, on the blocking pool and under the same timeout
        // as the help run.
        let listed = run(program, en.args).map(|out| (en.parse)(&out)).unwrap_or_default();
        complete = !listed.is_empty();
        if complete {
            models = listed;
        }
    }
    (CliProbe { available: true, models, error: None }, complete)
}

fn probe_uncached(program: &str) -> (CliProbe, bool) {
    // No stdin: this probe only reads what the CLI prints unprompted.
    probe_with(program, |program, args| run_cli(program, args, None))
}

/// Probe an agent CLI (availability + model list). COMPLETE probes are cached
/// for the app run; failures and partial answers are NOT — a CLI installed
/// while loomux is running must become launchable on the next probe (spawns
/// already see it via fresh-PATH resolution), and by the same argument an
/// opencode whose `models` run failed — a network blip, a provider configured
/// or `opencode auth login` completed a minute later — must be able to report
/// its real list without a restart. Caching the degraded list would pin the
/// worst moment of the session for the rest of it.
///
/// The cost of not caching it is one extra pair of subprocess runs per probe
/// call for a CLI that keeps failing to enumerate — bounded by the same
/// timeout, off-thread, and rare in practice because the launcher memoizes its
/// own probes per app run too.
///
/// Off-thread (#746 — `crate::blocking::run_blocking`, P1 of
/// `docs/design/performance.md`). On a cache miss this spawns the agent CLI with
/// `--help` and poll-joins it for up to eight seconds, which Tauri ran on the
/// webview thread: the longest single stall any command in the census could
/// produce, and a process spawn there besides (INV-2). A CLI with an
/// `ENUMERATORS` row spends a second such run on its list command, so its
/// worst case is two timeouts, not one — off-thread, once per app run, and
/// bounded either way.
///
/// **Reentrancy — an interleaving accepted, not a guard.** The cache lock is
/// taken twice, released between, and off-thread two probes of the same program
/// can therefore both miss it and both run `--help`. That is deliberate rather
/// than overlooked. The probe only READS the machine — PATH, and for an
/// `ENUMERATORS` CLI the providers that machine has configured — so both
/// computations agree and the second `insert` overwrites an identical value;
/// in the one case they could differ (a provider list that changed between the
/// two runs) both answers are equally current, so keeping the later write is
/// right rather than merely harmless. The whole cost of the race is one
/// duplicate subprocess, once per CLI per session. Holding the lock across `probe_uncached` would fix
/// a non-problem by creating a real one: the launcher probes several CLIs to
/// build its picker, and serializing them behind one lock would turn N
/// independent eight-second worst cases into their SUM — the exact stall this
/// conversion exists to remove, moved rather than deleted.
#[tauri::command]
pub async fn probe_agent_cli(program: String) -> CliProbe {
    crate::blocking::run_blocking(move || probe_cached(&program)).await
}

/// The body of [`probe_agent_cli`], callable from a thread that is not serving
/// a command — the #1020 startup sweep warms this cache so the launcher's first
/// paint does not wait eight seconds for a `--help` run it could have had
/// already. Every rule above (what is cached, what is not, the accepted
/// interleaving) is this function's; the command is the delegation wrapper.
///
/// Blocking: never call it from the webview thread. `probe_agent_cli` is the
/// path that owns that concern.
pub(crate) fn probe_cached(program: &str) -> CliProbe {
    let program = program.trim().to_lowercase();
    if let Some(hit) = cache().lock().unwrap().get(&program) {
        return hit.clone();
    }
    let (probe, complete) = probe_uncached(&program);
    if probe.available && complete {
        cache().lock().unwrap().insert(program, probe.clone());
    }
    probe
}

#[cfg(test)]
mod tests {
    use super::*;
    use std::cell::RefCell;

    const CLAUDE_STYLE_HELP: &str = "\
  --mcp-config <configs...>             Load MCP servers\n\
  --model <model>                       Model for the current session. Provide\n\
                                        an alias for the latest model (e.g.\n\
                                        'fable', 'opus', or 'sonnet') or a\n\
                                        model's full name (e.g.\n\
                                        'claude-fable-5').\n\
  -n, --name <name>                     Set a display name\n";

    /// Shaped like an `opencode --help` page — a fixture, not a transcript
    /// (constraint 3: no agent CLI is run to collect one). What it has to be
    /// is *representative on one point*: its `--model` section yields a
    /// non-empty help-parsed list (`gpt-5.1`), so "the enumerator replaced it"
    /// and "the enumerator fell back to it" are both observable.
    const OPENCODE_STYLE_HELP: &str = "\
  -h, --help            Print help\n\
  -m, --model <model>   Model to use, as a `provider/model` id (e.g.\n\
                        'opencode/gpt-5.1-codex'), or a configured alias\n\
                        like 'gpt-5.1'.\n\
  -s, --session <id>    Resume a session\n";

    /// `opencode models` output. The docs give the id format ("in the form of
    /// `provider/model`") but not the layout, so this fixture deliberately
    /// wraps the ids in the kinds of line a listing command might also print —
    /// the parser has to drop those rather than admit them.
    const OPENCODE_MODEL_LIST: &str = concat!(
        "Fetching models from models.dev\n",
        "\n",
        "anthropic/claude-sonnet-4-5\n",
        "anthropic/claude-haiku-4-5\n",
        "opencode/deepseek-v4-flash-free\n",
        "openrouter/anthropic/claude-sonnet-4\n",
        "\u{1b}[32mopencode/gpt-5.1-codex\u{1b}[0m\n",
        "anthropic/claude-sonnet-4-5\n",
        "See https://models.dev for the full catalog.\n",
    );

    /// The same command, if its output were TAB-COLUMNED — a layout the docs
    /// neither state nor rule out, and the one that broke the parser's
    /// degrade-safety claim in review (#939). Also a fixture, not a transcript.
    const OPENCODE_TABBED_LIST: &str = concat!(
        "provider\tmodel\tcost\n",
        "anthropic/claude-sonnet-4-5\tClaude Sonnet 4.5\t$3/$15\n",
        "opencode/deepseek-v4-flash-free\tDeepSeek V4 Flash Free\tfree\n",
    );

    fn opencode_ids() -> Vec<String> {
        ["anthropic/claude-sonnet-4-5", "anthropic/claude-haiku-4-5", "opencode/deepseek-v4-flash-free", "openrouter/anthropic/claude-sonnet-4", "opencode/gpt-5.1-codex"]
            .iter()
            .map(|s| s.to_string())
            .collect()
    }

    #[test]
    fn parses_claude_style_quoted_aliases() {
        let help = CLAUDE_STYLE_HELP;
        let models = parse_models_from_help(help);
        assert!(models.contains(&"fable".to_string()));
        assert!(models.contains(&"opus".to_string()));
        assert!(models.contains(&"sonnet".to_string()));
        assert!(models.contains(&"claude-fable-5".to_string()));
        assert!(!models.iter().any(|m| m == "name"), "must not leak the next option: {models:?}");
    }

    #[test]
    fn parses_copilot_style_bare_ids() {
        let help = "\
  --model MODEL        Set the AI model. Pass auto to pick automatically.\n\
                       Available: gpt-5.2, claude-sonnet-4.6, claude-haiku-4.5,\n\
                       gpt-5.3-codex\n\
  --no-color           Disable color\n";
        let models = parse_models_from_help(help);
        for m in ["gpt-5.2", "claude-sonnet-4.6", "claude-haiku-4.5", "gpt-5.3-codex"] {
            assert!(models.contains(&m.to_string()), "missing {m} in {models:?}");
        }
        assert!(!models.iter().any(|m| m == "no-color"), "next option leaked: {models:?}");
    }

    #[test]
    fn no_model_section_yields_empty() {
        assert!(parse_models_from_help("usage: foo [-h]").is_empty());
    }

    #[test]
    fn parses_a_provider_slash_model_listing() {
        let models = parse_models_from_list(OPENCODE_MODEL_LIST);
        assert_eq!(models, opencode_ids(), "ids in listed order, ANSI stripped, repeats dropped");
        assert!(!models.iter().any(|m| m.contains("models.dev")), "a URL is not an id: {models:?}");
        assert!(!models.iter().any(|m| m == "Fetching"), "prose leaked: {models:?}");
    }

    #[test]
    fn an_unrecognised_listing_yields_no_models() {
        // The failure mode that matters: a layout this parser has never seen
        // must produce NOTHING (so the caller keeps what it had), never a
        // half-scraped list of words.
        assert!(parse_models_from_list("No providers configured. Run `opencode auth login` first.\n").is_empty());
        assert!(parse_models_from_list("").is_empty());
    }

    #[test]
    fn a_tab_columned_listing_yields_clean_ids_never_a_splice() {
        // #939 review. A tab is a control byte AND a column separator: deleting
        // it glues the id to the next column into `…-4-5Claude`, which is
        // id-SHAPED, non-empty, and therefore promoted over the help-parsed
        // list and to the head of the picker.
        let models = parse_models_from_list(OPENCODE_TABBED_LIST);
        assert_eq!(
            models,
            vec!["anthropic/claude-sonnet-4-5".to_string(), "opencode/deepseek-v4-flash-free".to_string()],
            "the id extracts from its column; the rest of the row is not part of it"
        );
        for m in &models {
            assert!(
                !m.contains("Claude") && !m.contains("DeepSeek"),
                "a display-name column was spliced onto an id: {m}"
            );
        }
    }

    #[test]
    fn a_sequence_inside_a_token_splits_it_rather_than_healing_it() {
        // The same rule as the tab, for the other kind of removal: what is
        // taken out has to separate. Yielding nothing is the safe direction;
        // yielding a repaired-looking token is not.
        assert!(
            parse_models_from_list("anthro\u{1b}[0mpic/claude-sonnet-4-5\n").is_empty(),
            "a token interrupted mid-way must not be stitched back together"
        );
    }

    #[test]
    fn opencode_takes_its_models_from_the_models_subcommand() {
        let (probe, complete) = probe_with("opencode", |_program, args| match args {
            "--help" => Ok(OPENCODE_STYLE_HELP.to_string()),
            "models" => Ok(OPENCODE_MODEL_LIST.to_string()),
            other => panic!("probed an unexpected command: {other}"),
        });
        assert!(probe.available);
        assert_eq!(probe.models, opencode_ids());
        assert!(
            !probe.models.iter().any(|m| m == "gpt-5.1"),
            "what the CLI itself reports replaces what its help prose suggested: {:?}",
            probe.models
        );
        assert!(complete, "an answer from the CLI's own enumerator is the complete one");
    }

    #[test]
    fn a_tab_columned_listing_never_reaches_the_picker_as_a_splice() {
        // The same fixture through the probe seam, because THIS is where a
        // mangled id does its damage: a non-empty parse replaces the
        // help-parsed list, so junk here outranks the honest fallback.
        let (probe, complete) = probe_with("opencode", |_program, args| match args {
            "--help" => Ok(OPENCODE_STYLE_HELP.to_string()),
            _ => Ok(OPENCODE_TABBED_LIST.to_string()),
        });
        assert!(complete);
        assert_eq!(
            probe.models,
            vec!["anthropic/claude-sonnet-4-5".to_string(), "opencode/deepseek-v4-flash-free".to_string()]
        );
    }

    #[test]
    fn the_opencode_enumerator_asks_for_models_and_nothing_else() {
        // Its own test rather than a tail assertion on another one: a pin that
        // only runs after several unrelated asserts have passed is a pin no
        // red round ever reaches (#939 review).
        let calls = RefCell::new(Vec::new());
        let _ = probe_with("opencode", |program, args| {
            calls.borrow_mut().push(format!("{program} {args}"));
            Ok(String::new())
        });
        let seen: Vec<String> = calls.borrow().clone();
        assert_eq!(
            seen,
            vec!["opencode --help".to_string(), "opencode models".to_string()],
            "exactly `models` — never `models --refresh`, which re-pulls models.dev behind the human's back"
        );
    }

    #[test]
    fn a_failed_models_subcommand_falls_back_to_help_and_stays_available() {
        let (probe, complete) = probe_with("opencode", |_program, args| match args {
            "--help" => Ok(OPENCODE_STYLE_HELP.to_string()),
            _ => Err("`opencode models` timed out".into()),
        });
        assert!(probe.available, "an installed CLI whose list command failed is still installed");
        assert!(probe.error.is_none(), "and carries no error the launcher would refuse a launch on: {:?}", probe.error);
        assert_eq!(probe.models, vec!["gpt-5.1".to_string()], "falls back to the help-parsed list");
        assert!(!complete, "a fallback list must not be cached for the rest of the app run");
    }

    #[test]
    fn an_unreadable_models_listing_leaves_the_help_parsed_list_alone() {
        let (probe, complete) = probe_with("opencode", |_program, args| match args {
            "--help" => Ok(OPENCODE_STYLE_HELP.to_string()),
            _ => Ok("No providers configured.\n".to_string()),
        });
        assert!(probe.available);
        assert_eq!(probe.models, vec!["gpt-5.1".to_string()], "an empty parse must not empty the list");
        assert!(!complete, "nor may an empty enumeration be cached as the answer");
    }

    #[test]
    fn a_cli_without_an_enumerator_runs_only_help() {
        let calls = RefCell::new(Vec::new());
        let (probe, complete) = probe_with("claude", |program, args| {
            calls.borrow_mut().push(format!("{program} {args}"));
            Ok(if args == "--help" { CLAUDE_STYLE_HELP.to_string() } else { String::new() })
        });
        assert!(probe.models.contains(&"sonnet".to_string()));
        assert!(complete, "a CLI with nothing to enumerate is answered in full by its help");
        let seen: Vec<String> = calls.borrow().clone();
        assert_eq!(seen, vec!["claude --help".to_string()], "claude has no list command; spawning one costs a subprocess for nothing");
    }

    #[test]
    fn a_missing_program_never_reaches_its_enumerator() {
        let calls = RefCell::new(Vec::new());
        let (probe, complete) = probe_with("opencode", |_program, args| {
            calls.borrow_mut().push(args.to_string());
            Err("'opencode' was not found on PATH".into())
        });
        assert!(!probe.available);
        assert!(probe.models.is_empty());
        assert!(!complete, "and a missing CLI is never cached, so installing it mid-session works");
        assert_eq!(calls.borrow().len(), 1, "nothing to enumerate for a CLI that isn't installed");
    }

    /// pi's exact `--list-models` table, generated by the vendor's own
    /// algorithm (`SOURCE` `list-models.ts:83-114` at the pin in
    /// `docs/design/pi.md`: padEnd every column to its width, join with two
    /// spaces) over four rows — this is the LAYOUT pi prints, pasted verbatim;
    /// the row values are representative, since constraint 3 forbids running a
    /// real pi to collect one. Note the trailing spaces: the last column is
    /// padEnd'd too, so every row line ends in spaces the header does not have.
    const PI_MODEL_TABLE: &str = concat!(
        "provider    model               context  max-out  thinking  images\n",
        "anthropic   claude-haiku-4-5    200K     64K      yes       no    \n",
        "anthropic   claude-sonnet-4-5   200K     64K      yes       yes   \n",
        "google      gemini-3-pro        1M       64K      yes       yes   \n",
        "openrouter  z-ai/glm-5.3-flash  131K     32K      yes       no    \n",
    );

    fn pi_ids() -> Vec<String> {
        [
            "anthropic/claude-haiku-4-5",
            "anthropic/claude-sonnet-4-5",
            "google/gemini-3-pro",
            "openrouter/z-ai/glm-5.3-flash",
        ]
        .iter()
        .map(|s| s.to_string())
        .collect()
    }

    /// pi's real `--help` around `--model` (`SOURCE` `args.ts:279-282`). It
    /// names NO model — so the help parse yields nothing, and the enumerator is
    /// pi's only source of ids. That is why pi gets an `ENUMERATORS` row at all.
    const PI_STYLE_HELP: &str = "\
Options:
  --provider <name>              Provider name (default: google)
  --model <pattern>              Model pattern or ID (supports \"provider/id\" and optional \":<thinking>\")
  --api-key <key>                API key (defaults to env vars)
";

    /// The load-error warning pi can print BEFORE the table
    /// (`SOURCE` `list-models.ts:36`: `chalk.yellow(...)` to stderr — here on
    /// stdout, as it arrives if the streams ever merge). The colour codes wrap
    /// the whole message, so the reset lands on the SECOND physical line.
    const PI_LOAD_WARNING: &str = concat!(
        "\u{1b}[33mWarning: errors loading models.json:\n",
        "models.json:3:5 unknown provider \"acme\"\u{1b}[39m\n",
    );

    #[test]
    fn parses_pi_model_table_into_provider_slash_model_ids() {
        let models = parse_models_from_table(PI_MODEL_TABLE);
        assert_eq!(models, pi_ids(), "one id per row, assembled from the two id columns, in listed order");
        assert!(!models.iter().any(|m| m == "provider/model"), "the header row is not a model: {models:?}");
        assert!(
            !models.iter().any(|m| m.ends_with("200K") || m.ends_with("64K") || m.ends_with("yes") || m.ends_with("no")),
            "no context/max-out/thinking column leaked into an id: {models:?}"
        );
    }

    #[test]
    fn a_warning_line_before_the_pi_header_yields_nothing_extra() {
        // The warning lines are neither a header nor id-shaped rows, so they
        // contribute nothing — and the table after them still parses fully.
        assert!(
            parse_models_from_table(PI_LOAD_WARNING).is_empty(),
            "the warning alone yields nothing"
        );
        assert_eq!(parse_models_from_table(&format!("{PI_LOAD_WARNING}{PI_MODEL_TABLE}")), pi_ids());
    }

    #[test]
    fn a_tab_columned_pi_table_yields_nothing_never_a_splice() {
        // plain_line turns a tab into ONE space, which is not a two-space run:
        // a tab-columned table (a layout pi does not print, but a terminal or
        // a future rewrite could) has its rows collapse into a single column
        // each, so nothing is kept. What must never happen is the #939 splice —
        // `anthropic` glued to `claude-haiku-4-5` into one id-shaped token.
        const TABBED: &str = concat!(
            "provider\tmodel\tcontext\tmax-out\tthinking\timages\n",
            "anthropic\tclaude-haiku-4-5\t200K\t64K\tyes\tno\n",
            "openrouter\tz-ai/glm-5.3-flash\t131K\t32K\tyes\tno\n",
        );
        let models = parse_models_from_table(TABBED);
        assert!(models.is_empty(), "a tab column layout yields nothing: {models:?}");
        for m in &models {
            assert!(!m.contains("anthropicclaude") && !m.contains("anthropic claude"), "no splice: {m}");
        }
    }

    #[test]
    fn the_no_match_and_no_models_messages_yield_nothing() {
        // `SOURCE` list-models.ts:42 (formatNoModelsAvailableMessage — the docs
        // paths are install-dependent, so the fixture spells them loosely) and
        // :53. Neither contains the header, so neither reaches a column split.
        assert!(parse_models_from_table("No models matching \"glm\"\n").is_empty());
        assert!(parse_models_from_table(
            "No models available. Use /login to log into a provider via OAuth or API key. See:\n  providers.md\n  models.md\n"
        )
        .is_empty());
        assert!(parse_models_from_table("").is_empty());
    }

    #[test]
    fn a_post_header_line_whose_columns_are_not_ids_is_dropped() {
        // A fixture, not a transcript: pi prints nothing after the table today,
        // but the parser's contract is under-recognise rather than manufacture,
        // so a prose line that ever followed the table must not become a model
        // — `See` is not an id and `https://…` carries an empty `/`-segment.
        const WITH_FOOTER: &str = concat!(
            "provider    model               context  max-out  thinking  images\n",
            "See  https://docs.pi.dev  for the catalog\n",
            "anthropic   claude-haiku-4-5    200K     64K      yes       no    \n",
        );
        assert_eq!(parse_models_from_table(WITH_FOOTER), vec!["anthropic/claude-haiku-4-5".to_string()]);
    }

    #[test]
    fn pi_enumerates_through_list_models_and_nothing_else() {
        let calls = RefCell::new(Vec::new());
        let _ = probe_with("pi", |program, args| {
            calls.borrow_mut().push(format!("{program} {args}"));
            Ok(if args == "--help" { PI_STYLE_HELP.to_string() } else { PI_MODEL_TABLE.to_string() })
        });
        assert_eq!(
            calls.borrow().clone(),
            vec!["pi --help".to_string(), "pi --list-models".to_string()],
            "exactly `--list-models`, never with a search pattern"
        );
    }

    #[test]
    fn pi_enumerated_models_replace_the_help_parsed_list() {
        let (probe, complete) = probe_with("pi", |_program, args| match args {
            "--help" => Ok(PI_STYLE_HELP.to_string()),
            "--list-models" => Ok(PI_MODEL_TABLE.to_string()),
            other => panic!("probed an unexpected command: {other}"),
        });
        assert!(probe.available);
        assert_eq!(probe.models, pi_ids());
        assert!(complete, "pi's own table is the complete answer");
    }

    #[test]
    fn a_timed_out_pi_listing_falls_back_to_help_and_stays_uncached() {
        // The 8 s vs 15 s budget: pi's cold models.json refresh can lose our
        // probe's race. The probe must still report pi as installed, and the
        // incomplete answer must not be cached (the caller-side test for the
        // same rule is `worthKeeping` in test/modelcatalog.test.ts).
        let (probe, complete) = probe_with("pi", |_program, args| match args {
            "--help" => Ok(PI_STYLE_HELP.to_string()),
            _ => Err("`pi --list-models` timed out".into()),
        });
        assert!(probe.available, "an installed CLI whose list command timed out is still installed");
        assert!(probe.error.is_none(), "no error the launcher would refuse a launch on: {:?}", probe.error);
        assert!(probe.models.is_empty(), "pi's --help names no model, so there is nothing to fall back to");
        assert!(!complete, "a timed-out enumeration must not be cached for the rest of the app run");
    }
}
