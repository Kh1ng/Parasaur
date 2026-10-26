use super::decision::decide_next_action;
use super::human_required_reason::HumanRequiredReason;
use super::recovery::{
    defer_if_branch_attached, detect_stuck_loop, human_required_already_reported,
    human_required_report_identity, latest_clear_attempts_timestamp, no_admission_diagnostics,
    recently_capacity_deferred_work_ids, reconcile_abandoned_dispatches, record_action_events,
    remediation_plan_for_action, report_blocked_work_items_once, retain_snapshot_candidates,
};
use super::NextAction;
use anyhow::Result;
use serde::Serialize;
use std::collections::HashSet;
use std::sync::mpsc::sync_channel;
use std::time::Duration;

#[path = "runtime/profile_lock.rs"]
mod profile_lock;
pub use profile_lock::acquire_profile_lock;
use profile_lock::reload_config_for_profile;

#[path = "runtime/probe.rs"]
mod probe;

#[path = "runtime/route_state.rs"]
mod route_state;
use route_state::{record_capacity_deferral, route_state_fingerprint};
#[path = "runtime/action_execution.rs"]
mod action_execution;
#[path = "runtime/dispatch_policy.rs"]
mod dispatch_policy;
pub(crate) use action_execution::execute_action;
#[path = "runtime/dispatch_state.rs"]
mod dispatch_state;
use dispatch_state::{
    action_review_generation, append_stuck_loop_gate_if_transition, is_validation_gate_failure,
    suppress_recent_capacity_deferrals,
};
#[path = "runtime/intake.rs"]
mod intake;
use intake::{
    action_creates_managed_mr, action_intake_key, apply_parallel_projection, retain_unclaimed_work,
    unavailable_work_ids,
};
#[path = "runtime/admission.rs"]
mod admission;
#[path = "runtime/merge.rs"]
mod merge;
#[path = "runtime/node_capacity.rs"]
mod node_capacity;
#[cfg(test)]
pub(crate) use node_capacity::test_lease as test_node_lease;
#[path = "runtime/node_reprobe.rs"]
mod node_reprobe;
pub use admission::RouteNodeAdmission;
pub(crate) use admission::{NodeAdmissionDeferred, WorkerNodeLease};
use node_reprobe::{NodeCapacityReprobe, WaitOutcome as ReprobeWaitOutcome};
#[path = "runtime/pm.rs"]
mod pm;

/// TICKET-079: `gah loop --once` -- exactly one bounded controller
/// iteration. Build a snapshot, decide one action, execute at most that
/// one action, persist one controller event trail, exit. No daemon, no
/// repeated recursion.
#[derive(Debug, Serialize)]
pub struct LoopOnceResult {
    pub action: NextAction,
    pub outcome: String,
}

/// Resolve the CLI parallel argument without consuming recurring mode's zero
/// sentinel. A daemon must reload the profile limit each iteration; `--once`
/// resolves it once for its bounded invocation.
pub(crate) fn loop_parallel_argument(
    once: bool,
    cli_parallel: usize,
    configured_parallel: usize,
) -> usize {
    if once && cli_parallel == 0 {
        configured_parallel
    } else {
        cli_parallel
    }
}

/// Say once, on each change, how many workers scaling allows and why.
fn report_worker_limits(
    last: &mut Option<crate::routing::worker_scaling::WorkerLimits>,
    current: Option<crate::routing::worker_scaling::WorkerLimits>,
) {
    if *last == current {
        return;
    }
    if let Some(limits) = &current {
        if limits.workers != limits.baseline_workers || last.is_some() {
            eprintln!(
                "gah loop: {} workers (baseline {}){}",
                limits.workers,
                limits.baseline_workers,
                limits
                    .notes
                    .iter()
                    .map(|note| format!("; {note}"))
                    .collect::<String>()
            );
        }
    }
    *last = current;
}

/// Run the controller continuously in one process. The process lock is held
/// for the lifetime of the loop so a second manager for the same profile
/// cannot create a competing worker pool.
pub fn run_loop(
    initial_cfg: &crate::config::GahConfig,
    profile_name: &str,
    json: bool,
    parallel_arg: usize,
    skip_validation_gate: bool,
    config_path: &std::path::Path,
) -> Result<()> {
    super::ownership::arm_parent_death_signal()?;
    let _lock = acquire_profile_lock(profile_name, config_path)?;
    let mut cloud_heartbeat = crate::node_register::CloudHeartbeat::default();

    // Dashboard Settings can change config at runtime; reload every iteration
    // so changes apply without a restart. Falls back to the last-good config
    // on a transient read failure (e.g. mid-write) rather than killing the loop.
    let mut last_cfg: Option<crate::config::GahConfig> = Some(initial_cfg.clone());
    let mut last_limits = None;

    loop {
        if crate::runner::shutdown_requested() {
            return shutdown_gracefully();
        }

        let cfg: &crate::config::GahConfig = match reload_config_for_profile(
            config_path,
            profile_name,
        ) {
            Ok(mut loaded) => {
                let limits = crate::routing::worker_scaling::apply(&mut loaded, profile_name);
                report_worker_limits(&mut last_limits, limits);
                last_cfg = Some(loaded);
                last_cfg.as_ref().expect("just assigned")
            }
            Err(error) => {
                eprintln!(
                    "gah loop: failed to reload config ({}); reusing last known config for this iteration",
                    error
                );
                match last_cfg.as_ref() {
                    Some(c) => c,
                    // No prior successful load to fall back to; surface the error.
                    None => return Err(error),
                }
            }
        };

        if cfg.defaults.factory_enabled == Some(false) {
            eprintln!("gah loop: factory module disabled; stopping before another iteration");
            return shutdown_gracefully();
        }
        cloud_heartbeat.refresh(cfg);

        // The explicit `--parallel` flag (parallel_arg > 0) wins; otherwise
        // derive the worker pool size from the freshly-reloaded profile.
        let parallel = if parallel_arg == 0 {
            crate::config::get_profile(cfg, profile_name)?.max_parallel_workers() as usize
        } else {
            parallel_arg
        };

        // Transient failures must not kill the daemon; a validation-gate
        // failure means the safety check itself is unhealthy, so that one
        // pauses immediately for an explicit operator restart instead.
        #[rustfmt::skip]
        let iteration = run_pass(cfg, profile_name, json, parallel, skip_validation_gate, true);
        match iteration {
            Ok(()) if !wait_for_loop_interval(pass_interval(cfg, profile_name)) => {
                return shutdown_gracefully();
            }
            Ok(()) => {}
            Err(_) if crate::runner::shutdown_requested() => {
                return shutdown_gracefully();
            }
            Err(error) if is_validation_gate_failure(&error) => {
                eprintln!(
                    "gah loop: paused because the validation gate failed; repair the gate and explicitly restart the loop: {error:#}"
                );
                return Err(error);
            }
            Err(error) => {
                eprintln!("gah loop: iteration failed; retrying after backoff: {error:#}");
                // Stay shutdown-responsive during backoff too.
                if !wait_for_loop_interval(Duration::from_secs(300)) {
                    return shutdown_gracefully();
                }
            }
        }
    }
}

