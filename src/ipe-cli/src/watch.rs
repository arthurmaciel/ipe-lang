//! `ipe watch`.
//!
//! The salsa-aware orchestrator that wires [`ipe_watch`]'s salsa-agnostic
//! primitives (confined watcher, debounce, process supervisor) to THIS
//! crate's warm compile pipeline. This is the first real CONSUMER of
//! incremental compilation's speed benefit — a naive "re-run `ipe build`
//! from scratch on every save" watch mode would defeat the entire point of
//! the salsa port.
//!
//! Decision record: `docs/adr/0032-salsa-incremental-compilation-phase1.md`.
//!
//! ## Architecture
//!
//! Three threads plus the orchestrator (this module's `run`):
//!
//! 1. **notify watcher thread** (owned by the `notify::Watcher` handle) —
//!    pushes every IN-SCOPE raw path change onto an `mpsc` channel. The
//!    [`ipe_watch::WatchScope::is_relevant`] filter runs INSIDE the event
//!    callback, so an excluded-dir storm never reaches the channel at all.
//!    The callback ALSO rejects `EventKind::Access` (open/read)
//!    and `EventKind::Other` before that filter even runs — load-bearing,
//!    not an optimisation: `resolve_project_sources` opens every in-scope
//!    file on every rebuild, and without this exclusion that OPEN is
//!    itself an observable event that would queue another rebuild forever.
//!    One Access sub-variant, `Close(Write)`, is deliberately EXEMPTED from
//!    that rejection — it is the write-completion proof a debounce window
//!    alone cannot substitute for; see the callback's own doc comment for
//!    why.
//! 2. **coalesce thread** — [`ipe_watch::coalesce_loop`] turns that raw
//!    stream into settled batches (the debounce half).
//! 3. **compile worker thread** (spawned fresh per rebuild cycle) — holds a
//!    CLONED [`ipe_db::IpeDatabase`] handle and runs [`compile_prepared`]
//!    inside [`salsa::Cancelled::catch`]. The orchestrator thread never runs
//!    a salsa query itself; it only mutates inputs (which is what makes a
//!    superseding edit cancel the in-flight worker — see the cancellation
//!    section below).
//!
//! The orchestrator drains one unified `mpsc::Receiver<OrchestratorEvent>`
//! that both the coalesce thread and every worker/cargo-wait thread feed —
//! a single blocking `recv()` with **no busy-polling**, and no risk of two
//! event sources racing on separate wakeups.
//!
//! ## Cancellation, and why it needs no extra machinery
//!
//! Salsa's `#[salsa::input]` setters require `&mut IpeDatabase` (routed
//! through `zalsa_mut()`), which — per `salsa::Storage`'s own documented
//! contract (verified against the pinned `salsa=0.27.2` source,
//! `src/storage.rs`'s `cancel_others`) — sets a cancellation flag and BLOCKS
//! until every other `Storage` handle (a `.clone()` of the database, exactly
//! what a compile worker holds) has been dropped. A query running on a
//! cancelled snapshot unwinds via `panic::resume_unwind(Cancelled)` the next
//! time it checks (every tracked-function boundary — the `WillCheckCancellation`
//! event salsa's own test suite pins). So:
//!
//! - the orchestrator NEVER calls `sync_source_root` while ALSO holding a
//!   worker's clone alive on its own thread — it hands the clone to the
//!   worker THREAD and keeps only the original `db_main` on the orchestrator
//!   thread;
//! - when a new settled batch arrives mid-build, `sync_source_root(&mut
//!   db_main, …)` is called immediately — this call blocks (invisibly, from
//!   the orchestrator's point of view) until the worker thread's query
//!   unwinds and drops its cloned `Storage`, then returns; the worker thread
//!   observes `Cancelled` via `salsa::Cancelled::catch`, reports it, and
//!   exits;
//! - the orchestrator then spawns a FRESH worker against the just-synced
//!   (latest) state.
//!
//! This is exactly rust-analyzer's own cancellation pattern, and it needs
//! zero new synchronisation primitives beyond what salsa already provides.
//!
//! `cargo build` cancellation (never overlapping cargo builds) uses the
//! portable equivalent for a plain OS process: the
//! orchestrator holds the `Child` handle directly and calls `.kill()` on a
//! superseding batch; a dedicated per-build "waiter" thread blocks on
//! `.wait()` and reports completion (or, if killed, a status the
//! orchestrator recognises as "superseded, not a real failure") through the
//! SAME unified event channel, tagged with a generation counter so a stale
//! completion from an already-superseded cycle is silently ignored rather
//! than raced against the new one.

use std::collections::BTreeMap;
use std::path::{Path, PathBuf};
use std::process::{Child, Command};
use std::sync::mpsc;
use std::sync::{Arc, Mutex};
use std::thread;
use std::time::{Duration, Instant};

use ipe_intern::Interner;

use crate::project;
use crate::{CliError, write_emitted_project};

/// A lifecycle notification from a running watch session.
///
/// Delivered synchronously (before the orchestrator moves on) through
/// [`WatchOptions::on_event`]. This is the seam integration tests use to
/// observe internal state transitions (exactly-once coalescing, red-build
/// preservation, cancellation) without racing wall-clock timing or
/// capturing stderr — and, incidentally, a reusable hook for a future
/// structured/`--json` watch log. The CLI path leaves `on_event` unset
/// (`None`), so it costs nothing there.
#[derive(Debug, Clone)]
pub enum WatchEvent {
    /// A settled batch triggered a NEW rebuild cycle. Exactly one of these
    /// fires per coalesced batch, never per raw filesystem event.
    RebuildStarted { generation: u64 },
    /// `generation`'s compile finished with a compiler diagnostic — the
    /// running process (if any) is untouched (INV-3).
    CompileFailed { generation: u64 },
    /// `generation`'s compile was cancelled by a superseding edit
    /// — never reported to the end user, but observable here for tests.
    CompileCancelled { generation: u64 },
    /// `generation`'s `cargo build` failed — the running process (if any)
    /// is untouched (INV-3).
    CargoFailed { generation: u64 },
    /// `generation`'s `cargo build` was killed because a newer batch
    /// superseded it ("never overlapping cargo builds").
    CargoKilled { generation: u64 },
    /// `generation` reached [`ipe_watch::SupervisorState::apply_green`] and
    /// this was the outcome.
    Restarted {
        generation: u64,
        outcome: RestartOutcomeKind,
    },
    /// `generation`'s edit was classified appearance-only and hot-swapped into
    /// the running app via a `LiteralTable` patch — no cargo rebuild, no restart.
    /// `views` is the number of edited views patched. Only fires under
    /// `IPE_WATCH_HOT_APPEARANCE`.
    AppearanceHotSwapped { generation: u64, views: usize },
}

/// A test/observability-friendly mirror of [`ipe_watch::RestartOutcome`].
///
/// That type intentionally isn't `Clone` — it can carry a live [`Child`]
/// via [`ipe_watch::SupervisorState`] elsewhere in this module — so
/// [`WatchEvent`] carries this small `Clone`-able summary instead.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum RestartOutcomeKind {
    Spawned,
    UnchangedBinary,
    Restarted,
    RespawnedLastGood,
    NothingRunning,
}

/// Configuration for one `ipe watch` session. Every field has a sound
/// default via [`WatchOptions::new`]; the CLI layer (`run_watch` in
/// `lib.rs`) is the only place that overrides them from flags.
pub struct WatchOptions {
    pub entry: PathBuf,
    pub out_dir: PathBuf,
    pub runtime_dir: PathBuf,
    /// The port injected as `IPE_WEB_PORT` for the spawned child and probed
    /// for `/_ipe/readyz` when the emitted project is detected as a
    /// Ipe.Web app. Harmless (ignored) for every other app shape.
    pub port: u16,
    pub debounce: ipe_watch::DebounceConfig,
    pub restart_timeouts: ipe_watch::RestartTimeouts,
    /// The resolved `cargo` executable each rebuild spawns. The CLI layer
    /// resolves it once (fail-closed) before the loop starts and stores the
    /// path here; the default is the bare name `cargo`, deferring to `PATH`
    /// resolution for callers that do not pre-resolve.
    pub cargo_path: PathBuf,
    /// Optional lifecycle observer — see [`WatchEvent`]. `None` on the CLI
    /// path.
    pub on_event: Option<Arc<dyn Fn(WatchEvent) + Send + Sync>>,
    /// Suppress progress chatter — only warnings and errors are printed.
    /// Passes `-q` to cargo and skips the lifecycle status lines.
    pub quiet: bool,
    /// DEV-ONLY blue-green cutover. When set, `ipe watch` puts a persistent
    /// front proxy on `port` and runs each rebuilt binary behind it on a fresh
    /// internal loopback port, cutting traffic over once the new binary passes
    /// readiness — so a rebuild never drops the browser's connection. The CLI
    /// path sets this on by default (see [`crate::bluegreen_enabled`]; opt out
    /// with `IPE_WATCH_NO_BLUEGREEN`); the raw [`WatchOptions::new`] default is
    /// off (the direct-bind, kill-old-then-spawn-new path) for a library caller
    /// that has not chosen. Never compiled into a release binary or an emitted
    /// app.
    pub bluegreen: bool,
    /// DEV-ONLY state-reset escape hatch. When set, the next spawned child
    /// receives `IPE_WEB_RESET_STATE=1`, which makes the runtime skip the
    /// session-checkpoint hydration and force every returning session to a fresh
    /// `init` for the lifetime of that process. The flag is off by default (the
    /// additive-preserve algorithm runs normally). Exposed as `ipe watch
    /// --reset-state`. Never compiled into a release binary.
    pub reset_state: bool,
}

impl WatchOptions {
    #[must_use]
    pub fn new(entry: PathBuf, out_dir: PathBuf, runtime_dir: PathBuf) -> Self {
        Self {
            entry,
            out_dir,
            runtime_dir,
            port: 8000,
            debounce: ipe_watch::DebounceConfig::default(),
            restart_timeouts: ipe_watch::RestartTimeouts::for_dev_watch(),
            cargo_path: PathBuf::from("cargo"),
            on_event: None,
            quiet: false,
            bluegreen: false,
            reset_state: false,
        }
    }
}

fn emit(opts: &WatchOptions, event: WatchEvent) {
    if let Some(cb) = &opts.on_event {
        cb(event);
    }
}

/// Render a watch lifecycle line with 2-space gutter and optional colour.
/// `role` selects the semantic colour: `Info`, `Success`, or `Failure`.
#[derive(Clone, Copy)]
enum WatchRole {
    /// Informational status: building, watching, change detected.
    Info,
    /// A successful outcome: app started, app reloaded.
    Success,
    /// A failure outcome: build failed, readiness failed.
    Failure,
}

fn watch_line(text: &str, role: WatchRole) -> String {
    let p = crate::style::Palette::for_stream(&std::io::stderr());
    let (colour, glyph, reset) = match role {
        WatchRole::Info => (p.dim, "", p.reset),
        WatchRole::Success => (p.green, "", p.reset),
        // A failed rebuild leaves the last-good binary running, so it is a soft
        // warning, not a hard stop — a calm light yellow, never alarming red.
        WatchRole::Failure => (p.bright_yellow, crate::style::glyph::FAIL, p.reset),
    };
    let prefix = if glyph.is_empty() {
        format!("{colour}{}{reset}", crate::style::GUTTER)
    } else {
        format!("{}{colour}{glyph}{reset} ", crate::style::GUTTER)
    };
    format!("{prefix}{text}")
}

/// Per-phase wall-clock timing for ONE rebuild cycle, printed to stderr as a
/// guttered breakdown when `IPE_WATCH_TIMING=1` — a diagnostic for locating
/// where a rebuild's wall-clock goes.
///
/// Off by default: [`RebuildTimings::enabled`] reads the env gate ONCE at
/// cycle start; when unset, the `report` is a no-op and the per-phase
/// `Instant` reads it guards cost nothing, so the normal `ipe watch` path is
/// unaffected.
///
/// Each field is the wall-clock of a real phase boundary in the orchestrator
/// (measured with [`Instant`], never a fabricated split). Phases that run on a
/// helper thread (compile, cargo) measure their own span there and hand the
/// measured [`Duration`] back through the event channel, so the orchestrator
/// records a real elapsed time rather than inferring one from event arrival.
#[derive(Debug, Default, Clone, Copy)]
struct RebuildTimings {
    enabled: bool,
    /// When this cycle's `FsBatch` was received — the anchor the total is
    /// measured against.
    cycle_start: Option<Instant>,
    /// edit → settled batch (the coalescer's quiescence window). `None` for
    /// the initial kickoff cycle and resolve-retry cycles, which carry no
    /// first-event timestamp.
    settle: Option<Duration>,
    /// `resolve_project_sources` + FFI-catalog prep + `sync_source_root`
    /// (input mutation into the warm salsa db) — the orchestrator-thread work
    /// of the `FsBatch` arm before the compile worker is spawned.
    resolve: Option<Duration>,
    /// `compile_prepared`: canon + link + typecheck + lower + emit-IR, the
    /// salsa warm-compile. Measured on the worker thread.
    compile: Option<Duration>,
    /// `write_emitted_project`: serialise the in-memory emitted project to the
    /// out-dir (`src/*.rs`, `Cargo.toml`, prune).
    write: Option<Duration>,
    /// `cargo build`: compile + link the emitted crate. One number — the JSON
    /// stream does not separate rustc codegen from the final link step, so it
    /// is reported whole (see the report's own note).
    cargo: Option<Duration>,
    /// Kill the old child + spawn the new one + readiness probe
    /// (`SupervisorState::apply_green`).
    restart: Option<Duration>,
}