/// Shared by every shutdown-detection branch in `run_loop`: log, kill any
/// still-running background probe children (see `runner::process::
/// kill_all_supervised_children`'s doc comment), then exit clean.
fn shutdown_gracefully() -> Result<()> {
    eprintln!("gah loop: shutdown requested; stopping after terminal cleanup");
    crate::runner::process::kill_all_supervised_children();
    Ok(())
}

/// The profile's configured rest between passes (`pacing.loop_interval_seconds`).
fn pass_interval(cfg: &crate::config::GahConfig, profile_name: &str) -> Duration {
    crate::config::get_profile(cfg, profile_name)
        .map(|profile| profile.pacing.loop_interval())
        .unwrap_or_else(|_| crate::quota::PacingConfig::default().loop_interval())
}

fn wait_for_loop_interval(delay: Duration) -> bool {
    wait_interruptibly(delay, crate::runner::shutdown_requested)
}

fn wait_interruptibly(delay: Duration, shutdown_requested: impl Fn() -> bool) -> bool {
    crate::clock::wait_for(delay, shutdown_requested)
}

/// Total memory of this node when the platform exposes it. `gah config
/// set` uses it to reject node-capacity values this node could never
/// admit (review of #1383); callers skip the check when it is `None`, so
/// configs written for other machines still load and save.
pub fn node_total_memory_bytes() -> Option<u64> {
    node_capacity::sample()
        .ok()
        .map(|pressure| pressure.memory_total_bytes)
}

/// What admission measures against on this node, for the Settings page to
/// show beside the limits. `None` where the platform does not expose it.
#[derive(Debug, Clone, Copy, PartialEq, serde::Serialize)]
pub struct NodeResources {
    pub memory_total_mib: u64,
    pub memory_available_mib: u64,
    pub logical_cpus: usize,
    pub load_one: f64,
    /// Inside WSL the totals are what Windows grants the VM, not the host's.
    pub wsl: bool,
}

pub fn node_resources() -> Option<NodeResources> {
    let pressure = node_capacity::sample().ok()?;
    Some(NodeResources {
        memory_total_mib: pressure.memory_total_bytes / (1024 * 1024),
        memory_available_mib: pressure.memory_available_bytes / (1024 * 1024),
        logical_cpus: pressure.logical_cpus,
        load_one: pressure.load_one,
        wsl: std::env::var_os("WSL_DISTRO_NAME").is_some(),
    })
}

/// Announce node-capacity settings when they change, not on every ~30s
/// iteration -- an unattended loop would otherwise repeat the same line
/// about 2,880 times a day (review of #1383). A fresh process (`--once`,
/// loop restart) always logs once. Also warns when the settings can
/// never be satisfied on this node, instead of leaving that fact buried
/// in per-deferral logs.
fn log_node_capacity_settings(settings: crate::config::NodeCapacitySettings) {
    static LAST_LOGGED: std::sync::Mutex<Option<crate::config::NodeCapacitySettings>> =
        std::sync::Mutex::new(None);
    let Ok(mut last) = LAST_LOGGED.lock() else {
        return;
    };
    if last.as_ref() == Some(&settings) {
        return;
    }
    *last = Some(settings);
    eprintln!(
        "gah loop: node capacity worker reservation {} MiB, memory floor {}",
        settings.worker_memory_mib,
        settings.floor_description(),
    );
    if let Some(total) = node_total_memory_bytes() {
        if let Err(error) = settings.validate_against_node_total(total) {
            eprintln!("gah loop: WARNING {error:#}");
        }
    }
}

pub fn run_once(
    cfg: &crate::config::GahConfig,
    profile_name: &str,
    json: bool,
    parallel: usize,
    skip_validation_gate: bool,
    run_periodic_probes: bool,
) -> Result<()> {
    let mut cloud_heartbeat = crate::node_register::CloudHeartbeat::default();
    cloud_heartbeat.refresh(cfg);
    run_pass(
        cfg,
        profile_name,
        json,
        parallel,
        skip_validation_gate,
        run_periodic_probes,
    )
}