impl RebuildTimings {
    /// Start a cycle's timing. Reads the `IPE_WATCH_TIMING` gate once; a value
    /// of exactly `1` enables the breakdown, anything else (unset included)
    /// leaves it off.
    fn start(settle: Option<Duration>) -> Self {
        let enabled = std::env::var("IPE_WATCH_TIMING").as_deref() == Ok("1");
        Self {
            enabled,
            cycle_start: enabled.then(Instant::now),
            settle,
            ..Self::default()
        }
    }

    /// The sum of every recorded phase — the accounted-for wall-clock. The
    /// residual against the observed total is everything the phase splits miss
    /// (channel hops between the orchestrator and its worker/waiter threads,
    /// scheduling latency).
    fn summed(&self) -> Duration {
        [
            self.settle,
            self.resolve,
            self.compile,
            self.write,
            self.cargo,
            self.restart,
        ]
        .into_iter()
        .flatten()
        .sum()
    }

    /// Render the breakdown to stderr, guttered, one phase per line in ms plus
    /// the observed total and the residual (total − Σ phases), so a reader can
    /// see how much wall-clock the phase splits fail to account for (channel
    /// hops, scheduling). A no-op when the gate is off.
    fn report(&self, generation: u64) {
        if !self.enabled {
            return;
        }
        let Some(start) = self.cycle_start else {
            return;
        };
        let total = start.elapsed();
        let ms = |d: Option<Duration>| {
            d.map_or_else(
                || "     —".to_owned(),
                |d| format!("{:6.1}", d.as_secs_f64() * 1000.0),
            )
        };
        let residual = total.saturating_sub(self.summed());
        let body = format!(
            "[ipe watch timing] generation {generation}\n\
             settle    {} ms   (edit -> settled batch)\n\
             resolve   {} ms   (read sources + ffi + salsa sync)\n\
             compile   {} ms   (canon+link+typecheck+lower+emit-IR)\n\
             write     {} ms   (emit Rust project to disk)\n\
             cargo     {} ms   (cargo build: compile + link)\n\
             restart   {} ms   (kill old + spawn new + readiness)\n\
             --------\n\
             total     {:6.1} ms   (observed, FsBatch -> restart done)\n\
             residual  {:6.1} ms   (total - sum of phases)",
            ms(self.settle),
            ms(self.resolve),
            ms(self.compile),
            ms(self.write),
            ms(self.cargo),
            ms(self.restart),
            total.as_secs_f64() * 1000.0,
            residual.as_secs_f64() * 1000.0,
        );
        eprint!("\n{}\n", crate::style::gutter(&body));
    }
}

/// One resolved project snapshot — the ingredients [`compile_modules`]
/// (the one-shot driver) would consume, but returned to the CALLER instead
/// of immediately compiled, so `ipe watch` can re-resolve on every settled
/// batch and feed the result through a WARM, reused database via
/// `ipe_db::sync_source_root` rather than constructing a fresh one per
/// build. Deliberately mirrors `run_build`'s own manifest-resolution
/// dispatch (`crates/ipe/src/lib.rs`) without touching that code — the
/// one-shot entry points stay exactly as tested by the golden suite; this
/// is an independent, read-only duplicate of the RESOLUTION step only (no
/// compiler stage runs here).
pub(crate) struct ResolvedProject {
    pub(crate) sources: BTreeMap<Vec<String>, (PathBuf, String)>,
    pub(crate) discovered: Vec<project::DiscoveredModule>,
    pub(crate) entry_path: Vec<String>,
    pub(crate) blame_path: PathBuf,
    pub(crate) db_driver: ipe_backend_rust::DbDriver,
    /// The `[wasm] publicEnv` allowlist (empty for the no-manifest / sibling-
    /// discovery path — there is no manifest to declare one).
    pub(crate) wasm_public_env: Vec<String>,
    /// The sanitized Cargo package name for the emitted crate (from `package.ipe`
    /// name via [`ipe_backend_rust::sanitize_cargo_name`]). Empty string
    /// when no manifest is present (sibling-discovery path uses `"ipe-app"`).
    pub(crate) cargo_name: String,
}

/// Resolve `entry` (a `.ipe` file or a project directory) into a fresh
/// [`ResolvedProject`] by re-reading every relevant file from disk. Mirrors
/// `run_build`'s dispatch: directory → `package.ipe` inside it; `.ipe` → walk
/// up for a manifest, else sibling discovery.
///
/// `entry_text_override`, when given, shadows the entry `.ipe` file's disk
/// bytes in the no-manifest branch — the LSP hands the unsaved editor
/// buffer here so module-path discovery follows what the author sees, not
/// stale disk state. `ipe watch` always passes `None` (disk is its truth).
///
/// # Errors
/// [`CliError::Io`] on any filesystem failure; [`CliError::Pipeline`] if the
/// entry file itself fails to parse (needed only to learn its declared
/// module path in the no-manifest case).
pub(crate) fn resolve_project_sources(
    entry: &Path,
    entry_text_override: Option<&str>,
) -> Result<ResolvedProject, CliError> {
    let manifest_path = if entry.is_dir() {
        match project::manifest_in_dir(entry) {
            Some(manifest) => Some(manifest),
            None if project::migration_pending(entry) => {
                return Err(CliError::Usage(project::MIGRATE_CONFIG_HINT));
            }
            None => {
                return Err(CliError::Usage(
                    "directory supplied but no package.ipe found inside it",
                ));
            }
        }
    } else {
        crate::find_manifest_for_ipe_file(entry)
    };

    if let Some(manifest_path) = manifest_path {
        let manifest = project::parse_manifest(&manifest_path)?;
        let discovered = project::discover_modules(&manifest.src_root)?;
        let mut sources: BTreeMap<Vec<String>, (PathBuf, String)> = BTreeMap::new();
        for m in &discovered {
            let src = crate::io_bounded::read_to_string_capped(
                &m.path,
                crate::io_bounded::SOURCE_READ_CAP,
            )?;
            sources.insert(m.module_path.clone(), (m.path.clone(), src));
        }
        let cargo_name = ipe_backend_rust::sanitize_cargo_name(&manifest.name);
        // The entry defaults to `["Main"]`; a `programs` manifest routes its
        // (default) program's declared entry file through instead. Named
        // multi-program selection is a reported residual — see
        // `misc/docs/package-programs-design.md`.
        let entry_path = manifest.resolved_entry()?;
        return Ok(ResolvedProject {
            sources,
            discovered,
            entry_path,
            blame_path: manifest_path,
            db_driver: manifest.driver,
            wasm_public_env: manifest.wasm.public_env,
            cargo_name,
        });
    }

    // No manifest: sibling discovery, mirroring `build_with_sibling_discovery`.
    let source = match entry_text_override {
        Some(text) => text.to_owned(),
        None => {
            crate::io_bounded::read_to_string_capped(entry, crate::io_bounded::SOURCE_READ_CAP)?
        }
    };
    let mut name_interner = Interner::new();
    let parsed = ipe_parse::parse_module(&source, &mut name_interner).map_err(|diag| {
        CliError::Pipeline {
            file: entry.to_path_buf(),
            src: source.clone(),
            diag: Box::new(diag),
        }
    })?;
    let entry_module_path: Vec<String> = parsed
        .name
        .value
        .iter()
        .map(|s| name_interner.resolve(*s).unwrap_or_default().to_owned())
        .collect();
    let src_root = entry
        .parent()
        .filter(|p| p.is_dir())
        .unwrap_or_else(|| Path::new("."));
    let mut discovered = project::discover_modules(src_root)?;
    if !discovered
        .iter()
        .any(|m| m.module_path == entry_module_path)
    {
        discovered.push(project::DiscoveredModule {
            path: entry.to_path_buf(),
            module_path: entry_module_path.clone(),
        });
    }
    let mut sources: BTreeMap<Vec<String>, (PathBuf, String)> = BTreeMap::new();
    for m in &discovered {
        if m.module_path == entry_module_path {
            sources.insert(
                entry_module_path.clone(),
                (entry.to_path_buf(), source.clone()),
            );
        } else {
            let src = crate::io_bounded::read_to_string_capped(
                &m.path,
                crate::io_bounded::SOURCE_READ_CAP,
            )?;
            sources.insert(m.module_path.clone(), (m.path.clone(), src));
        }
    }
    Ok(ResolvedProject {
        sources,
        discovered,
        entry_path: entry_module_path,
        blame_path: entry.to_path_buf(),
        db_driver: ipe_backend_rust::DbDriver::Sqlite,
        wasm_public_env: Vec::new(),
        cargo_name: String::new(),
    })
}

/// The project root + entry directory a [`ipe_watch::WatchScope`] confines
/// itself to, derived from one resolved snapshot.
fn scope_roots(resolved: &ResolvedProject, entry: &Path) -> (PathBuf, PathBuf) {
    // The manifest's directory when a `package.ipe` is the blame path;
    // otherwise the blame path IS the entry file, so its parent is the source
    // root — matching `build_with_sibling_discovery`.
    if resolved.blame_path.file_name().and_then(|n| n.to_str())
        == Some(crate::package_manifest::PACKAGE_IPE)
    {
        let root = resolved
            .blame_path
            .parent()
            .map_or_else(|| PathBuf::from("."), Path::to_path_buf);
        (root.clone(), root)
    } else {
        let dir = entry
            .parent()
            .filter(|p| p.is_dir())
            .map_or_else(|| PathBuf::from("."), Path::to_path_buf);
        (dir.clone(), dir)
    }
}

/// One event on the orchestrator's unified channel. Carries a `generation`
/// on every variant whose completion could race a superseding cycle, so a
/// STALE completion (from a cycle the orchestrator has already moved past)
/// is recognisable and silently dropped rather than raced against the
/// current one.
enum OrchestratorEvent {
    /// A settled batch of filesystem changes — the coalescer's output.
    /// Carries no paths: `ipe watch` re-resolves the WHOLE project on every
    /// cycle (cheap — a directory walk over a bounded file set) and lets
    /// `sync_source_root`'s own byte-equal no-op boundary do the real
    /// dirty-vs-clean filtering, so there is no need to thread individual
    /// changed paths through the recompute step. `settle` carries the
    /// coalescer's edit→settled latency for `IPE_WATCH_TIMING` (`None` for the
    /// initial kickoff and resolve-retry cycles, which have no batch).
    FsBatch { settle: Option<Duration> },
    /// The compile worker for `generation` finished (successfully, with a
    /// compiler diagnostic, or cancelled). `compile` is the worker-measured
    /// wall-clock of `compile_prepared` (only meaningful for a Green/Red
    /// outcome; a cancelled cycle's time is not reported).
    CompileDone {
        generation: u64,
        outcome: CompileOutcome,
        compile: Duration,
    },
    /// The `cargo build` for `generation` finished (successfully, with a
    /// build failure, or was killed because it was superseded). `cargo` is the
    /// waiter-measured wall-clock from spawn to exit.
    CargoDone {
        generation: u64,
        outcome: CargoOutcome,
        cargo: Duration,
    },
    /// An external caller requested a clean shutdown (see [`WatchHandle`]).
    /// Used by tests and any future embedder that needs to stop a watch
    /// session programmatically rather than only on Ctrl-C.
    Shutdown,
}

/// Upper bound on how long [`WatchHandle::stop`] (and, transitively,
/// [`WatchHandle`]'s `Drop` safety net) will block waiting for the
/// orchestrator thread to confirm it has actually finished tearing down
/// (child process killed/reaped, watcher + coalesce threads joined) —
/// never an unbounded wait (the "every long-running command is timeout-bounded"
/// rule: every long-running command is timeout-bounded). Generously above the realistic worst case: a
/// `graceful_stop` of [`ipe_watch::RestartTimeouts::default`]'s 3 s, plus
/// slack for the cargo-kill waiter's poll loop, the compile worker's salsa
/// unwind, and the coalesce thread's join — all of which are themselves
/// individually bounded and normally complete in well under a second once
/// shutdown starts (the dev-watch `graceful_stop`,
/// [`ipe_watch::RestartTimeouts::for_dev_watch`], is a fraction of a second).
const SHUTDOWN_WAIT_BUDGET: Duration = Duration::from_secs(20);

/// Delay before retrying a cycle whose `resolve_project_sources` call
/// failed. A transient resolve failure (mid-save partial write, a file
/// momentarily unreadable during an editor's atomic rename) has no
/// guarantee of a follow-up filesystem event to retry it, so the cycle
/// schedules its own retry rather than losing the save until the next
/// unrelated edit.
const RESOLVE_RETRY_DELAY: Duration = Duration::from_millis(250);

/// Schedule one follow-up [`OrchestratorEvent::FsBatch`] after
/// [`RESOLVE_RETRY_DELAY`] — the recovery path for a `resolve_project_sources`
/// failure. Without this, a transient failure has no other route back into
/// the orchestrator's event loop: the triggering save is lost until an
/// unrelated future filesystem event happens to arrive.
fn schedule_resolve_retry(evt_tx: &mpsc::Sender<OrchestratorEvent>) {
    let retry_tx = evt_tx.clone();
    thread::spawn(move || {
        thread::sleep(RESOLVE_RETRY_DELAY);
        let _ = retry_tx.send(OrchestratorEvent::FsBatch { settle: None });
    });
}

/// A handle to a running [`spawn`]ed watch session.
///
/// Lets the caller request a clean shutdown from another thread — the seam
/// integration tests use to stop `ipe watch` deterministically instead of
/// relying on a process signal.
///
/// `Drop` is a genuine safety net, not merely `stop()` called for you: an
/// embedder that lets a `WatchHandle` fall out of scope WITHOUT calling
/// `stop()` first — a bug in the embedder's own code, a panic unwinding
/// through a scope that holds one, an early `return`/`?` — must never leak
/// the supervised child process (a whole spawned `ipe-app` server binding a
/// real port) as an orphan. `stop()` and `Drop::drop` therefore share one
/// synchronous, bounded implementation: signal the orchestrator, then block
/// (up to [`SHUTDOWN_WAIT_BUDGET`]) until it confirms teardown is done —
/// not merely requested.
pub struct WatchHandle {
    stop_tx: mpsc::Sender<()>,
    /// Signalled by the orchestrator thread's own wrapper (see [`spawn`])
    /// once `run_inner` has returned — i.e. AFTER `SupervisorState::shutdown`
    /// has killed/reaped the supervised child and every helper thread has
    /// been joined. `Mutex<Option<..>>` rather than a bare `Receiver` so
    /// `stop()` can take `&self` (matching its pre-existing public
    /// signature) while still being able to drain the receiver exactly
    /// once; a second `stop()`/`Drop` call after the first successful wait
    /// finds `None` and is a harmless no-op, matching `stop()`'s existing
    /// idempotency contract.
    done_rx: Mutex<Option<mpsc::Receiver<()>>>,
}

impl WatchHandle {
    /// Request a clean shutdown and BLOCK (bounded by
    /// [`SHUTDOWN_WAIT_BUDGET`]) until the orchestrator thread confirms it
    /// has actually finished — not merely until the request was sent.
    /// Idempotent: a second call, or a call after `Drop` already waited
    /// (impossible through the public API, since `Drop` consumes `self`,
    /// but relevant to `Drop`'s own internal reuse of this method) is a
    /// harmless no-op.
    pub fn stop(&self) {
        let _ = self.stop_tx.send(());
        self.wait_for_shutdown();
    }

    /// Block until the orchestrator's done-signal arrives, or
    /// [`SHUTDOWN_WAIT_BUDGET`] elapses — whichever comes first. Draining
    /// (`Option::take`) the receiver makes this safe to call more than
    /// once: every call after the first successful wait (or a prior
    /// `Drop`) is a no-op.
    fn wait_for_shutdown(&self) {
        let mut guard = self
            .done_rx
            .lock()
            .unwrap_or_else(std::sync::PoisonError::into_inner);
        if let Some(rx) = guard.take() {
            let _ = rx.recv_timeout(SHUTDOWN_WAIT_BUDGET);
        }
    }
}

impl Drop for WatchHandle {
    /// The safety net described on the type itself: guarantees the
    /// supervised child process is torn down even when the embedder never
    /// called `stop()` — including when a panic unwinds through a scope
    /// holding a `WatchHandle`. Rust always runs `Drop` during ordinary
    /// unwinding (this is not the `abort` panic strategy), so this fires on
    /// both the "forgot to call `stop()`" and the "panicked while holding
    /// one" cases the review flagged. `stop_tx.send` and
    /// `recv_timeout` are both plain, synchronous, non-blocking-by-default
    /// calls (no `.await`, nothing that needs an async runtime), so this is
    /// sound to run directly from `drop`.
    fn drop(&mut self) {
        let _ = self.stop_tx.send(());
        self.wait_for_shutdown();
    }
}

/// Spawn `ipe watch` on its own thread, returning a join handle plus a
/// [`WatchHandle`] the caller can use to stop it.
///
/// Identical behaviour to [`run`], with one addition: an external `stop()`
/// call is delivered
/// through the SAME unified event channel `run`'s own loop already drains
/// (as an [`OrchestratorEvent::Shutdown`]), so shutdown ordering is
/// serialised with every other event exactly like a real Ctrl-C would be —
/// no separate code path to keep in sync.
#[must_use]
pub fn spawn(opts: WatchOptions) -> (thread::JoinHandle<Result<(), CliError>>, WatchHandle) {
    let (stop_tx, stop_rx) = mpsc::channel::<()>();
    // `done_tx` is moved into the spawned thread's own closure (never handed
    // to `run_inner` itself) and is unconditionally dropped the instant that
    // closure returns — on EVERY exit path (the clean `Ok(())` after full
    // shutdown, or an early setup-failure `Err`), not just the happy path.
    // `WatchHandle::wait_for_shutdown` therefore unblocks promptly even if
    // `run_inner` fails before ever reaching its main loop.
    let (done_tx, done_rx) = mpsc::channel::<()>();
    let handle = thread::spawn(move || {
        let result = run_inner(&opts, Some(stop_rx));
        let _ = done_tx.send(());
        result
    });
    (
        handle,
        WatchHandle {
            stop_tx,
            done_rx: Mutex::new(Some(done_rx)),
        },
    )
}

enum CompileOutcome {
    Green(Arc<ipe_backend::EmittedProject>),
    Red(String),
    /// Cancelled via salsa (a newer generation superseded it) — never
    /// reported to the user; the newer cycle already took over.
    Cancelled,
}

enum CargoOutcome {
    Green(PathBuf),
    Red(String),
    Killed,
}

/// Run `ipe watch` until the process receives a shutdown signal (Ctrl-C) or
/// every event source disconnects.
///
/// Never returns an `Err` for a build failure — INV-3 means a red build is
/// a LOGGED event, not a fatal one; this only returns `Err` for a genuine
/// setup failure (scope refused, watcher couldn't start).
///
/// # Errors
/// [`CliError`] if the confined scope cannot be built, or the filesystem
/// watcher cannot be started.
pub fn run(opts: &WatchOptions) -> Result<(), CliError> {
    run_inner(opts, None)
}