fn run_pass(
    cfg: &crate::config::GahConfig,
    profile_name: &str,
    json: bool,
    parallel: usize,
    skip_validation_gate: bool,
    run_periodic_probes: bool,
) -> Result<()> {
    log_node_capacity_settings(cfg.defaults.node_capacity);
    let mut ledger_entries = crate::ledger::read_entries(cfg)?;
    reconcile_abandoned_dispatches(cfg, profile_name, &mut ledger_entries)?;
    super::import_requested_changes(cfg, profile_name, &mut ledger_entries)?;
    let profile = crate::config::get_profile(cfg, profile_name)?;
    let claim_scope = crate::work_claim::canonical_claim_scope(profile_name, &profile.repo_id);
    let now = crate::clock::now_utc();
    // Issue #761: recurring daemon only, not --once (see probe.rs).
    if run_periodic_probes {
        probe::run(now)?;
    }
    let mut snapshot =
        crate::status::build_snapshot_from_entries(cfg, profile_name, now, &ledger_entries)?;
    crate::prune::run_automatic(cfg, profile_name, &ledger_entries, &snapshot)?;
    crate::events::record(
        cfg,
        crate::events::EventType::ObservationCompleted,
        Some(profile_name),
        None,
        format!("profile={profile_name}"),
    )?;
    let history = crate::events::read_events(cfg)?;
    let capacity_deferred_work_ids = suppress_recent_capacity_deferrals(
        cfg,
        &mut snapshot,
        &history,
        &ledger_entries,
        profile_name,
        &profile.repo_id,
    );

    // Issue #1381: blocked items are reported once even when other work is
    // dispatched this tick.
    report_blocked_work_items_once(cfg, profile_name, &snapshot)?;

    // For parallel > 1, we need to decide multiple actions
    if parallel > 1 {
        run_parallel_once(
            cfg,
            profile_name,
            &snapshot,
            &ledger_entries,
            json,
            parallel,
            skip_validation_gate,
        )?;
    } else {
        // Original single action behavior, moving past work another worker
        // or loop holds (issue #1430).
        let (action, outcome) =
            run_moving_past_held_work(&snapshot, &capacity_deferred_work_ids, |view, excluded| {
                run_selected_action(
                    cfg,
                    profile_name,
                    &claim_scope,
                    view,
                    excluded,
                    &history,
                    &ledger_entries,
                    skip_validation_gate,
                )
            })?;

        let stop_event_type = match &action {
            NextAction::WaitUntil { .. } => crate::events::EventType::WaitSelected,
            NextAction::HumanRequired { .. } => crate::events::EventType::HumanRequired,
            _ => crate::events::EventType::LoopStopped,
        };
        let admission_note = (!action_admitted_work(&action, &outcome)).then(|| {
            let node_deferral = outcome
                .starts_with("Deferred ")
                .then(|| {
                    outcome
                        .split_once("; admission reason: ")
                        .map(|(_, reason)| reason)
                })
                .flatten();
            no_admission_diagnostics(&snapshot, 0, 1, node_deferral)
        });
        let newly_reported = record_stop_event(
            cfg,
            profile_name,
            &history,
            &action,
            stop_event_type,
            &outcome,
        )?;

        if json {
            println!(
                "{}",
                serde_json::to_string_pretty(&LoopOnceResult { action, outcome })?
            );
        } else {
            if newly_reported {
                println!("Decided: {} -- {}", action.kind(), action.reason());
                println!("{outcome}");
            }
            if let Some(note) = admission_note {
                println!("{note}");
            }
        }
    }
    Ok(())
}

/// Issue #1430: run the selected action and, while its item turns out to be
/// held by another worker or loop, drop that item and run the next selection
/// in this same cycle, so a single-worker factory moves on instead of idling
/// until the next cycle. Every selection goes through `select_and_run`, the
/// same gates included. Each round excludes one more item, so the loop ends;
/// when nothing else is actionable the last skip is the cycle's outcome.
fn run_moving_past_held_work(
    snapshot: &crate::status::StatusSnapshot,
    excluded_work_ids: &HashSet<String>,
    mut select_and_run: impl FnMut(
        &crate::status::StatusSnapshot,
        &HashSet<String>,
    ) -> Result<(NextAction, String)>,
) -> Result<(NextAction, String)> {
    let mut view = snapshot.clone();
    let mut excluded = excluded_work_ids.clone();
    loop {
        let (action, outcome) = select_and_run(&view, &excluded)?;
        let Some(work_id) = action
            .work_id()
            .filter(|_| outcome_held_elsewhere(&outcome))
        else {
            return Ok((action, outcome));
        };
        excluded.insert(work_id.to_string());
        retain_snapshot_candidates(&mut view, &excluded, &HashSet::new());
        if !selects_work(&decide_next_action(&view)) {
            return Ok((action, outcome));
        }
        eprintln!("gah loop: {outcome}; selecting the next item");
    }
}

/// Outcome prefix of an action whose item another worker or loop holds: the
/// machine-local claim store or the provider claim refused it.
const HELD_ELSEWHERE_PREFIX: &str = "Skipped ";

fn outcome_held_elsewhere(outcome: &str) -> bool {
    outcome.starts_with(HELD_ELSEWHERE_PREFIX)
}

fn selects_work(action: &NextAction) -> bool {
    !matches!(
        action,
        NextAction::WaitUntil { .. } | NextAction::HumanRequired { .. } | NextAction::NoOp { .. }
    )
}