/// The full implementation behind both [`run`] (CLI-facing, no external stop
/// channel) and [`spawn`] (embedder/test-facing, stoppable via
/// [`WatchHandle`]).
///
/// # Errors
/// [`CliError`] if the confined scope cannot be built, or the filesystem
/// watcher cannot be started.
#[allow(clippy::too_many_lines)]
fn run_inner(
    opts: &WatchOptions,
    external_stop: Option<mpsc::Receiver<()>>,
) -> Result<(), CliError> {
    let initial = resolve_project_sources(&opts.entry, None)?;
    let (root_dir, entry_dir) = scope_roots(&initial, &opts.entry);

    let scope = ipe_watch::WatchScope::build(&root_dir, &entry_dir)
        .map_err(|e| CliError::UsageOwned(e.to_string()))?;
    if !opts.quiet {
        eprintln!(
            "{}",
            watch_line(
                &format!(
                    "[ipe watch] watching {} ({} source files)",
                    scope.root().display(),
                    scope.file_count()
                ),
                WatchRole::Info
            )
        );
    }

    let (raw_tx, raw_rx) = mpsc::channel::<PathBuf>();
    let mut watcher = {
        let scope = scope.clone();
        notify::recommended_watcher(move |res: notify::Result<notify::Event>| {
            let Ok(event) = res else { return };
            // Reject non-mutating ACCESS events (open/read/execute) and the
            // watch-internal `Other` kind — EXCEPT `Access(Close(Write))`,
            // which is deliberately let through (see below). This is
            // load-bearing, not an optimisation: the orchestrator's own
            // `resolve_project_sources` OPENS every in-scope `.ipe` file
            // (and reads the watched directory) on EVERY rebuild cycle.
            // Some backends (Linux inotify, by default) report that
            // open/read as an `Access(Open)`/`Access(Close(Read))` event —
            // without this filter, the watcher would observe its own read,
            // queue another rebuild, read again to service it, and so on
            // forever (a self-triggering rebuild storm this was caught by,
            // not merely guarded against speculatively). `resolve_project_
            // sources` only ever opens `.ipe` files for READING, so it can
            // never itself produce the one Access variant this filter
            // exempts (`Close(Write)` — see below); the exemption cannot
            // reopen the self-trigger hole.
            //
            // `Close(Write)` exemption (coalescing race):
            // `std::fs::write` — and most editors' "atomic-ish"
            // save path — is `open(O_TRUNC) → write() → close()`, which is
            // NOT one atomic filesystem operation. `open(O_TRUNC)` alone
            // can fire `Modify(Data)` (truncating IS a data change) the
            // instant the file is EMPTIED, strictly BEFORE the writer's own
            // `write()` call actually lands the new bytes. Under enough
            // scheduling pressure on the WRITING process/thread (verified:
            // 8-way CPU saturation + a concurrent real `cargo build`
            // reproduces this reliably; a quiet system does not), the gap
            // between that `open(O_TRUNC)` and the following `write()` can
            // exceed the debounce quiescence window — the coalescer, having
            // received only the truncate's `Modify(Data)` and nothing more
            // within its window, correctly (by ITS OWN local contract)
            // considers the batch settled and fires a rebuild that reads a
            // GENUINELY EMPTY file on disk (`IPE-P0020` "malformed module
            // header"), followed shortly by a second, correct rebuild once
            // the writer finally catches up and closes the file.
            // `Close(Write)` is the one signal that is only ever
            // emitted once a write-mode file handle is actually `close()`d
            // — which, by the writing process's own fd lifecycle, can only
            // happen AFTER its `write()` call returns. Letting that specific
            // event back through means the coalescer's quiescence timer
            // resets on it exactly like any other mutating event, so a
            // truncate-then-write sequence that spans MORE than the nominal
            // debounce window still gets folded into the SAME batch — closed
            // by construction (keyed off the syscall that is a
            // write-completion PROOF), not by widening a timing margin and
            // hoping it's wide enough. `Create`/`Modify`/`Remove`/`Any` (the
            // "imprecise backend" catch-all) all pass through
            // unconditionally, unaffected by this exemption.
            let is_write_close = matches!(
                event.kind,
                notify::EventKind::Access(notify::event::AccessKind::Close(
                    notify::event::AccessMode::Write
                ))
            );
            if !is_write_close
                && (event.kind.is_access() || matches!(event.kind, notify::EventKind::Other))
            {
                return;
            }
            for path in event.paths {
                if scope.is_relevant(&path) {
                    let _ = raw_tx.send(path);
                }
            }
        })
        .map_err(|e| CliError::UsageOwned(format!("watch: cannot start filesystem watcher: {e}")))?
    };
    for w in scope.roots_to_watch() {
        notify::Watcher::watch(&mut watcher, w.as_path(), notify::RecursiveMode::Recursive)
            .map_err(|e| {
                CliError::UsageOwned(format!(
                    "watch: cannot watch {}: {e}",
                    w.as_path().display()
                ))
            })?;
    }

    warn_if_memory_store();

    let (batch_tx, batch_rx) = mpsc::channel::<ipe_watch::Batch>();
    let debounce_cfg = opts.debounce;
    let coalesce_handle =
        thread::spawn(move || ipe_watch::coalesce_loop(&raw_rx, &batch_tx, debounce_cfg));

    let (evt_tx, evt_rx) = mpsc::channel::<OrchestratorEvent>();
    {
        let evt_tx = evt_tx.clone();
        thread::spawn(move || {
            for batch in batch_rx {
                // The settle window is the batch's arrival now minus when its
                // first raw event opened the window — the true edit→settled
                // latency, measured only when timing is on (the field is unused
                // otherwise).
                let settle = batch.first_event_at.map(|t| t.elapsed());
                if evt_tx.send(OrchestratorEvent::FsBatch { settle }).is_err() {
                    return;
                }
            }
        });
    }
    // SIGTERM → orderly shutdown, for the CLI `run()` path ONLY (`external_stop`
    // is `None` exactly there). A supervisor's `kill -TERM <ipe-pid>` (systemd's
    // default, PID-only — not the foreground process group Ctrl-C signals) would
    // otherwise hard-kill this process before ANY teardown code runs, orphaning
    // the supervised child on its port forever. The forwarder is a third instance
    // of the existing "send into the unified event channel" pattern; the
    // `Shutdown => break` arm below then runs the full, already-tested teardown.
    //
    // NEVER installed for `spawn()` (`external_stop` is `Some`): `spawn()` runs
    // on a same-process background thread inside an EMBEDDING HOST — installing a
    // process-wide SIGTERM handler there would silently and permanently change
    // the HOST's signal disposition (signal-hook does not restore the previous
    // disposition once its action is gone). `spawn()` keeps relying exclusively
    // on `WatchHandle`'s stop channel + `Drop` safety net.
    if external_stop.is_none() {
        #[cfg(unix)]
        {
            let evt_tx = evt_tx.clone();
            // Errors are logged, never fatal — a platform where signal
            // registration fails degrades to the pre-existing behaviour (no
            // PID-only-SIGTERM handling), never a hard failure of `ipe watch`.
            if let Err(e) = ipe_watch::install_sigterm_forwarder(move || {
                let _ = evt_tx.send(OrchestratorEvent::Shutdown);
            }) {
                eprintln!(
                    "{}",
                    watch_line(
                        &format!("[ipe watch] warning: could not install SIGTERM handler: {e}"),
                        WatchRole::Info
                    )
                );
            }
        }
    }
    if let Some(stop_rx) = external_stop {
        let evt_tx = evt_tx.clone();
        thread::spawn(move || {
            if stop_rx.recv().is_ok() {
                let _ = evt_tx.send(OrchestratorEvent::Shutdown);
            }
        });
    }

    // Resolve the runtime crate root once, fail-closed, before the event loop
    // starts. The path-dependency emit needs the CRATE ROOT (the directory
    // holding the runtime `Cargo.toml`), not the source sub-tree. This
    // mirrors how `ipe build` resolves it via `runtime_embed::resolve()`.
    let runtime_dep_root = crate::runtime_embed::resolve()?.root().to_path_buf();

    // The DEV-ONLY blue-green front proxy. When enabled, it binds the user's
    // port up front and holds it for the whole session; the app binaries run
    // behind it on internal loopback ports and are cut over on readiness so a
    // rebuild never drops the browser's connection. Bind failure is fatal here
    // for the SAME reason a direct port-in-use is: the user asked for that
    // port and it is unavailable.
    let mut proxy: Option<ipe_watch::DevProxy> = if opts.bluegreen {
        let bound = ipe_watch::DevProxy::bind(opts.port).map_err(|e| {
            CliError::UsageOwned(format!(
                "watch: cannot bind the blue-green proxy on port {}: {e}",
                opts.port
            ))
        })?;
        if !opts.quiet {
            eprintln!(
                "{}",
                watch_line(
                    &format!(
                        "[ipe watch] blue-green proxy holding port {} (rebuilds cut over with no \
                         dropped connection)",
                        opts.port
                    ),
                    WatchRole::Info
                )
            );
        }
        Some(bound)
    } else {
        None
    };

    let mut db_main = ipe_db::IpeDatabase::new();
    let mut source_root: Option<ipe_db::SourceRoot> = None;
    let mut config: Option<ipe_db::BuildConfig> = None;
    let mut supervisor = ipe_watch::SupervisorState::fresh();
    let mut generation: u64 = 0;
    let mut compile_worker: Option<thread::JoinHandle<()>> = None;
    let mut cargo_child: Option<Arc<std::sync::Mutex<Child>>> = None;
    // Set at `CompileDone` (Green), consumed at `CargoDone` (Green) — the
    // readiness strategy is a property of the SOURCE (does it call
    // `Web.app`?), decided once per generation right after emit, not
    // re-derived from the built executable (which carries no such marker).
    let mut current_is_web = false;
    // The emit of the currently-RUNNING binary, kept only under the appearance
    // hot-swap flag. The classifier diffs each new emit against this to decide
    // AppearanceOnly (push a table patch, skip cargo) vs Logic (recompile). It is
    // updated ONLY when a recompile is actually launched (Logic path / first
    // build) — never on an appearance push, because the running binary still
    // bakes THESE defaults (they key the runtime overlay), so chained style edits
    // each diff against the same running baseline. `None` until the first emit,
    // or whenever the flag is off.
    let mut running_emitted: Option<Arc<ipe_backend::EmittedProject>> = None;
    // The per-session control token that authenticates a `/_ipe/hot-appearance`
    // POST and a `/_ipe/watch/status` build-status POST. Minted once here and
    // injected into every spawned child via `child_env` as `IPE_WATCH_HOT_TOKEN`,
    // so only this watch process can drive either dev endpoint of the app it
    // launched. Minted when EITHER the appearance hot-swap flag OR the browser
    // build-status banner is on — the failure banner must reach the child even
    // with appearance hot-swap off (the two endpoints gate independently on the
    // server; the shared token arms only whichever route is actually mounted).
    let hot_token: Option<String> =
        if crate::hot_appearance_enabled() || crate::watch_banner_enabled() {
            Some(mint_hot_token())
        } else {
            None
        };
    // The appearance hot-swap classifier and its running-emit baseline are armed
    // ONLY by the appearance flag — never merely by the banner. The child's emit
    // carries a `LiteralTable` overlay only under `hot_appearance_enabled()`
    // (see the emit config), so a patch push against a banner-only build would
    // target a binary with no overlay to patch.
    let appearance_active = crate::hot_appearance_enabled();
    // The current live cycle's per-phase timing (`IPE_WATCH_TIMING`). Reset at
    // each `FsBatch`; the resolve/compile/write/cargo phases fill it as their
    // events land, and it is reported at the terminal event (restart done, or
    // a red build). A superseding batch simply overwrites it — the stale
    // cycle's partial timing is discarded exactly like its stale events.
    let mut timings = RebuildTimings::default();

    // Kick off the first build immediately — don't wait for a file event.
    if evt_tx
        .send(OrchestratorEvent::FsBatch { settle: None })
        .is_err()
    {
        return Ok(());
    }

    while let Ok(event) = evt_rx.recv() {
        match event {
            OrchestratorEvent::FsBatch { settle } => {
                generation += 1;
                let this_gen = generation;
                timings = RebuildTimings::start(settle);
                // The orchestrator-thread phase (resolve + ffi + salsa sync)
                // starts here; its span closes just before the compile worker
                // is spawned below.
                let resolve_started = Instant::now();
                emit(
                    opts,
                    WatchEvent::RebuildStarted {
                        generation: this_gen,
                    },
                );

                // Single-flight: a superseding batch kills any in-flight
                // cargo build immediately ("never overlapping cargo
                // builds"). Only a signal is sent here (`kill`, never
                // a blocking `wait`) — the build's own waiter thread (see
                // `spawn_cargo_build`) observes the exit via its own poll
                // and reports `CargoOutcome::Killed`, so this arm never
                // blocks the orchestrator.
                if let Some(child) = cargo_child.take()
                    && let Ok(mut child) = child.lock()
                {
                    let _ = child.kill();
                }

                let resolved = match resolve_project_sources(&opts.entry, None) {
                    Ok(r) => r,
                    Err(e) => {
                        eprintln!(
                            "{}",
                            watch_line(&format!("[ipe watch] {e}"), WatchRole::Failure)
                        );
                        // This cycle's `generation` bump and cargo-kill
                        // already happened above, so without a scheduled
                        // retry the save that triggered this cycle is lost
                        // until an unrelated future edit.
                        schedule_resolve_retry(&evt_tx);
                        continue;
                    }
                };

                let mut sources = resolved.sources;
                let mut discovered = resolved.discovered;
                let injected = project::inject_compiled_std_closure(&mut sources, &mut discovered);

                // Load the FFI catalog and inject installed-crate interface
                // modules — the same seam `run_build` uses (CO-INCR-005).
                // An error logs and skips the cycle (same policy as a
                // resolution failure above) rather than tearing down the
                // whole watch session.
                let ffi_prep = match crate::ffi::prepare_ffi(&mut sources, &resolved.blame_path) {
                    Ok(p) => p,
                    Err(e) => {
                        eprintln!(
                            "{}",
                            watch_line(
                                &format!("[ipe watch] FFI catalog error: {e}"),
                                WatchRole::Failure
                            )
                        );
                        continue;
                    }
                };

                let desired: BTreeMap<Vec<String>, (String, ipe_db::ModuleOrigin)> = sources
                    .iter()
                    .map(|(p, (_, text))| {
                        let origin = if injected.contains(p) {
                            ipe_db::ModuleOrigin::EmbeddedStdlib
                        } else if ffi_prep.injected.contains(p) {
                            ipe_db::ModuleOrigin::FfiInterface
                        } else {
                            ipe_db::ModuleOrigin::User
                        };
                        (p.clone(), (text.clone(), origin))
                    })
                    .collect();

                // This call BLOCKS until any in-flight compile
                // worker's cancelled query unwinds and drops its database
                // clone — see the module doc's cancellation walkthrough.
                let root = if let Some(root) = source_root {
                    ipe_db::sync_source_root(&mut db_main, root, &desired);
                    root
                } else {
                    let root = crate::create_source_root(
                        &db_main,
                        &sources,
                        &injected,
                        &ffi_prep.injected,
                    );
                    source_root = Some(root);
                    root
                };

                let cfg = if let Some(cfg) = config {
                    if cfg.db_driver(&db_main) != resolved.db_driver {
                        use salsa::Setter as _;
                        cfg.set_db_driver(&mut db_main).to(resolved.db_driver);
                    }
                    if cfg.wasm_public_env(&db_main) != &resolved.wasm_public_env {
                        use salsa::Setter as _;
                        cfg.set_wasm_public_env(&mut db_main)
                            .to(resolved.wasm_public_env.clone());
                    }
                    cfg
                } else {
                    // Pass ffi_prep.emit so the backend can write FFI
                    // bindings (src/ffi.rs) into the emitted project — the
                    // same slot `run_build` fills via BuildConfig (CO-INCR-005).
                    let cfg = ipe_db::BuildConfig::new(
                        &db_main,
                        resolved.db_driver,
                        ffi_prep.emit,
                        ipe_ir::Target::Native,
                        resolved.wasm_public_env.clone(),
                        false,
                        // `ipe watch` is a development loop — Debug.* is allowed.
                        false,
                        // Dependency-model emit: the project links the runtime as a
                        // path dependency (what `ipe build` uses by default), so
                        // no runtime source is vendored into `src/ipe_runtime/`.
                        // `runtime_dep_root` is the verified crate root (holds
                        // `Cargo.toml`), resolved once before the loop via
                        // `runtime_embed::resolve()`, matching `ipe build`'s path.
                        Some(ipe_backend_rust::RuntimeDep {
                            root: runtime_dep_root.clone(),
                        }),
                        // `ipe watch` does not expose `--debugger`; never record.
                        false,
                        resolved.cargo_name.clone(),
                        crate::hot_appearance_enabled(),
                    );
                    config = Some(cfg);
                    cfg
                };

                // The prior worker (if any) has already unwound by the time
                // `sync_source_root` returned above; join to reclaim the
                // thread handle (fast — it already finished).
                if let Some(h) = compile_worker.take() {
                    let _ = h.join();
                }

                // Close the orchestrator-thread phase: everything from the
                // start of this arm (resolve + ffi + salsa input mutation) up
                // to handing off to the compile worker.
                timings.resolve = Some(resolve_started.elapsed());

                let db_worker = db_main.clone();
                let entry_path = resolved.entry_path.clone();
                let blame_path = resolved.blame_path.clone();
                let evt_tx = evt_tx.clone();
                compile_worker = Some(thread::spawn(move || {
                    // Measure the salsa warm-compile on the worker thread: the
                    // orchestrator only sees the event, so the span has to be
                    // taken here at the real call boundary.
                    let compile_started = Instant::now();
                    let outcome =
                        match salsa::Cancelled::catch(std::panic::AssertUnwindSafe(|| {
                            crate::compile_prepared(
                                &db_worker,
                                root,
                                &sources,
                                &entry_path,
                                &blame_path,
                                cfg,
                            )
                        })) {
                            Ok(Ok(emitted)) => CompileOutcome::Green(Arc::new(emitted)),
                            Ok(Err(e)) => CompileOutcome::Red(e.to_string()),
                            Err(_cancelled) => CompileOutcome::Cancelled,
                        };
                    let _ = evt_tx.send(OrchestratorEvent::CompileDone {
                        generation: this_gen,
                        outcome,
                        compile: compile_started.elapsed(),
                    });
                }));
            }

            OrchestratorEvent::CompileDone {
                generation: g,
                outcome,
                compile,
            } => {
                if g != generation {
                    continue; // stale — a newer cycle already superseded this one.
                }
                timings.compile = Some(compile);
                match outcome {
                    CompileOutcome::Cancelled => {
                        emit(opts, WatchEvent::CompileCancelled { generation: g });
                    }
                    CompileOutcome::Red(msg) => {
                        // Frame the diagnostic like `ipe run`: a blank line
                        // above, every line guttered two spaces (so the whole
                        // report sits inset, not just the header), a blank line
                        // below to set it off from the next watch line. Light
                        // yellow, not red — the last-good binary stays up.
                        let p = crate::style::Palette::for_stream(&std::io::stderr());
                        let body = format!(
                            "{}{} [ipe watch] build failed (last-good binary stays up):{}\n{}",
                            p.bright_yellow,
                            crate::style::glyph::FAIL,
                            p.reset,
                            msg.trim_end()
                        );
                        eprint!("\n{}\n", crate::style::gutter(&body));
                        emit(opts, WatchEvent::CompileFailed { generation: g });
                        if let Some(tok) = hot_token.as_deref() {
                            post_watch_status(opts.port, tok, false, &first_error_line(&msg));
                        }
                        // A red compile is terminal for this cycle (no cargo,
                        // no restart) — report the partial breakdown here.
                        timings.report(g);
                    }
                    CompileOutcome::Green(emitted) => {
                        // Appearance hot-swap: if the flag is on and we already
                        // have a running binary, classify this emit against it.
                        // An AppearanceOnly delta (only hoisted style-literal
                        // VALUES moved) is pushed as a `LiteralTable` patch to the
                        // running app and skips cargo entirely — the sub-second
                        // path. Anything else is Logic and recompiles below. The
                        // classifier is conservative by construction: a logic
                        // change perturbs the emitted Rust outside a defaults
                        // array, forcing Logic (see `hot_classify`).
                        if let (true, Some(tok), Some(running)) = (
                            appearance_active,
                            hot_token.as_deref(),
                            running_emitted.as_ref(),
                        ) {
                            match crate::hot_classify::classify(running, &emitted) {
                                crate::hot_classify::Classification::HotSwappable(hot) => {
                                    // The running binary is unchanged, so
                                    // `running_emitted` stays the baseline. Push
                                    // each edited view's appearance patch AND each
                                    // edited arm's transition patch, then skip
                                    // cargo. Both must reach the app for the swap
                                    // to be complete; a failure of EITHER is a soft
                                    // miss that falls through to a normal recompile
                                    // so the edit still lands.
                                    let views_ok = push_appearance_patches(
                                        opts.port, tok, &hot.views, opts.quiet,
                                    );
                                    let transitions_ok = push_transition_patches(
                                        opts.port,
                                        tok,
                                        &hot.transitions,
                                        opts.quiet,
                                    );
                                    // The additive-`Msg`-set leg: the endpoint
                                    // re-proves the superset and refuses a
                                    // non-additive candidate, so a miss here (like
                                    // a view/transition miss) falls back to a full
                                    // recompile.
                                    let msg_sets_ok = push_msg_set_patches(
                                        opts.port,
                                        tok,
                                        &hot.msg_sets,
                                        opts.quiet,
                                    );
                                    if views_ok && transitions_ok && msg_sets_ok {
                                        emit(
                                            opts,
                                            WatchEvent::AppearanceHotSwapped {
                                                generation: g,
                                                views: hot.views.len()
                                                    + hot.transitions.len()
                                                    + hot.msg_sets.len(),
                                            },
                                        );
                                        post_watch_status(opts.port, tok, true, "");
                                        timings.report(g);
                                        continue;
                                    }
                                }
                                crate::hot_classify::Classification::Logic => {
                                    // Recompile below.
                                }
                            }
                        }
                        // Watch is always a dynamic dev build — no static plan,
                        // no tree-shaking (the full runtime tree keeps rebuilds
                        // incremental across a session's changing reach set).
                        let write_started = Instant::now();
                        if let Err(e) = write_emitted_project(
                            &emitted,
                            &opts.out_dir,
                            &opts.runtime_dir,
                            None,
                            false,
                        ) {
                            eprintln!(
                                "{}",
                                watch_line(
                                    &format!("[ipe watch] failed to write emitted project: {e}"),
                                    WatchRole::Failure
                                )
                            );
                            continue;
                        }
                        timings.write = Some(write_started.elapsed());
                        // This emit is about to be compiled into the new running
                        // binary, so it becomes the classifier's baseline for the
                        // next edit (only relevant under the appearance flag).
                        if appearance_active {
                            running_emitted = Some(emitted.clone());
                        }
                        current_is_web = is_ipe_web_project(&emitted);
                        // Design doc "First-run vs warm-run UX": the cold
                        // (first) build pays the full dependency-compile
                        // cost and can take minutes; every subsequent
                        // rebuild is warm (seconds). Distinguishing them
                        // here means "watch is slow" is never misattributed
                        // to the salsa layer, which already ran in
                        // milliseconds by the time this line prints.
                        if !opts.quiet {
                            if generation == 1 {
                                eprintln!(
                                    "{}",
                                    watch_line(
                                        "[ipe watch] building (first run — compiling \
                                         dependencies, this is the slow one)…",
                                        WatchRole::Info
                                    )
                                );
                            } else {
                                eprintln!(
                                    "{}",
                                    watch_line(
                                        "[ipe watch] change detected — rebuilding…",
                                        WatchRole::Info
                                    )
                                );
                            }
                        }
                        match spawn_cargo_build(
                            &opts.cargo_path,
                            &opts.out_dir,
                            generation,
                            evt_tx.clone(),
                            opts.quiet,
                        ) {
                            Ok(child) => cargo_child = Some(child),
                            Err(e) => eprintln!(
                                "{}",
                                watch_line(
                                    &format!("[ipe watch] cannot start cargo build: {e}"),
                                    WatchRole::Failure
                                )
                            ),
                        }
                    }
                }
            }

            OrchestratorEvent::CargoDone {
                generation: g,
                outcome,
                cargo,
            } => {
                if g != generation {
                    continue;
                }
                cargo_child = None;
                timings.cargo = Some(cargo);
                match outcome {
                    CargoOutcome::Killed => {
                        emit(opts, WatchEvent::CargoKilled { generation: g });
                    }
                    CargoOutcome::Red(msg) => {
                        eprintln!(
                            "{}",
                            watch_line(
                                &format!(
                                    "[ipe watch] cargo build failed (last-good binary stays \
                                     up):\n{msg}"
                                ),
                                WatchRole::Failure
                            )
                        );
                        emit(opts, WatchEvent::CargoFailed { generation: g });
                        if let Some(tok) = hot_token.as_deref() {
                            post_watch_status(opts.port, tok, false, &first_error_line(&msg));
                        }
                        // A red cargo build is terminal (no restart) — report
                        // the partial breakdown here.
                        timings.report(g);
                    }
                    CargoOutcome::Green(exe_path) => {
                        let restart_started = Instant::now();
                        let outcome = if let Some(proxy) = proxy.as_ref() {
                            // Blue-green: the new binary binds a FRESH internal
                            // port behind the proxy; readiness is probed on
                            // that internal port; on ready, the proxy cuts over
                            // to it and the old binary is drained — the
                            // user-facing port (held by the proxy) never stops
                            // answering. A web app gets the precise
                            // `/_ipe/readyz` probe; every other shape falls
                            // back to a short alive-grace, exactly as the
                            // direct path does.
                            let internal_port = match free_loopback_port() {
                                Ok(p) => p,
                                Err(e) => {
                                    eprintln!(
                                        "{}",
                                        watch_line(
                                            &format!(
                                                "[ipe watch] cannot allocate an internal port for \
                                                 the blue-green cutover: {e}"
                                            ),
                                            WatchRole::Failure
                                        )
                                    );
                                    continue;
                                }
                            };
                            let readiness = if current_is_web {
                                ipe_watch::ReadinessCheck::HttpReadyz {
                                    port: internal_port,
                                }
                            } else {
                                ipe_watch::ReadinessCheck::AliveGrace {
                                    grace: Duration::from_millis(300),
                                }
                            };
                            let out_dir = opts.out_dir.clone();
                            let tok = hot_token.clone();
                            let reset_state = opts.reset_state;
                            supervisor.apply_green_behind_proxy(
                                &exe_path,
                                internal_port,
                                move |path, port| {
                                    spawn_command(
                                        path,
                                        &child_env(
                                            port,
                                            &out_dir,
                                            tok.as_deref(),
                                            true,
                                            reset_state,
                                        ),
                                    )
                                },
                                readiness,
                                opts.restart_timeouts,
                                |ready_port| proxy.set_upstream(ready_port),
                            )
                        } else {
                            let readiness = if current_is_web {
                                ipe_watch::ReadinessCheck::HttpReadyz { port: opts.port }
                            } else {
                                ipe_watch::ReadinessCheck::AliveGrace {
                                    grace: Duration::from_millis(300),
                                }
                            };
                            let env = child_env(
                                opts.port,
                                &opts.out_dir,
                                hot_token.as_deref(),
                                false,
                                opts.reset_state,
                            );
                            supervisor.apply_green(
                                &exe_path,
                                move |path| spawn_command(path, &env),
                                readiness,
                                opts.restart_timeouts,
                            )
                        };
                        timings.restart = Some(restart_started.elapsed());
                        report_restart_outcome(&outcome, opts.quiet);
                        emit(
                            opts,
                            WatchEvent::Restarted {
                                generation: g,
                                outcome: restart_outcome_kind(&outcome),
                            },
                        );
                        // The terminal event of a fully-green cycle — the whole
                        // breakdown is now populated.
                        timings.report(g);
                    }
                }
            }

            OrchestratorEvent::Shutdown => break,
        }
    }

    // Explicitly drop the notify watcher — and with it, its owned `raw_tx`
    // clone — BEFORE waiting on `coalesce_handle` below. `raw_tx` is moved
    // (never `.clone()`d — see `mpsc::channel` above) into `watcher`'s own
    // event callback, so `watcher` is the SOLE owner of a live sender.
    // `ipe_watch::coalesce_loop`'s blocking `raw_rx.recv()` only returns
    // once every `raw_tx` sender has been dropped; leaving `watcher` to die
    // via its ordinary end-of-function scope drop (i.e. AFTER
    // `coalesce_handle.join()` below) means that `join()` blocks FOREVER —
    // notify's own internal OS-watch thread stays parked (`epoll_wait`),
    // `raw_rx` never observes a disconnect, and the whole shutdown wedges.
    // Confirmed live via `/proc/<pid>/task/*/wchan` before this fix: the
    // notify thread parked in `ep_poll` while every sibling thread sat in
    // `futex_wait_queue_me`, and both `watch_rebuild_on_save_swaps_…` and
    // `watch_coalesces_a_rapid_double_save_…` hung past their nextest
    // SIGTERM ceiling as a direct result.
    drop(watcher);

    if let Some(child) = cargo_child.take()
        && let Ok(mut child) = child.lock()
    {
        let _ = child.kill();
    }
    supervisor.shutdown(opts.restart_timeouts);
    // Stop the front proxy AFTER the supervised child is down: it held the
    // user's port for the whole session, so releasing it last means the port
    // is answered until the very end of teardown rather than flapping.
    if let Some(mut proxy) = proxy.take() {
        proxy.shutdown();
    }
    if let Some(h) = compile_worker {
        let _ = h.join();
    }
    let _ = coalesce_handle.join();
    Ok(())
}

/// Ask the OS for a free loopback TCP port by binding an ephemeral one and
/// immediately dropping the listener, returning the port it chose.
///
/// A tiny race exists between releasing the port here and the spawned child
/// binding it — acceptable for a DEV loop on loopback, and closed in practice
/// because the child binds it within milliseconds and the blue-green readiness
/// probe would catch (and INV-3-preserve against) a bind failure. Kept minimal
/// deliberately: a robust production port lease is out of scope for a dev-only
/// cutover.
///
/// # Errors
/// An I/O error if no ephemeral port can be bound at all.
fn free_loopback_port() -> std::io::Result<u16> {
    let listener = std::net::TcpListener::bind((std::net::Ipv4Addr::LOCALHOST, 0))?;
    Ok(listener.local_addr()?.port())
}

/// Detection heuristic for readiness strategy: the backend's Ipe.Web entry
/// point emission always contains the literal `ipe_runtime::web::web_app`
/// call (`crates/ipe_backend_rust/src/emit_web.rs`) — deterministic,
/// compiler-controlled text, not user input, so a substring check is sound
/// here (unlike parsing arbitrary user text). Ipe.Web apps get the
/// precise `/_ipe/readyz` probe; every other shape (Ipe.Http.Server has no
/// readiness endpoint yet, and its listen port is a Ipê-source-level
/// argument this driver cannot statically know) falls back to
/// `AliveGrace` — matching the design doc's own readiness bifurcation
/// ("`/_ipe/readyz` for Ipe.Web; alive + optional health for CLI").
fn is_ipe_web_project(emitted: &ipe_backend::EmittedProject) -> bool {
    emitted
        .files
        .iter()
        .find(|(rel, _)| rel.as_str() == "src/main.rs")
        .is_some_and(|(_, text)| text.contains("ipe_runtime::web::web_app"))
}

/// Build the child process's environment.
///
/// Sets both `IPE_WEB_PORT` and `IPE_SERVER_PORT` to the SAME configured
/// port — harmless (ignored) for whichever app shape didn't ask for it, and
/// what lets a `Ipe.Http.Server` fixture that reads `IPE_SERVER_PORT` (the
/// convention this repo's own `server_e2e.rs` test suite already
/// establishes) be driven by `--port` exactly like a Ipe.Web app is.
///
/// Also provides the watch-scoped half of session continuity —
/// default the dev session store to `file` (persisted under `out_dir`,
/// confined to the emit tree's parent so the emit→cargo bridge's
/// `src/`-only prune pass never touches it) unless the caller's OWN
/// environment already configures `IPE_WEB_STORE`, in which case that
/// choice is respected verbatim (and warned about when it is exactly
/// `memory` — see `warn_if_memory_store`, called once at watch startup).
fn child_env(
    port: u16,
    out_dir: &Path,
    hot_token: Option<&str>,
    bluegreen: bool,
    reset_state: bool,
) -> Vec<(String, String)> {
    let mut env = vec![
        ("IPE_WEB_PORT".to_owned(), port.to_string()),
        ("IPE_SERVER_PORT".to_owned(), port.to_string()),
    ];
    // Blue-green cutover: tell the emitted server it runs behind the watch
    // proxy so its client greets a reconnect with the positive "updated ✓"
    // toast instead of the "Reconnecting…" banner. Only the blue-green path
    // sets this; the direct-bind path (and any release build) leaves it unset.
    if bluegreen {
        env.push(("IPE_WEB_SWAP_TOAST".to_owned(), "1".to_owned()));
    }
    // State-reset escape hatch: force every returning session to a fresh `init`
    // for the child's lifetime, bypassing additive-splice. Dev-only; a release
    // binary never receives this — `IPE_WEB_RESET_STATE` is a no-op unless
    // the emitted binary's runtime reads it via `reset_state_from_env`.
    if reset_state {
        env.push(("IPE_WEB_RESET_STATE".to_owned(), "1".to_owned()));
    }
    // Under appearance hot-swap, hand the running app the per-session control
    // token so its `/_ipe/hot-appearance` endpoint accepts patches from THIS
    // watch (and nothing else). Absent ⇒ the endpoint fails closed.
    if let Some(tok) = hot_token {
        env.push(("IPE_WATCH_HOT_TOKEN".to_owned(), tok.to_owned()));
        // The emitted app's runtime reads `IPE_WATCH_HOT_APPEARANCE` to activate
        // its overlay (see the runtime's `literal_table`). A hot token present
        // means this watch built with the hot-swap emit, so tell the child to
        // turn its overlay on — explicitly, so default-on works without the user
        // setting anything.
        env.push(("IPE_WATCH_HOT_APPEARANCE".to_owned(), "1".to_owned()));
    }
    if std::env::var("IPE_WEB_STORE").is_err() {
        // `file`, not `sqlite`: a plain `Web.app` reaches no DB kernel, so the
        // emitted crate carries no `db` feature and the sqlite store compiles
        // out (it would silently degrade to an in-memory store that does NOT
        // survive a rebuild — no Model handoff). The `file` store rides the
        // `web` feature every web build already has, reusing the same
        // schema-tagged checkpoint codec, so the blue-green swap can rehydrate
        // the Model. Confined to the emit tree's parent so the `src/`-only
        // prune pass never touches it.
        env.push(("IPE_WEB_STORE".to_owned(), "file".to_owned()));
        let store_path = out_dir
            .parent()
            .unwrap_or(out_dir)
            .join(".ipe-watch-sessions.json");
        env.push((
            "IPE_WEB_STORE_PATH".to_owned(),
            store_path.to_string_lossy().into_owned(),
        ));
    }
    // A dev rebuild is down for seconds (the cargo relink dominates), so widen
    // the browser's fast-reconnect window past its default to cover it: the page
    // reconnects a fast-retry tick after the new server binds instead of waiting
    // out an exponential-backoff interval. The caller's own value wins.
    if std::env::var("IPE_WEB_RETRY_FAST_WINDOW_MS").is_err() {
        env.push(("IPE_WEB_RETRY_FAST_WINDOW_MS".to_owned(), "8000".to_owned()));
    }
    env
}