/// One single-worker selection: decide, apply the stuck-loop and attached-
/// branch gates, take the machine-local claim, and execute.
#[allow(clippy::too_many_arguments)]
fn run_selected_action(
    cfg: &crate::config::GahConfig,
    profile_name: &str,
    claim_scope: &str,
    snapshot: &crate::status::StatusSnapshot,
    excluded_work_ids: &HashSet<String>,
    history: &[crate::events::ControllerEvent],
    ledger_entries: &[crate::ledger::LedgerEntry],
    skip_validation_gate: bool,
) -> Result<(NextAction, String)> {
    let original_action = decide_next_action(snapshot);
    let original_review_generation = action_review_generation(snapshot, &original_action);
    let mut action = original_action.clone();
    let reset_after = original_action.work_id().and_then(|work_id| {
        latest_clear_attempts_timestamp(
            ledger_entries,
            profile_name,
            &crate::config::get_profile(cfg, profile_name).ok()?.repo_id,
            work_id,
        )
    });
    if let Some(reason) = detect_stuck_loop(
        history,
        profile_name,
        &original_action,
        reset_after,
        original_review_generation.as_deref(),
    ) {
        // Persist a work-item-scoped durable human gate so that
        // subsequent loop iterations see human_required=true for this
        // work_id via ledger_lookup_for_ticket and skip it, rather than
        // re-selecting DispatchTicket every cycle (the original
        // trip-without-latch bug).
        if let Some(wid) = original_action.work_id() {
            if let Err(e) = append_stuck_loop_gate_if_transition(
                cfg,
                profile_name,
                wid,
                &reason,
                original_review_generation.as_deref(),
            ) {
                eprintln!("warning: failed to persist stuck-loop gate: {e:#}");
            }
        }
        // TICKET-skip-and-continue: the gate is now persisted as a
        // work-item-scoped human_required (above). Re-decide with a fresh
        // snapshot that EXCLUDES the stuck work_id, so the controller
        // picks the NEXT eligible work item instead of parking the whole
        // profile. Only if nothing else is actionable do we surface
        // profile-wide HumanRequired -- that is a genuine profile stall,
        // not a single blocked ticket.
        let fresh = crate::status::build_snapshot_from_entries(
            cfg,
            profile_name,
            crate::clock::now_utc(),
            ledger_entries,
        )?;
        let mut scoped = fresh;
        let mut excluded_work_ids = excluded_work_ids.clone();
        excluded_work_ids.extend(original_action.work_id().map(str::to_string));
        retain_snapshot_candidates(&mut scoped, &excluded_work_ids, &HashSet::new());
        let redispatched = decide_next_action(&scoped);
        if redispatched.kind() == "no_op" {
            // Nothing else actionable -> genuine stall, surface it.
            action = NextAction::HumanRequired {
                work_id: original_action.work_id().map(str::to_string),
                reason,
                reference: original_action.work_id().map(str::to_string),
                reason_code: Some(HumanRequiredReason::StuckLoopGate.as_str().to_string()),
            };
        } else {
            action = redispatched;
        }
    }
    // TICKET-282: a FixMr reusing a branch already attached to a foreign
    // or stale worktree must be deferred (non-terminal) and the loop
    // continued with the next eligible item, never allowed to stall the
    // recurring loop on a hard `git worktree add` failure.
    if let Some(redispatch) =
        defer_if_branch_attached(cfg, profile_name, &action, excluded_work_ids)?
    {
        action = redispatch;
    }
    record_action_events(
        cfg,
        profile_name,
        &original_action,
        &action,
        original_review_generation.as_deref(),
    )?;

    let outcome = if let Some(work_id) = action
        .work_id()
        .map(crate::work_claim::normalize_work_identity)
        .filter(|_| {
            !matches!(
                action,
                NextAction::WaitUntil { .. }
                    | NextAction::HumanRequired { .. }
                    | NextAction::NoOp { .. }
            )
        }) {
        if !crate::work_claim::try_claim_work(claim_scope, &work_id)? {
            format!("{HELD_ELSEWHERE_PREFIX}already-claimed work '{work_id}'")
        } else {
            match execute_action(
                cfg,
                profile_name,
                &action,
                ledger_entries,
                skip_validation_gate,
                Some(RouteNodeAdmission::single_worker(
                    action.clone(),
                    cfg.defaults.node_capacity,
                )),
            ) {
                Ok(outcome) => {
                    crate::work_claim::release_owned_work(claim_scope, &work_id)?;
                    outcome
                }
                Err(error) => {
                    crate::work_claim::release_owned_work(claim_scope, &work_id)?;
                    return Err(error);
                }
            }
        }
    } else {
        execute_action(
            cfg,
            profile_name,
            &action,
            ledger_entries,
            skip_validation_gate,
            Some(RouteNodeAdmission::single_worker(
                action.clone(),
                cfg.defaults.node_capacity,
            )),
        )?
    };
    Ok((action, outcome))
}

/// Record the stop event for a wait/human-required/no-op action. A repeated
/// human-required report is suppressed (issue #1381), and human-required
/// events always persist their reason code and remediation plan so the
/// deduplication can recognise them on the next tick. Returns false when the
/// report was a repeat, so callers can suppress repeated text output too.
fn record_stop_event(
    cfg: &crate::config::GahConfig,
    profile_name: &str,
    _history: &[crate::events::ControllerEvent],
    action: &NextAction,
    stop_event_type: crate::events::EventType,
    outcome: &str,
) -> Result<bool> {
    let history = crate::events::read_events(cfg)?;
    if human_required_already_reported(&history, profile_name, action) {
        return Ok(false);
    }
    if matches!(action, NextAction::HumanRequired { .. }) {
        crate::events::record_with_reason_code_and_plan(
            cfg,
            stop_event_type,
            Some(profile_name),
            human_required_report_identity(action),
            outcome,
            action.human_required_reason_code(),
            remediation_plan_for_action(cfg, profile_name, action).as_ref(),
        )?;
        Ok(true)
    } else {
        crate::events::record(
            cfg,
            stop_event_type,
            Some(profile_name),
            action.work_id(),
            outcome,
        )?;
        Ok(true)
    }
}