/// Mint a per-session control token for the `/_ipe/hot-appearance` endpoint.
///
/// The token authenticates a live appearance patch: only this watch process
/// knows it (it is injected into the child's env and never printed), so even a
/// dev server bound to `0.0.0.0` cannot be driven by a LAN peer. Primary source
/// is the OS CSPRNG (`/dev/urandom`); if that is unavailable, a SHA-256 mix of
/// several process-unique entropy sources is used so the token is never a fixed
/// or trivially-guessable value. Rendered as lowercase hex.
fn mint_hot_token() -> String {
    use sha2::{Digest as _, Sha256};
    use std::io::Read as _;

    let mut buf = [0u8; 32];
    if let Ok(mut f) = std::fs::File::open("/dev/urandom")
        && f.read_exact(&mut buf).is_ok()
    {
        return hex::encode(buf);
    }
    // Fallback: hash a mix of process-unique, hard-to-predict values. Not a
    // CSPRNG, but never a constant — and the endpoint is dev-only and
    // fail-closed regardless.
    let mut h = Sha256::new();
    let now = std::time::SystemTime::now()
        .duration_since(std::time::UNIX_EPOCH)
        .map_or(0, |d| d.as_nanos());
    h.update(now.to_le_bytes());
    h.update(std::process::id().to_le_bytes());
    h.update(format!("{:?}", std::thread::current().id()).as_bytes());
    // A heap-allocation address adds ASLR entropy across runs.
    let probe = Box::new(0u8);
    h.update((std::ptr::from_ref::<u8>(&probe).addr()).to_le_bytes());
    hex::encode(h.finalize())
}

/// POST every edited view's appearance patch to the running app's
/// `/_ipe/hot-appearance` endpoint, authenticated with the session control
/// token. Returns `true` only if every patch was accepted (HTTP 200), so a
/// caller can fall back to a full recompile on any miss. An empty patch list is
/// a no-op success (a whitespace-only edit the emitter normalised away).
fn push_appearance_patches(
    port: u16,
    token: &str,
    patches: &[crate::hot_classify::ViewPatch],
    quiet: bool,
) -> bool {
    for vp in patches {
        let body = serde_json::json!({
            "defaults": vp.defaults,
            "patch": vp.patch,
        })
        .to_string();
        if !matches!(post_hot_appearance(port, token, &body), Ok(true)) {
            if !quiet {
                eprintln!(
                    "{}",
                    watch_line(
                        "[ipe watch] appearance hot-swap push failed — falling back to a \
                         full rebuild",
                        WatchRole::Info
                    )
                );
            }
            return false;
        }
    }
    if !quiet {
        eprintln!(
            "{}",
            watch_line(
                "[ipe watch] appearance edit hot-swapped (no rebuild)",
                WatchRole::Info
            )
        );
    }
    true
}

/// Send one `POST /_ipe/hot-appearance` to loopback `port` over a raw HTTP/1.1
/// connection, returning `Ok(true)` on a `200 OK` status line. Loopback-only and
/// dev-only, so a minimal blocking request (no client crate, no keep-alive) is
/// sufficient; a short connect/read timeout keeps a dead app from stalling the
/// watch loop.
///
/// # Errors
/// An I/O error if the connection cannot be made or the exchange fails.
fn post_hot_appearance(port: u16, token: &str, body: &str) -> std::io::Result<bool> {
    use std::io::{Read as _, Write as _};
    use std::net::TcpStream;
    let addr = std::net::SocketAddr::from((std::net::Ipv4Addr::LOCALHOST, port));
    let mut stream = TcpStream::connect_timeout(&addr, Duration::from_millis(500))?;
    stream.set_read_timeout(Some(Duration::from_millis(1500)))?;
    stream.set_write_timeout(Some(Duration::from_millis(1500)))?;
    let req = format!(
        "POST /_ipe/hot-appearance HTTP/1.1\r\n\
         Host: 127.0.0.1:{port}\r\n\
         X-Ipe-Hot-Token: {token}\r\n\
         Content-Type: application/json\r\n\
         Content-Length: {len}\r\n\
         Connection: close\r\n\r\n{body}",
        len = body.len(),
    );
    stream.write_all(req.as_bytes())?;
    stream.flush()?;
    let mut resp = Vec::new();
    // Read only the status line's worth; the body is empty (`OK`) either way.
    let mut chunk = [0u8; 256];
    if let Ok(n) = stream.read(&mut chunk)
        && let Some(head) = chunk.get(..n)
    {
        resp.extend_from_slice(head);
    }
    let head = String::from_utf8_lossy(&resp);
    Ok(head.starts_with("HTTP/1.1 200"))
}

/// POST every edited `update` arm's transition patch to the running app's
/// `/_ipe/hot-transition` endpoint, authenticated with the same session control
/// token as the appearance channel. Returns `true` only if every patch was
/// accepted (HTTP 200), so a caller can fall back to a full recompile on any
/// miss. An empty patch list is a no-op success.
fn push_transition_patches(
    port: u16,
    token: &str,
    patches: &[crate::hot_classify::TransitionPatch],
    quiet: bool,
) -> bool {
    for tp in patches {
        let body = serde_json::json!({
            "old_json": tp.old_json,
            "new_json": tp.new_json,
        })
        .to_string();
        if !matches!(post_hot_transition(port, token, &body), Ok(true)) {
            if !quiet {
                eprintln!(
                    "{}",
                    watch_line(
                        "[ipe watch] transition hot-swap push failed — falling back to a \
                         full rebuild",
                        WatchRole::Info
                    )
                );
            }
            return false;
        }
    }
    if !quiet && !patches.is_empty() {
        eprintln!(
            "{}",
            watch_line(
                "[ipe watch] update-arm edit hot-swapped (no rebuild)",
                WatchRole::Info
            )
        );
    }
    true
}

/// Send one `POST /_ipe/hot-transition` to loopback `port`, returning `Ok(true)`
/// on a `200 OK` status line. Same minimal blocking-request shape and timeouts
/// as [`post_hot_appearance`] — loopback + dev-only, so no client crate needed.
///
/// # Errors
/// An I/O error if the connection cannot be made or the exchange fails.
fn post_hot_transition(port: u16, token: &str, body: &str) -> std::io::Result<bool> {
    use std::io::{Read as _, Write as _};
    use std::net::TcpStream;
    let addr = std::net::SocketAddr::from((std::net::Ipv4Addr::LOCALHOST, port));
    let mut stream = TcpStream::connect_timeout(&addr, Duration::from_millis(500))?;
    stream.set_read_timeout(Some(Duration::from_millis(1500)))?;
    stream.set_write_timeout(Some(Duration::from_millis(1500)))?;
    let req = format!(
        "POST /_ipe/hot-transition HTTP/1.1\r\n\
         Host: 127.0.0.1:{port}\r\n\
         X-Ipe-Hot-Token: {token}\r\n\
         Content-Type: application/json\r\n\
         Content-Length: {len}\r\n\
         Connection: close\r\n\r\n{body}",
        len = body.len(),
    );
    stream.write_all(req.as_bytes())?;
    stream.flush()?;
    let mut resp = Vec::new();
    let mut chunk = [0u8; 256];
    if let Ok(n) = stream.read(&mut chunk)
        && let Some(head) = chunk.get(..n)
    {
        resp.extend_from_slice(head);
    }
    let head = String::from_utf8_lossy(&resp);
    Ok(head.starts_with("HTTP/1.1 200"))
}

/// Push each additive-`Msg`-set patch to the running app's `/_ipe/hot-msg`
/// endpoint, authenticated with the same session control token. Returns `true`
/// only if every patch was accepted (HTTP 200); the endpoint refuses a
/// non-additive candidate (409 Conflict), which the classifier already excludes,
/// so a non-200 here is a soft miss the caller falls back from to a full
/// recompile. An empty patch list is a no-op success.
fn push_msg_set_patches(
    port: u16,
    token: &str,
    patches: &[crate::hot_classify::MsgSetPatch],
    quiet: bool,
) -> bool {
    for mp in patches {
        let body = serde_json::json!({
            "live_json": mp.live_json,
            "candidate_json": mp.candidate_json,
        })
        .to_string();
        if !matches!(post_hot_msg(port, token, &body), Ok(true)) {
            if !quiet {
                eprintln!(
                    "{}",
                    watch_line(
                        "[ipe watch] Msg-set hot-swap push failed — falling back to a \
                         full rebuild",
                        WatchRole::Info
                    )
                );
            }
            return false;
        }
    }
    if !quiet && !patches.is_empty() {
        eprintln!(
            "{}",
            watch_line(
                "[ipe watch] added Msg variant hot-swapped (no rebuild)",
                WatchRole::Info
            )
        );
    }
    true
}

/// Send one `POST /_ipe/hot-msg` to loopback `port`, returning `Ok(true)` on a
/// `200 OK` status line. Same minimal blocking-request shape and timeouts as
/// [`post_hot_transition`] — loopback + dev-only, so no client crate needed.
///
/// # Errors
/// An I/O error if the connection cannot be made or the exchange fails.
fn post_hot_msg(port: u16, token: &str, body: &str) -> std::io::Result<bool> {
    use std::io::{Read as _, Write as _};
    use std::net::TcpStream;
    let addr = std::net::SocketAddr::from((std::net::Ipv4Addr::LOCALHOST, port));
    let mut stream = TcpStream::connect_timeout(&addr, Duration::from_millis(500))?;
    stream.set_read_timeout(Some(Duration::from_millis(1500)))?;
    stream.set_write_timeout(Some(Duration::from_millis(1500)))?;
    let req = format!(
        "POST /_ipe/hot-msg HTTP/1.1\r\n\
         Host: 127.0.0.1:{port}\r\n\
         X-Ipe-Hot-Token: {token}\r\n\
         Content-Type: application/json\r\n\
         Content-Length: {len}\r\n\
         Connection: close\r\n\r\n{body}",
        len = body.len(),
    );
    stream.write_all(req.as_bytes())?;
    stream.flush()?;
    let mut resp = Vec::new();
    let mut chunk = [0u8; 256];
    if let Ok(n) = stream.read(&mut chunk)
        && let Some(head) = chunk.get(..n)
    {
        resp.extend_from_slice(head);
    }
    let head = String::from_utf8_lossy(&resp);
    Ok(head.starts_with("HTTP/1.1 200"))
}

fn spawn_command(exe_path: &Path, env: &[(String, String)]) -> Command {
    let mut cmd = Command::new(exe_path);
    for (k, v) in env {
        cmd.env(k, v);
    }
    cmd
}

/// Extract the first non-blank line from a compiler diagnostic, capped at
/// 120 characters, for inclusion in the build-failed banner.
fn first_error_line(msg: &str) -> String {
    msg.lines()
        .find(|l| !l.trim().is_empty())
        .unwrap_or("")
        .chars()
        .take(120)
        .collect()
}

/// POST `{ok, error}` to the child's dev-only `/_ipe/watch/status` endpoint.
///
/// Best-effort: silently ignores all errors. The child may not be running yet,
/// or the endpoint may not be mounted (non-web app, banner disabled, etc.) —
/// all of those are fine. A short connect+read timeout keeps a dead app from
/// stalling the watch loop.
fn post_watch_status(port: u16, token: &str, ok: bool, error: &str) {
    // Build the JSON body without serde_json to avoid a new dependency.
    // Escape only backslash and double-quote — the error string is already
    // a first-line excerpt from compiler output (ASCII/UTF-8, no control chars
    // that need JSON-escaping beyond those two).
    let body = if ok {
        r#"{"ok":true}"#.to_string()
    } else {
        let esc = error.replace('\\', "\\\\").replace('"', "\\\"");
        format!(r#"{{"ok":false,"error":"{esc}"}}"#)
    };
    let _ = post_to_watch_status(port, token, &body);
}

/// Send one raw HTTP/1.1 POST to `/_ipe/watch/status`. Returns `Ok(())` when
/// the server replied (any status); any I/O failure is silently discarded by
/// the caller. Mirrors the structure of `post_hot_appearance`.
fn post_to_watch_status(port: u16, token: &str, body: &str) -> std::io::Result<()> {
    use std::io::Write as _;
    use std::net::TcpStream;
    let addr = std::net::SocketAddr::from((std::net::Ipv4Addr::LOCALHOST, port));
    let mut stream = TcpStream::connect_timeout(&addr, Duration::from_millis(500))?;
    stream.set_write_timeout(Some(Duration::from_millis(1500)))?;
    let req = format!(
        "POST /_ipe/watch/status HTTP/1.1\r\n\
         Host: 127.0.0.1:{port}\r\n\
         X-Ipe-Hot-Token: {token}\r\n\
         Content-Type: application/json\r\n\
         Content-Length: {len}\r\n\
         Connection: close\r\n\r\n{body}",
        len = body.len(),
    );
    stream.write_all(req.as_bytes())?;
    stream.flush()?;
    Ok(())
}

/// The `memory`-store warning: called once, at watch startup, so it is
/// printed exactly once per session rather than on every rebuild.
///
/// # Errors
/// Never — this only ever prints; it returns nothing failable, kept as a
/// plain function (not `Result`) so call sites don't need to thread an
/// unused error channel.
fn warn_if_memory_store() {
    if std::env::var("IPE_WEB_STORE").as_deref() == Ok("memory") {
        eprintln!(
            "{}",
            watch_line(
                "[ipe watch] warning: IPE_WEB_STORE=memory is set — session state will NOT \
                 survive a watch-triggered restart. Unset it (watch defaults to a file-backed \
                 store) or set IPE_WEB_STORE=file explicitly to keep your session across rebuilds.",
                WatchRole::Info
            )
        );
    }
}

fn report_restart_outcome(outcome: &ipe_watch::RestartOutcome, quiet: bool) {
    match outcome {
        ipe_watch::RestartOutcome::Spawned => {
            if !quiet {
                eprintln!(
                    "{}",
                    watch_line("[ipe watch] app started", WatchRole::Success)
                );
            }
        }
        ipe_watch::RestartOutcome::UnchangedBinary => {}
        ipe_watch::RestartOutcome::Restarted => {
            if !quiet {
                eprintln!(
                    "{}",
                    watch_line("[ipe watch] app reloaded", WatchRole::Success)
                );
            }
        }
        ipe_watch::RestartOutcome::RespawnedLastGood { broken } => eprintln!(
            "{}",
            watch_line(
                &format!(
                    "[ipe watch] new binary failed its readiness probe ({}); kept the previous \
                     last-good binary running instead",
                    broken.display()
                ),
                WatchRole::Failure
            )
        ),
        ipe_watch::RestartOutcome::NothingRunning {
            broken,
            last_good_error,
        } => {
            eprintln!(
                "{}",
                watch_line(
                    &format!(
                        "[ipe watch] new binary failed its readiness probe ({}); no previous \
                         last-good binary could be brought up{}",
                        broken.display(),
                        last_good_error
                            .as_ref()
                            .map_or_else(String::new, |e| format!(" ({e})"))
                    ),
                    WatchRole::Failure
                )
            );
        }
    }
}

/// Project a [`ipe_watch::RestartOutcome`] down to the `Clone`-able
/// [`RestartOutcomeKind`] tests observe via [`WatchEvent::Restarted`].
const fn restart_outcome_kind(outcome: &ipe_watch::RestartOutcome) -> RestartOutcomeKind {
    match outcome {
        ipe_watch::RestartOutcome::Spawned => RestartOutcomeKind::Spawned,
        ipe_watch::RestartOutcome::UnchangedBinary => RestartOutcomeKind::UnchangedBinary,
        ipe_watch::RestartOutcome::Restarted => RestartOutcomeKind::Restarted,
        ipe_watch::RestartOutcome::RespawnedLastGood { .. } => {
            RestartOutcomeKind::RespawnedLastGood
        }
        ipe_watch::RestartOutcome::NothingRunning { .. } => RestartOutcomeKind::NothingRunning,
    }
}

/// Spawn `cargo build --message-format=json` in `out_dir` and a companion
/// Opt-out env gate for the dev-loop incremental rebuild path. When set to any
/// value other than `0`, `ipe watch` keeps the machine's normal build
/// configuration (sccache wrapper, non-incremental) for the emitted-app rebuild
/// instead of the fast incremental path.
const NO_INCREMENTAL_ENV: &str = "IPE_WATCH_NO_INCREMENTAL";

/// The build-acceleration strategy for one watch-mode `cargo build`, chosen from
/// the target's warmth.
///
/// sccache and rustc-incremental are mutually exclusive (sccache refuses to cache
/// an incremental crate) and they accelerate opposite halves of the loop: sccache
/// caches whole *dependency* crates in a shared store — its win is the one-time
/// cold compile of the registry deps the emitted app links; incremental caches at
/// codegen-unit granularity within one warm target — its win is the per-edit
/// rebuild of the app crate (the vendored runtime module tree compiled inside it).
/// So the split that matters is *cold deps vs warm app*, not first-run vs later: a
/// target whose deps are not yet built compiles under sccache, and every warm
/// rebuild after that uses incremental. A machine-level
/// `build.rustc-wrapper = "sccache"` + `build.incremental = false` would otherwise
/// force every rebuild to re-codegen the whole app from scratch; the warm path
/// overrides it in THIS child only.
///
/// Behaviour-identical either way — incremental changes codegen partitioning, not
/// program semantics (enforced by the clean-vs-incremental parity gate) — and
/// scoped to the watch child: `ipe build` (release / clean / CI) never calls this.
enum BuildAccel {
    /// Explicit opt-out ([`NO_INCREMENTAL_ENV`]): leave the machine's build
    /// configuration untouched for the emitted-app rebuild.
    MachineDefault,
    /// Cold target — an `sccache` wrapper for a fast one-time dependency compile.
    /// Incremental is off (the two cannot coexist); the payoff is bounded to the
    /// first build on a fresh target.
    ColdSccache(PathBuf),
    /// Warm target — per-crate incremental codegen, sccache taken out of the
    /// picture for this child.
    WarmIncremental,
}

/// The target directory this watch build will use: an inherited `CARGO_TARGET_DIR`
/// wins, else cargo's default of `<out_dir>/target`.
fn watch_target_dir(out_dir: &Path) -> PathBuf {
    std::env::var_os("CARGO_TARGET_DIR").map_or_else(|| out_dir.join("target"), PathBuf::from)
}

/// Whether a resolved target directory already holds a compiled dependency
/// library (a single `.rlib` under `debug/deps` — the registry crates the emitted
/// app links). Fail-safe: any I/O error reads as no-rlib, so the worst case is one
/// extra sccache-mode build, never a wrong-but-fast one. Pure in its argument —
/// the ambient-env resolution lives in [`target_is_warm`].
fn dir_has_dep_rlib(target_dir: &Path) -> bool {
    let deps = target_dir.join("debug").join("deps");
    let Ok(entries) = std::fs::read_dir(&deps) else {
        return false;
    };
    entries
        .flatten()
        .any(|e| e.path().extension().is_some_and(|x| x == "rlib"))
}

/// A target is *warm* once it already holds compiled dependency libraries; a
/// fresh (or pruned) target holds none. Resolves the target directory cargo will
/// actually use (honouring an inherited `CARGO_TARGET_DIR`, exactly as the watch
/// build will) and checks it for a dependency `.rlib`.
fn target_is_warm(out_dir: &Path) -> bool {
    dir_has_dep_rlib(&watch_target_dir(out_dir))
}

/// Locate an `sccache` executable on `PATH`, if the machine has one. sccache is
/// optional: absent, a cold build simply falls back to the warm/incremental path
/// — correct, only slower for the first compile.
fn find_sccache() -> Option<PathBuf> {
    let path = std::env::var_os("PATH")?;
    std::env::split_paths(&path)
        .flat_map(|dir| [dir.join("sccache"), dir.join("sccache.exe")])
        .find(|p| p.is_file())
}

/// Pick the acceleration strategy for the next watch build from the opt-out gate
/// and the target's warmth. A cold target with sccache available builds its deps
/// under sccache; a warm target (or no sccache) uses incremental. Re-evaluated
/// per build, so the cold sccache build's deps make the very next build warm and
/// incremental — the one-time cold→warm transition the design intends.
///
/// The decision is computed at the call site and passed to
/// [`apply_build_accel_env`], keeping the env-to-`Command` mapping a pure function.
fn choose_build_accel(out_dir: &Path, opt_out: bool) -> BuildAccel {
    if opt_out {
        return BuildAccel::MachineDefault;
    }
    match (target_is_warm(out_dir), find_sccache()) {
        (false, Some(sccache)) => BuildAccel::ColdSccache(sccache),
        _ => BuildAccel::WarmIncremental,
    }
}

/// Map a [`BuildAccel`] onto a watch child's `cargo build` environment. Pure: the
/// only inputs are the chosen strategy and the command.
fn apply_build_accel_env(cmd: &mut Command, accel: &BuildAccel) {
    match accel {
        BuildAccel::MachineDefault => {}
        BuildAccel::ColdSccache(sccache) => {
            // sccache cannot cache an incremental crate, so incremental is off for
            // this cold build. Wire the wrapper explicitly rather than trust the
            // machine config, so the cold path works with or without a global
            // sccache setting.
            cmd.env("CARGO_INCREMENTAL", "0");
            cmd.env("RUSTC_WRAPPER", sccache);
            cmd.env("RUSTC_WORKSPACE_WRAPPER", "");
        }
        BuildAccel::WarmIncremental => {
            cmd.env("CARGO_INCREMENTAL", "1");
            // Clear BOTH wrapper hooks so a machine-level `rustc-wrapper = "sccache"`
            // (which forces non-incremental) does not defeat the incremental
            // request. Empty string, not `remove_env`: cargo reads the wrapper from
            // its resolved config, so an empty override in the child env is what
            // actually disables it — removing the var alone would let the config win.
            cmd.env("RUSTC_WRAPPER", "");
            cmd.env("RUSTC_WORKSPACE_WRAPPER", "");
        }
    }
}

/// Read a boolean opt-out/opt-in env gate: true when the variable is set to any
/// value other than empty or `0`.
fn env_flag_on(name: &str) -> bool {
    std::env::var(name).is_ok_and(|v| !v.is_empty() && v != "0")
}

/// waiter thread that reports completion (or "killed — superseded")
/// through `evt_tx`, tagged with `generation`. Returns a shared handle the
/// orchestrator can `.kill()` from a DIFFERENT thread while the waiter is
/// concurrently polling it — see the module doc's cancellation section.
///
/// The returned handle is wrapped in `Arc<Mutex<..>>` rather than handed
/// out as a bare `Child` because BOTH the orchestrator (kill-on-supersede)
/// and this function's own waiter thread (exit detection) need independent
/// access; the waiter deliberately uses `try_wait` in a short poll loop
/// rather than a blocking `wait()` so it never holds the lock across a
/// call that could block for the build's entire duration — holding the
/// lock there would make the orchestrator's `.kill()` block on the very
/// wait it's trying to interrupt (a real deadlock this design avoids by
/// construction, not by convention).
///
/// # Errors
/// An I/O error if the `cargo` process itself cannot be spawned.
fn spawn_cargo_build(
    cargo_path: &Path,
    out_dir: &Path,
    generation: u64,
    evt_tx: mpsc::Sender<OrchestratorEvent>,
    quiet: bool,
) -> std::io::Result<Arc<std::sync::Mutex<Child>>> {
    let mut cmd = Command::new(cargo_path);
    cmd.arg("build")
        .arg("--message-format=json")
        .current_dir(out_dir)
        .stdout(std::process::Stdio::piped())
        .stderr(std::process::Stdio::piped());
    let accel = choose_build_accel(out_dir, env_flag_on(NO_INCREMENTAL_ENV));
    apply_build_accel_env(&mut cmd, &accel);
    if quiet {
        cmd.arg("-q");
    } else {
        // Force colour + the progress bar through the pipe when our stderr is a terminal.
        crate::force_cargo_terminal_ui(&mut cmd);
    }
    // Anchor the cargo phase at spawn — the waiter thread reports the elapsed
    // time back through `CargoDone` for `IPE_WATCH_TIMING`.
    let cargo_started = Instant::now();
    let mut child = cmd.spawn()?;

    // Take the pipes now, before the `Child` moves behind the shared lock —
    // reading them on their own threads (rather than after exit) avoids the
    // classic `Command`-pipe deadlock where a full OS pipe buffer blocks the
    // child before it can exit.
    let stdout = child.stdout.take();
    let stderr = child.stderr.take();
    let shared = Arc::new(std::sync::Mutex::new(child));
    let shared_for_waiter = Arc::clone(&shared);

    let stdout_reader = thread::spawn(move || read_all(stdout));
    // Relay stderr live so the user sees cargo's progress bar and compiler
    // messages as they arrive, while still capturing the full text for the
    // failure diagnostic (CargoOutcome::Red carries it).
    let stderr_reader = thread::spawn(move || relay_and_capture_stderr(stderr));

    thread::spawn(move || {
        let status = loop {
            let polled = shared_for_waiter
                .lock()
                .ok()
                .and_then(|mut c| c.try_wait().ok().flatten());
            if let Some(status) = polled {
                break Some(status);
            }
            thread::sleep(Duration::from_millis(30));
        };
        let out_buf = stdout_reader.join().unwrap_or_default();
        let err_buf = stderr_reader.join().unwrap_or_default();
        let outcome = match status {
            None => CargoOutcome::Red("cargo build: could not observe exit status".to_owned()),
            Some(status) if status.success() => find_executable_path(&out_buf).map_or_else(
                || {
                    CargoOutcome::Red(
                        "cargo build succeeded but produced no executable artifact".to_owned(),
                    )
                },
                CargoOutcome::Green,
            ),
            Some(status) => {
                if is_killed_status(status) {
                    CargoOutcome::Killed
                } else {
                    CargoOutcome::Red(err_buf)
                }
            }
        };
        let _ = evt_tx.send(OrchestratorEvent::CargoDone {
            generation,
            outcome,
            cargo: cargo_started.elapsed(),
        });
    });

    Ok(shared)
}

/// Drain an optional pipe to a `String`, best-effort (a read failure yields
/// whatever was read so far — never a panic, never lost build output on a
/// transient short read).
fn read_all(pipe: Option<impl std::io::Read>) -> String {
    let mut buf = String::new();
    if let Some(mut s) = pipe {
        let _ = s.read_to_string(&mut buf);
    }
    buf
}

/// Relay `cargo`'s stderr live to our own stderr (so the user sees the progress
/// bar and compiler messages as they arrive) and simultaneously accumulate the
/// full text for the failure diagnostic. Uses the same chunk boundary as
/// [`crate::read_progress_chunk`] so carriage-return progress-bar frames flow
/// through without buffering until the next newline.
fn relay_and_capture_stderr(pipe: Option<impl std::io::Read>) -> String {
    use std::io::{BufReader, Write as _};
    let mut captured = String::new();
    let Some(reader) = pipe else { return captured };
    let mut reader = BufReader::new(reader);
    let mut chunk = String::new();
    loop {
        chunk.clear();
        match crate::read_progress_chunk(&mut reader, &mut chunk) {
            Ok(0) | Err(_) => break,
            Ok(_) => {
                eprint!("{chunk}");
                let _ = std::io::stderr().flush();
                captured.push_str(&chunk);
            }
        }
    }
    captured
}

/// Whether a non-success exit status looks like "killed by us" (a signal
/// termination on unix, matching `Child::kill`'s SIGKILL) rather than a
/// genuine compile error — used to route a superseded build to
/// `CargoOutcome::Killed` (silently dropped) instead of
/// `CargoOutcome::Red` (reported as a failure INV-3 must preserve
/// last-good against).
fn is_killed_status(status: std::process::ExitStatus) -> bool {
    #[cfg(unix)]
    {
        use std::os::unix::process::ExitStatusExt as _;
        status.signal().is_some()
    }
    #[cfg(not(unix))]
    {
        !status.success()
    }
}

/// Parse `cargo build --message-format=json`'s stdout for the produced
/// `executable` artifact path. Mirrors `oracle::build_rust_binary`'s own
/// parsing (that crate stays a dev-dependency only — see `Cargo.toml`'s own
/// note — so this is a small, independent re-implementation rather than a
/// production dependency on a test-utility crate).
fn find_executable_path(cargo_json_stdout: &str) -> Option<PathBuf> {
    for line in cargo_json_stdout.lines() {
        let value: serde_json::Value = serde_json::from_str(line).ok()?;
        if value.get("reason").and_then(serde_json::Value::as_str) == Some("compiler-artifact")
            && let Some(exe) = value.get("executable").and_then(serde_json::Value::as_str)
        {
            return Some(PathBuf::from(exe));
        }
    }
    None
}

#[cfg(test)]
mod tests {
    use super::{
        BuildAccel, Command, Duration, OrchestratorEvent, RESOLVE_RETRY_DELAY, RebuildTimings,
        apply_build_accel_env, child_env, choose_build_accel, dir_has_dep_rlib, env_flag_on, mpsc,
        schedule_resolve_retry,
    };
    use std::ffi::OsStr;
    use std::path::{Path, PathBuf};

    /// Collect a `Command`'s env overrides as owned strings, resolving the
    /// override VALUE (`None` means "remove from the child env"). Lets a test
    /// assert exactly which vars `apply_dev_incremental_env` set and to what.
    fn env_overrides(cmd: &Command) -> Vec<(String, Option<String>)> {
        cmd.get_envs()
            .map(|(k, v)| {
                (
                    k.to_string_lossy().into_owned(),
                    v.map(|v| v.to_string_lossy().into_owned()),
                )
            })
            .collect()
    }

    fn override_for<'a>(
        env: &'a [(String, Option<String>)],
        key: &str,
    ) -> Option<&'a Option<String>> {
        env.iter().find(|(k, _)| k == key).map(|(_, v)| v)
    }

    /// The warm path requests incremental codegen AND clears both rustc wrapper
    /// hooks in the child env, so a machine-level `rustc-wrapper = "sccache"`
    /// (which forces non-incremental) cannot defeat the incremental build. The
    /// clear is an EMPTY override, not a removal — cargo reads the wrapper from
    /// its resolved config, so only an empty value in the child env disables it.
    #[test]
    fn warm_accel_enables_incremental_and_clears_wrapper() {
        let mut cmd = Command::new(OsStr::new("cargo"));
        apply_build_accel_env(&mut cmd, &BuildAccel::WarmIncremental);
        let env = env_overrides(&cmd);
        assert_eq!(
            override_for(&env, "CARGO_INCREMENTAL"),
            Some(&Some("1".to_owned())),
            "the warm path must request incremental codegen"
        );
        assert_eq!(
            override_for(&env, "RUSTC_WRAPPER"),
            Some(&Some(String::new())),
            "the warm path must clear RUSTC_WRAPPER to an empty value (disables sccache)"
        );
        assert_eq!(
            override_for(&env, "RUSTC_WORKSPACE_WRAPPER"),
            Some(&Some(String::new())),
            "the warm path must clear RUSTC_WORKSPACE_WRAPPER too"
        );
    }

    /// The cold path wires the `sccache` wrapper for a fast one-time dependency
    /// compile and turns incremental OFF (the two are mutually exclusive).
    #[test]
    fn cold_accel_wires_sccache_and_disables_incremental() {
        let sccache = PathBuf::from("/usr/bin/sccache");
        let mut cmd = Command::new(OsStr::new("cargo"));
        apply_build_accel_env(&mut cmd, &BuildAccel::ColdSccache(sccache.clone()));
        let env = env_overrides(&cmd);
        assert_eq!(
            override_for(&env, "CARGO_INCREMENTAL"),
            Some(&Some("0".to_owned())),
            "the cold path must disable incremental (sccache cannot cache it)"
        );
        assert_eq!(
            override_for(&env, "RUSTC_WRAPPER"),
            Some(&Some(sccache.to_string_lossy().into_owned())),
            "the cold path must wire the sccache wrapper explicitly"
        );
    }

    /// With the opt-out on, the watch build inherits the machine's normal build
    /// configuration: no incremental request, no wrapper override.
    #[test]
    fn machine_default_accel_leaves_env_untouched() {
        let mut cmd = Command::new(OsStr::new("cargo"));
        apply_build_accel_env(&mut cmd, &BuildAccel::MachineDefault);
        let env = env_overrides(&cmd);
        assert!(
            override_for(&env, "CARGO_INCREMENTAL").is_none(),
            "opt-out must not request incremental"
        );
        assert!(
            override_for(&env, "RUSTC_WRAPPER").is_none(),
            "opt-out must not touch the rustc wrapper"
        );
    }

    /// A present hot token means the watch built the hot-swap emit, so the child
    /// env must carry BOTH the control token and `IPE_WATCH_HOT_APPEARANCE=1` —
    /// the flag the emitted app's runtime reads to activate its overlay, set
    /// explicitly so default-on hot-swap works without the user setting anything.
    #[test]
    fn child_env_activates_hot_appearance_when_token_present() {
        let env = child_env(
            3000,
            Path::new("/tmp/ipe-out"),
            Some("deadbeef"),
            false,
            false,
        );
        assert!(
            env.iter()
                .any(|(k, v)| k == "IPE_WATCH_HOT_TOKEN" && v == "deadbeef"),
            "the control token must be handed to the child"
        );
        assert!(
            env.iter()
                .any(|(k, v)| k == "IPE_WATCH_HOT_APPEARANCE" && v == "1"),
            "a hot token present must activate the child's overlay via IPE_WATCH_HOT_APPEARANCE=1"
        );
    }

    /// No hot token (hot-swap off) means no overlay-activating flag reaches the
    /// child — the emitted app stays inert.
    #[test]
    fn child_env_omits_hot_appearance_without_token() {
        let env = child_env(3000, Path::new("/tmp/ipe-out"), None, false, false);
        assert!(
            !env.iter().any(|(k, _)| k == "IPE_WATCH_HOT_APPEARANCE"),
            "without a hot token the child must not be told to activate the overlay"
        );
        assert!(
            !env.iter().any(|(k, _)| k == "IPE_WATCH_HOT_TOKEN"),
            "without a hot token no control token is handed to the child"
        );
    }

    /// The opt-out short-circuits to `MachineDefault` regardless of warmth, so a
    /// user who opts out always gets the machine's normal build configuration.
    #[test]
    fn opt_out_chooses_machine_default() {
        let dir = std::env::temp_dir();
        assert!(
            matches!(choose_build_accel(&dir, true), BuildAccel::MachineDefault),
            "opt-out must choose MachineDefault"
        );
    }

    /// Warmth detection over a resolved target directory: empty reads cold, a
    /// `debug/deps` holding an `.rlib` reads warm. Drives the cold-sccache →
    /// warm-incremental transition across a session. Tests the ambient-env-free
    /// core so it is independent of the `CARGO_TARGET_DIR` the test harness sets.
    #[test]
    fn target_warmth_tracks_dep_rlibs() {
        let target = std::env::temp_dir().join(format!(
            "ipe_warmth_{}_{}",
            std::process::id(),
            RESOLVE_RETRY_DELAY.as_nanos()
        ));
        let deps = target.join("debug").join("deps");
        // No target yet ⇒ cold.
        assert!(!dir_has_dep_rlib(&target), "a fresh target must read cold");
        std::fs::create_dir_all(&deps).expect("create deps dir");
        // Deps dir exists but holds no rlib ⇒ still cold.
        assert!(
            !dir_has_dep_rlib(&target),
            "an empty deps dir must still read cold"
        );
        std::fs::write(deps.join("libfoo-0000.rlib"), b"x").expect("write rlib");
        // A compiled dependency library is present ⇒ warm.
        assert!(
            dir_has_dep_rlib(&target),
            "a target with a dep rlib must read warm"
        );
        let _ = std::fs::remove_dir_all(&target);
    }

    /// The env flag reader treats an unset variable as off — the safe default
    /// for the incremental opt-out. (Set/`0`/non-empty branches are exercised
    /// without mutating process env, which the workspace lints forbid.)
    #[test]
    fn env_flag_reader_treats_unset_as_off() {
        // A non-`IPE_`-prefixed name no other code sets (so it is reliably
        // unset in the test process, and the env-docs scanner does not treat it
        // as an undocumented `IPE_*` variable).
        assert!(
            !env_flag_on("WATCH_FLAG_READER_DEFINITELY_UNSET_PROBE"),
            "an unset flag must read as off"
        );
    }

    /// The summed phases must equal the total when the total IS the sum plus a
    /// small unaccounted residual — the invariant the `report` residual line
    /// surfaces. Built with fixed durations so it is deterministic (no
    /// wall-clock): the residual a real cycle prints is `total − summed`, and
    /// this pins that `summed()` adds every recorded phase (a dropped phase
    /// would inflate the residual and silently mis-attribute cost).
    #[test]
    fn summed_phases_account_for_the_whole_when_no_residual() {
        let ms = Duration::from_millis;
        let t = RebuildTimings {
            settle: Some(ms(10)),
            resolve: Some(ms(5)),
            compile: Some(ms(20)),
            write: Some(ms(3)),
            cargo: Some(ms(4000)),
            restart: Some(ms(120)),
            ..RebuildTimings::default()
        };
        // A fabricated "observed total" equal to the sum: residual is zero,
        // i.e. the phases account for the whole cycle within tolerance.
        let total = t.summed();
        let residual = total.saturating_sub(t.summed());
        assert_eq!(
            t.summed(),
            ms(10 + 5 + 20 + 3 + 4000 + 120),
            "summed() must add every recorded phase"
        );
        assert!(
            residual <= Duration::from_millis(1),
            "phase sum must equal a total that IS the sum, within 1ms: residual {residual:?}"
        );
    }

    /// A missing phase (e.g. `settle` on the kickoff cycle) is simply omitted
    /// from the sum — never counted as zero-that-inflates, never a panic.
    #[test]
    fn summed_skips_unrecorded_phases() {
        let ms = Duration::from_millis;
        let t = RebuildTimings {
            resolve: Some(ms(5)),
            compile: Some(ms(20)),
            ..RebuildTimings::default()
        };
        assert_eq!(t.summed(), ms(25));
    }

    /// CO-INCR-008: a `resolve_project_sources` failure must not lose the
    /// rebuild cycle silently. `schedule_resolve_retry` is the orchestrator's
    /// ONLY route back into its event loop after such a failure (no
    /// filesystem event is guaranteed to follow), so this pins that a
    /// `FsBatch` retry actually lands on the channel.
    #[test]
    fn schedule_resolve_retry_sends_a_follow_up_fs_batch() {
        let (evt_tx, evt_rx) = mpsc::channel::<OrchestratorEvent>();
        schedule_resolve_retry(&evt_tx);
        let event = evt_rx
            .recv_timeout(RESOLVE_RETRY_DELAY * 4)
            .expect("a retry FsBatch must arrive — the save must not be lost");
        assert!(
            matches!(event, OrchestratorEvent::FsBatch { .. }),
            "the retry must be a FsBatch, not some other orchestrator event"
        );
    }

    /// The retry is delayed, not immediate — an instant re-send would defeat
    /// the point of a "short delay" retry (hammering a still-broken
    /// filesystem state) and would also mask a resolve failure that
    /// self-heals within one debounce window.
    #[test]
    fn schedule_resolve_retry_waits_before_sending() {
        let (evt_tx, evt_rx) = mpsc::channel::<OrchestratorEvent>();
        schedule_resolve_retry(&evt_tx);
        assert!(
            evt_rx.recv_timeout(Duration::from_millis(10)).is_err(),
            "the retry must not fire immediately"
        );
        evt_rx
            .recv_timeout(RESOLVE_RETRY_DELAY * 4)
            .expect("the retry must still arrive after the short delay");
    }
}