/// TICKET-096: Parallel execution for multiple actions
fn run_parallel_once(
    cfg: &crate::config::GahConfig,
    profile_name: &str,
    _snapshot: &crate::status::StatusSnapshot,
    ledger_entries: &[crate::ledger::LedgerEntry],
    json: bool,
    max_parallel: usize,
    skip_validation_gate: bool,
) -> Result<()> {
    let mut executed_work_ids = HashSet::new();
    let profile = crate::config::get_profile(cfg, profile_name)?;
    let claim_scope = crate::work_claim::canonical_claim_scope(profile_name, &profile.repo_id);
    let effective_open_mr_limit = profile
        .max_open_managed_mrs
        .unwrap_or(max_parallel as u32)
        .max(1);
    let mut active_intake_keys: HashSet<String> = HashSet::new();

    // Profile routing decides which eligible backend handles each action. Do
    // not use the number of persisted availability rows as a worker limit:
    // that list is sparse and only contains observed scopes, not every
    // configured backend.
    let effective_parallel_limit = max_parallel;

    let mut results: Vec<(usize, LoopOnceResult)> = Vec::new();
    // Issue #1381: why the most recent fill attempt admitted nothing.
    let mut no_admission_note: Option<String> = None;
    // Sequences whose human-required stop repeated the previous tick's report.
    let mut repeated_stop_sequences: HashSet<usize> = HashSet::new();

    fn observe_snapshot(
        cfg: &crate::config::GahConfig,
        profile_name: &str,
        ledger_entries: &[crate::ledger::LedgerEntry],
    ) -> Result<crate::status::StatusSnapshot> {
        crate::status::build_snapshot_from_entries(
            cfg,
            profile_name,
            crate::clock::now_utc(),
            ledger_entries,
        )
    }

    std::thread::scope(|scope| -> Result<()> {
        let mut active = 0usize;
        let mut next_sequence = 0usize;
        let mut saw_real_work = false;
        let mut pending_terminal: Option<(NextAction, NextAction, Option<String>)> = None;
        let mut fill_attempts_remaining = effective_parallel_limit;
        let mut refill_suppressed = false;
        let mut node_capacity_reprobe = NodeCapacityReprobe::default();
        let mut node_alternative_attempts_remaining = effective_parallel_limit;
        let (done_tx, done_rx) = sync_channel::<(usize, LoopOnceResult)>(effective_parallel_limit);
        let (route_admission_tx, route_admission_rx) = admission::request_channel();
        let mut admission_coordinator =
            admission::Coordinator::new(route_admission_rx, cfg.defaults.node_capacity);

        'scheduler: loop {
            if admission::service_pending_request(
                &mut admission_coordinator,
                active,
                effective_parallel_limit,
                &mut node_capacity_reprobe,
            )? {
                continue;
            }

            while active < effective_parallel_limit && fill_attempts_remaining > 0 {
                if crate::runner::shutdown_requested() {
                    break;
                }
                fill_attempts_remaining -= 1;
                let claimed_work_ids = crate::work_claim::get_claimed_work_ids(&claim_scope)?;
                let ledger_entries = crate::ledger::read_entries(cfg)?;
                let mut fresh_snapshot = observe_snapshot(cfg, profile_name, &ledger_entries)?;
                apply_parallel_projection(
                    &mut fresh_snapshot,
                    &active_intake_keys,
                    effective_open_mr_limit,
                );

                // Do not let the next slot re-select work already claimed by
                // another process or spawned earlier in this refill cycle.
                retain_unclaimed_work(&mut fresh_snapshot, &claimed_work_ids, &executed_work_ids);

                let history = crate::events::read_events(cfg)?;
                let capacity_deferred_work_ids = suppress_recent_capacity_deferrals(
                    cfg,
                    &mut fresh_snapshot,
                    &history,
                    &ledger_entries,
                    profile_name,
                    &crate::config::get_profile(cfg, profile_name)?.repo_id,
                );

                let original_action = decide_next_action(&fresh_snapshot);
                let original_review_generation =
                    action_review_generation(&fresh_snapshot, &original_action);
                let mut action = original_action.clone();

                let reset_after = original_action.work_id().and_then(|work_id| {
                    latest_clear_attempts_timestamp(
                        &ledger_entries,
                        profile_name,
                        &crate::config::get_profile(cfg, profile_name).ok()?.repo_id,
                        work_id,
                    )
                });
                if let Some(reason) = detect_stuck_loop(
                    &history,
                    profile_name,
                    &original_action,
                    reset_after,
                    original_review_generation.as_deref(),
                ) {
                    if let Some(wid) = original_action.work_id() {
                        if let Err(error) = append_stuck_loop_gate_if_transition(
                            cfg,
                            profile_name,
                            wid,
                            &reason,
                            original_review_generation.as_deref(),
                        ) {
                            eprintln!("warning: failed to persist stuck-loop gate: {error:#}");
                        }
                    }
                    if let Some(stuck_wid) = original_action.work_id() {
                        fresh_snapshot
                            .merge_requests
                            .retain(|mr| mr.work_id.as_deref() != Some(stuck_wid));
                        fresh_snapshot
                            .available_tickets
                            .retain(|t| t.work_id.as_deref() != Some(stuck_wid));
                        fresh_snapshot
                            .issue_intake_rejections
                            .retain(|issue| issue.work_id.as_deref() != Some(stuck_wid));
                    }
                    let redispatched = decide_next_action(&fresh_snapshot);
                    if redispatched.kind() == "no_op" {
                        action = NextAction::HumanRequired {
                            work_id: original_action.work_id().map(str::to_string),
                            reason,
                            reference: original_action.work_id().map(str::to_string),
                            reason_code: Some(
                                HumanRequiredReason::StuckLoopGate.as_str().to_string(),
                            ),
                        };
                    } else {
                        action = redispatched;
                    }
                }

                if let Some(redispatch) = defer_if_branch_attached(
                    cfg,
                    profile_name,
                    &action,
                    &unavailable_work_ids(
                        &capacity_deferred_work_ids,
                        &claimed_work_ids,
                        &executed_work_ids,
                    ),
                )? {
                    action = redispatch;
                }

                let action_work_id = action
                    .work_id()
                    .map(crate::work_claim::normalize_work_identity);
                if let Some(work_id) = action_work_id.as_deref() {
                    if claimed_work_ids.iter().any(|claimed| claimed == work_id)
                        || executed_work_ids.contains(work_id)
                    {
                        continue;
                    }
                }

                match &action {
                    NextAction::WaitUntil { .. }
                    | NextAction::HumanRequired { .. }
                    | NextAction::NoOp { .. } => {
                        if !saw_real_work {
                            no_admission_note = Some(no_admission_diagnostics(
                                &fresh_snapshot,
                                active,
                                effective_parallel_limit,
                                None,
                            ));
                            pending_terminal =
                                Some((original_action, action, original_review_generation));
                            if active == 0 {
                                continue;
                            }
                        }
                        if active > 0 {
                            break;
                        }
                    }
                    _ => {
                        let waits_for_route = admission::action_needs_handshake(&action);
                        let node_capacity_lease = if waits_for_route {
                            None
                        } else {
                            let admission = match node_capacity::try_acquire(
                                &action,
                                admission_coordinator.active_node_workers(),
                                cfg.defaults.node_capacity,
                            ) {
                                Ok(admission) => admission,
                                Err(error) => {
                                    eprintln!(
                                        "gah loop: deferring worker because node pressure could not be verified: {error}"
                                    );
                                    node_capacity::LiveAdmission::Defer(format!(
                                        "node pressure unavailable: {error}"
                                    ))
                                }
                            };
                            match admission {
                                node_capacity::LiveAdmission::Admit(lease) => Some(lease),
                                node_capacity::LiveAdmission::Defer(reason) => {
                                    eprintln!(
                                        "gah loop: deferring additional worker at {active}/{effective_parallel_limit}: {reason}"
                                    );
                                    no_admission_note = Some(no_admission_diagnostics(
                                        &fresh_snapshot,
                                        active,
                                        effective_parallel_limit,
                                        Some(&reason),
                                    ));
                                    if active > 0 {
                                        node_capacity_reprobe.schedule(action.clone());
                                    }
                                    break;
                                }
                            }
                        };
                        if node_capacity_lease.is_some() {
                            node_capacity_reprobe.admitted(&action);
                        }

                        record_action_events(
                            cfg,
                            profile_name,
                            &original_action,
                            &action,
                            original_review_generation.as_deref(),
                        )?;

                        if let Some(work_id) = action_work_id.as_deref() {
                            // Reserve in memory on the tick; maintenance checks and
                            // claim acquisition run in the worker before any action.
                            executed_work_ids.insert(work_id.to_string());
                        }
                        if let Some(key) = action_intake_key(&action) {
                            active_intake_keys.insert(key);
                        }
                        pending_terminal = None;

                        let action_for_thread = action.clone();
                        let profile_for_thread = profile_name.to_string();
                        let claim_scope_for_thread = claim_scope.clone();
                        let work_id_for_thread = action_work_id;
                        let sequence = next_sequence;
                        next_sequence += 1;
                        saw_real_work = true;

                        let route_admission = if waits_for_route {
                            Some(RouteNodeAdmission::new(
                                sequence,
                                action_for_thread.clone(),
                                route_admission_tx.clone(),
                                cfg.defaults.node_capacity,
                            ))
                        } else {
                            None
                        };
                        if node_capacity_lease.is_some() {
                            admission_coordinator.register_lifecycle_worker(sequence);
                        }
                        let done_tx = done_tx.clone();
                        let ledger_entries_for_thread = ledger_entries;
                        active += 1;
                        scope.spawn(move || {
                            let _node_capacity_lease = node_capacity_lease;
                            let mut claimed_work_id = None;
                            let result =
                                std::panic::catch_unwind(std::panic::AssertUnwindSafe(|| {
                                    if let Some(work_id) = work_id_for_thread.as_deref() {
                                        if !crate::work_claim::try_claim_work(
                                            &claim_scope_for_thread,
                                            work_id,
                                        )? {
                                            return Ok(format!(
                                                "{HELD_ELSEWHERE_PREFIX}claim unavailable for '{work_id}'"
                                            ));
                                        }
                                        claimed_work_id = Some(work_id);
                                    }
                                    execute_action(
                                        cfg,
                                        &profile_for_thread,
                                        &action_for_thread,
                                        &ledger_entries_for_thread,
                                        skip_validation_gate,
                                        route_admission,
                                    )
                                }));
                            let (outcome, event_outcome) = match result {
                                Ok(Ok(outcome)) => (outcome.clone(), outcome),
                                Ok(Err(error)) => {
                                    let outcome = format!("Error: {error}");
                                    (outcome.clone(), outcome)
                                }
                                Err(_) => {
                                    let outcome = "Error: parallel GAH worker panicked".to_string();
                                    (outcome.clone(), outcome)
                                }
                            };
                            if let Some(work_id) = claimed_work_id {
                                let _ = crate::work_claim::release_owned_work(
                                    &claim_scope_for_thread,
                                    work_id,
                                );
                            }
                            let _ = crate::events::record(
                                cfg,
                                crate::events::EventType::LoopStopped,
                                Some(&profile_for_thread),
                                action_for_thread.work_id(),
                                event_outcome,
                            );
                            let _ = done_tx.send((
                                sequence,
                                LoopOnceResult {
                                    action: action_for_thread,
                                    outcome,
                                },
                            ));
                        });
                        // Give a route-ready worker its node decision before
                        // the next provider observation or worker launch.
                        continue 'scheduler;
                    }
                }
            }

            if active == 0 {
                if !saw_real_work {
                    if let Some((original_action, action, review_generation)) =
                        pending_terminal.take()
                    {
                        record_action_events(
                            cfg,
                            profile_name,
                            &original_action,
                            &action,
                            review_generation.as_deref(),
                        )?;
                        let outcome = execute_action(
                            cfg,
                            profile_name,
                            &action,
                            ledger_entries,
                            skip_validation_gate,
                            None,
                        )?;

                        let stop_event_type = match &action {
                            NextAction::WaitUntil { .. } => crate::events::EventType::WaitSelected,
                            NextAction::HumanRequired { .. } => {
                                crate::events::EventType::HumanRequired
                            }
                            NextAction::NoOp { .. } => crate::events::EventType::LoopStopped,
                            _ => unreachable!(),
                        };
                        let history = crate::events::read_events(cfg)?;
                        if !record_stop_event(
                            cfg,
                            profile_name,
                            &history,
                            &action,
                            stop_event_type,
                            &outcome,
                        )? {
                            repeated_stop_sequences.insert(next_sequence);
                        }

                        results.push((next_sequence, LoopOnceResult { action, outcome }));
                    }
                }
                break;
            }

            let (sequence, result) = if node_capacity_reprobe.is_scheduled() {
                match node_capacity_reprobe.wait(
                    &done_rx,
                    admission_coordinator.active_node_workers(),
                    effective_parallel_limit,
                    cfg.defaults.node_capacity,
                )? {
                    ReprobeWaitOutcome::WorkerCompleted(result) => result,
                    ReprobeWaitOutcome::RetryFill => {
                        node_capacity_reprobe.readmit(&mut executed_work_ids);
                        fill_attempts_remaining = 1;
                        continue;
                    }
                    ReprobeWaitOutcome::KeepWaiting => continue,
                    ReprobeWaitOutcome::Shutdown => break,
                }
            } else {
                match admission::recv_worker_done(&done_rx)? {
                    Some(result) => result,
                    None if crate::runner::shutdown_requested() => break,
                    None => continue,
                }
            };
            admission_coordinator.complete_worker(sequence);
            active -= 1;
            if active == 0 {
                node_capacity_reprobe.readmit(&mut executed_work_ids);
            }
            // A finished item's next step (the review of a new PR, the merge
            // after a review) may run in this batch rather than wait for the
            // slowest sibling.
            if has_follow_up_in_batch(&result.action, &result.outcome) {
                if let Some(work_id) = result.action.work_id() {
                    executed_work_ids.remove(&crate::work_claim::normalize_work_identity(work_id));
                }
            }
            if action_creates_managed_mr(&result.action) {
                if let Some(key) = action_intake_key(&result.action) {
                    active_intake_keys.remove(&key);
                }
            }
            if !admission::allow_bounded_node_alternative(
                &result.outcome,
                &mut node_alternative_attempts_remaining,
                &mut fill_attempts_remaining,
                refill_suppressed,
            ) {
                update_parallel_refill_budget(
                    &result.outcome,
                    effective_parallel_limit,
                    &mut fill_attempts_remaining,
                    &mut refill_suppressed,
                );
            }
            results.push((sequence, result));
        }
        Ok(())
    })?;

    results.sort_by_key(|(sequence, _)| *sequence);
    let (reported, results): (Vec<bool>, Vec<LoopOnceResult>) = results
        .into_iter()
        .map(|(sequence, result)| (!repeated_stop_sequences.contains(&sequence), result))
        .unzip();

    // Output results
    if json {
        println!("{}", serde_json::to_string_pretty(&results)?);
    } else {
        for (printed, (result, _)) in results
            .iter()
            .zip(&reported)
            .filter(|(_, new)| **new)
            .enumerate()
        {
            if printed > 0 {
                println!("---");
            }
            println!(
                "Decided: {} -- {}",
                result.action.kind(),
                result.action.reason()
            );
            println!("{}", result.outcome);
        }
        if results.is_empty() {
            println!("No actions executed (parallel limit reached or no eligible work)");
        }
        let admitted_work = results
            .iter()
            .any(|result| action_admitted_work(&result.action, &result.outcome));
        if !admitted_work {
            println!(
                "{}",
                no_admission_note.unwrap_or_else(|| no_admission_diagnostics(
                    _snapshot,
                    0,
                    effective_parallel_limit,
                    None
                ))
            );
        }
    }

    let failed_results: Vec<&LoopOnceResult> = results
        .iter()
        .filter(|result| parallel_outcome_is_failure(&result.outcome))
        .collect();
    if !failed_results.is_empty() {
        crate::work_claim::release_owned_for_profile(&claim_scope)?;
        anyhow::bail!(
            "{} parallel action(s) failed; first failure: {}",
            failed_results.len(),
            failed_results[0].outcome
        );
    }

    Ok(())
}

/// Capacity fallback after an attempt still represents admitted work; an
/// initial deferral or a lost claim does not.
fn action_admitted_work(action: &NextAction, outcome: &str) -> bool {
    selects_work(action)
        && !outcome_held_elsewhere(outcome)
        && (!outcome.starts_with("Deferred ") || !outcome.contains("no backend launched"))
}

fn update_parallel_refill_budget(
    outcome: &str,
    parallel_limit: usize,
    fill_attempts_remaining: &mut usize,
    refill_suppressed: &mut bool,
) -> bool {
    let error = outcome.starts_with("Error:");
    let failed = parallel_outcome_is_failure(outcome);
    let capacity_deferred = outcome.starts_with("Deferred ");
    if error {
        *refill_suppressed = true;
        *fill_attempts_remaining = 0;
    } else if capacity_deferred {
        *fill_attempts_remaining = 0;
    } else if !*refill_suppressed {
        *fill_attempts_remaining = parallel_limit;
    }
    failed
}

/// Whether a finished worker's item may be selected again in this batch.
/// Only agent work that ran to the end qualifies: it changes what the item
/// needs next. A merge or other bookkeeping step has no follow-up, and its
/// failures are reported in an ordinary outcome, so releasing it would retry
/// a refused merge at once. Errors, route deferrals, and items held elsewhere
/// stay excluded (issue #1430). Node deferrals are released separately by the
/// capacity reprobe.
fn has_follow_up_in_batch(action: &NextAction, outcome: &str) -> bool {
    matches!(
        action,
        NextAction::DispatchTicket { .. }
            | NextAction::FixMr { .. }
            | NextAction::Retry { .. }
            | NextAction::Escalate { .. }
            | NextAction::ReviewMr { .. }
    ) && !outcome.starts_with("Error:")
        && !outcome.starts_with("Deferred ")
        && !outcome_held_elsewhere(outcome)
}

fn parallel_outcome_is_failure(outcome: &str) -> bool {
    outcome.starts_with("Error:") && !outcome.contains("shutdown requested")
}

/// Records `DispatchStarted`, runs `dispatch::run`, then records either
/// `DispatchFinished` (success) or `DuplicateGuardTriggered` (the typed
/// duplicate-work refusal from TICKET-097's `check_duplicate_work`) / a
/// generic failure note -- so the event log distinguishes "the duplicate
/// guard correctly refused this" from an ordinary dispatch failure.
///
/// Used by both `gah loop --once` (which has a `NextAction`) and the
/// direct `gah dispatch` command; for the latter `work_id` is `None` until
/// `dispatch::run` resolves it. Emitting these events from the single
/// shared entry point is what lets the dashboard's controller-activity
/// panel observe *every* live dispatch -- including ones the supervisor
/// launches outside the dashboard -- instead of only dashboard-initiated
/// sessions (see issue #197).
pub(crate) fn run_dispatch_and_record(
    cfg: &crate::config::GahConfig,
    label: &str,
    work_id: Option<&str>,
    args: &crate::dispatch::DispatchArgs,
) -> Result<Option<String>> {
    let target_context = args
        .branch
        .as_deref()
        .or_else(|| (!args.target.is_empty()).then_some(args.target.as_str()));
    let start_detail = target_context
        .map(|target| format!("{label}: {target}"))
        .unwrap_or_else(|| label.to_string());
    crate::events::record_with_run_id(
        cfg,
        crate::events::EventType::DispatchStarted,
        Some(args.profile.as_str()),
        work_id,
        args.run_id.as_deref(),
        start_detail,
    )?;
    match crate::dispatch::run(cfg, args) {
        Ok(()) => {
            crate::events::record_with_run_id(
                cfg,
                crate::events::EventType::DispatchFinished,
                Some(args.profile.as_str()),
                work_id,
                args.run_id.as_deref(),
                format!("{label}: success"),
            )?;
            Ok(None)
        }
        Err(e) if crate::dispatch::capacity_deferred_error(&e) => {
            record_capacity_deferral(cfg, args, label, work_id, &e)
        }
        // Another loop holds the issue. That is a skip, not a failed dispatch.
        Err(e) if crate::dispatch::issue_claim_lost(&e).is_some() => {
            crate::events::record_with_run_id(
                cfg,
                crate::events::EventType::DispatchFinished,
                Some(args.profile.as_str()),
                work_id,
                args.run_id.as_deref(),
                format!("{label}: claim_lost: {e:#}"),
            )?;
            Ok(Some(format!("{HELD_ELSEWHERE_PREFIX}{e:#}")))
        }
        Err(e) => {
            let event_type = if crate::dispatch::duplicate_work_error(&e).is_some() {
                crate::events::EventType::DuplicateGuardTriggered
            } else if crate::dispatch::review_budget_exhausted_error(&e).is_some() {
                crate::events::EventType::ReviewBudgetExhausted
            } else {
                crate::events::EventType::DispatchFinished
            };
            let reason_code = if crate::policy::policy_blocked(&e).is_some()
                || (matches!(event_type, crate::events::EventType::DispatchFinished)
                    && e.chain().any(|cause| {
                        cause
                            .downcast_ref::<crate::routing::RouteError>()
                            .is_some_and(|route_error| {
                                matches!(
                                    route_error,
                                    crate::routing::RouteError::ApprovalRequired { .. }
                                )
                            })
                    })) {
                Some(HumanRequiredReason::PolicyApproval.as_str())
            } else {
                None
            };
            crate::events::record_dispatch_error(
                cfg,
                event_type,
                Some(args.profile.as_str()),
                work_id,
                args.run_id.as_deref(),
                format!("{label}: {e:#}"),
                reason_code,
                &e,
            )?;
            Err(e)
        }
    }
}

#[cfg(test)]
#[path = "ledger_read_tests.rs"]
mod ledger_read_tests;

#[cfg(test)]
#[path = "runtime/capacity_tests.rs"]
mod capacity_tests;

#[cfg(test)]
#[path = "runtime/tests.rs"]
mod tests;

#[cfg(test)]
#[path = "runtime/policy_tests.rs"]
mod policy_tests;
