use super::super::text::{extract_first_json_object, utf8_safe_prefix};
use super::context::ReviewDiffBundle;
use crate::availability;
use crate::config::{CandidateConfig, GahConfig, Profile};
use crate::job_kind::JobKind;
use crate::ledger::{self, LedgerEntry};
use crate::routing::RouteDecision;
use anyhow::Result;
use std::collections::HashSet;
use std::fmt;

mod ci_wait;

/// Typed, terminal refusal used when a ticket has exhausted its configured
/// review budget. Keeping this distinct from backend failures lets the
/// controller close the run cleanly and makes the operator-visible event
/// stream explain that no reviewer was launched and no extra quota was spent.
#[derive(Debug)]
pub struct ReviewBudgetExhausted {
    pub(in crate::dispatch) reason: String,
}

impl ReviewBudgetExhausted {
    pub(in crate::dispatch) fn new(reason: impl Into<String>) -> Self {
        Self {
            reason: reason.into(),
        }
    }
}

impl fmt::Display for ReviewBudgetExhausted {
    fn fmt(&self, f: &mut fmt::Formatter<'_>) -> fmt::Result {
        f.write_str(&self.reason)
    }
}

impl std::error::Error for ReviewBudgetExhausted {}

pub fn review_budget_exhausted_error(err: &anyhow::Error) -> Option<&ReviewBudgetExhausted> {
    err.downcast_ref::<ReviewBudgetExhausted>()
}

/// A reviewer process completed, but its payload was not safe to use as
/// repair context. This is neither a backend crash nor a code finding: the
/// controller should retain the attempt and ask the next configured reviewer.
#[derive(Debug)]
pub struct ReviewOutputInvalid {
    reason: String,
}

impl ReviewOutputInvalid {
    fn new(reason: impl Into<String>) -> Self {
        Self {
            reason: reason.into(),
        }
    }

    pub(in crate::dispatch) fn reason(&self) -> &str {
        &self.reason
    }
}

impl fmt::Display for ReviewOutputInvalid {
    fn fmt(&self, f: &mut fmt::Formatter<'_>) -> fmt::Result {
        write!(f, "review_output_invalid: {}", self.reason)
    }
}

impl std::error::Error for ReviewOutputInvalid {}

pub(in crate::dispatch) fn review_output_invalid_error(
    err: &anyhow::Error,
) -> Option<&ReviewOutputInvalid> {
    err.downcast_ref::<ReviewOutputInvalid>()
}

#[derive(Debug, Clone, PartialEq, Eq)]
pub(in crate::dispatch) struct ReviewBudgetBlock {
    pub(in crate::dispatch) reason: String,
}

/// Return a deterministic ticket-scoped review budget block before a reviewer
/// is launched. A cycle is a prior review dispatch that consumed a real
/// reviewer call; it includes failed and timed-out reviews because those can
/// still consume quota, but excludes both a prior budget refusal and a
/// duplicate-review short-circuit (same source SHA/tier already reviewed),
/// plus an operator-requested shutdown, since none is a completed opinion.
/// Paid usage is counted only from an
/// explicit recorded `api_key_backed` classification, never inferred from a
/// provider name or silently from unknown data. The paid cap applies only
/// when routing has explicitly selected a candidate configured as paid;
/// quota-backed, local, and unknown-cost routes remain eligible until the
/// cycle cap is reached. The ordinary cycle cap bounds routine reviewers, but
/// each explicitly configured escalatory backend/model gets one real attempt
/// even when routine history already reached that cap. This exception remains
/// bounded by the finite escalation chain; an already-attempted escalatory
/// route cannot use it again, and paid-review limits are still checked below.
pub(in crate::dispatch) fn check_review_budget(
    cfg: &GahConfig,
    profile: &Profile,
    profile_name: &str,
    work_id: Option<&str>,
    route: &RouteDecision,
    review_generation: Option<&str>,
) -> Result<Option<ReviewBudgetBlock>> {
    // Direct branch/MR reviews without a controller-provided ticket identity
    // cannot be attributed safely to a per-ticket budget. Fail open rather
    // than accidentally merging unrelated branches into one accounting bucket.
    let Some(work_id) = work_id.filter(|id| !id.trim().is_empty()) else {
        return Ok(None);
    };
    let routing = profile.effective_routing(&cfg.defaults);
    let entries = ledger::entries_for_work_id(cfg, work_id)?;
    // `clear-attempts` is an operator reset for this work item's bounded
    // automation budgets. Keep the append-only history, but do not let review
    // calls from before the latest matching tombstone permanently block the
    // ticket. Scope the reset to this profile/repository just like the review
    // records themselves so an identically-numbered issue elsewhere cannot
    // reset this budget.
    let active_entries = entries
        .iter()
        .rposition(|entry| {
            entry.profile == profile_name
                && entry.repo_id == profile.repo_id
                && entry.mode == "clear_attempts"
        })
        .map_or(entries.as_slice(), |index| &entries[index + 1..]);
    let reviews: Vec<_> = active_entries
        .iter()
        .filter(|entry| {
            entry.profile == profile_name
                && entry.repo_id == profile.repo_id
                && JobKind::parse(&entry.mode) == Ok(JobKind::Review)
                && entry.review_contract_version == Some(ledger::CURRENT_REVIEW_CONTRACT_VERSION)
                && super::head::same_head(entry, review_generation)
                && !matches!(
                    entry.validation_result.as_deref(),
                    Some("review_budget_exhausted")
                        | Some("skipped_duplicate_review")
                        | Some("deferred_capacity")
                        | Some("cancelled_shutdown")
                )
        })
        .collect();

    let cycle_count = reviews.len() as u32;
    let cycle_cap = routing.max_review_cycles_per_ticket();
    let selected_tier = derive_reviewer_tier(cfg, profile, route);
    let selected_reviewer_class = reviewer_dedup_class(selected_tier, route);
    let selected_escalatory_reviewer_is_untried = selected_tier == ReviewerTier::Escalatory
        && !reviews.iter().any(|entry| {
            entry.reviewer_class.as_deref() == Some(selected_reviewer_class.as_str())
                || (entry.effective_backend == route.effective_backend
                    && entry.effective_model == route.effective_model)
        });
    if cycle_count >= cycle_cap && !selected_escalatory_reviewer_is_untried {
        return Ok(Some(ReviewBudgetBlock {
            reason: format!(
                "review budget exhausted for {work_id}: {cycle_count}/{cycle_cap} review cycles used"
            ),
        }));
    }

    let selected_paid = route
        .routing_diagnostics
        .as_ref()
        .and_then(|diagnostics| diagnostics.selected_cost_class.as_deref())
        == Some("paid");
    if selected_paid {
        let paid_count = reviews
            .iter()
            .filter(|entry| entry.usage.usage_classification.as_deref() == Some("api_key_backed"))
            .count() as u32;
        let paid_cap = routing.max_paid_reviews_per_ticket();
        if paid_count >= paid_cap {
            return Ok(Some(ReviewBudgetBlock {
                reason: format!(
                    "paid review budget exhausted for {work_id}: {paid_count}/{paid_cap} API-backed reviews used"
                ),
            }));
        }
    }

    Ok(None)
}

/// The routine reviewer (`review_backend`, e.g. Vibe/Mistral) is fast and
/// cheap but was never meant to be the last word on a genuinely hard or
/// repeatedly-failing review. The repeated-failure trigger follows the
/// configured post-review repair budget; adds an
/// immediate-escalate path for a reviewer that itself reported low
/// confidence, since forcing 2 low-confidence rubber stamps before getting
/// a second opinion defeats the point of tracking confidence at all.
///
/// Reads `validation_result`/`confidence_impact` off this branch's own
/// `mode == "review"` entries -- NOT `review_verdict`/`review_confidence`.
/// Those two fields are written by `backfill_review_verdict` (ledger/mod.rs,
/// TICKET-125) onto the *implementation* (fix/improve) entry instead, by
/// design (see `backfill_review_verdict_attributes_to_implementation_entry_not_reviewer`).
/// A review dispatch's own entry never carries a `review_verdict`, so
/// checking that field here would make this permanently a no-op; the
/// verdict/confidence a review entry actually records about itself live in
/// `validation_result`/`confidence_impact` (set directly in `review()`).
pub(in crate::dispatch) fn review_escalation_reason(
    cfg: &GahConfig,
    profile: &Profile,
    profile_name: &str,
    branch: &str,
    review_generation: Option<&str>,
) -> Option<&'static str> {
    let repeated_failure_threshold = profile
        .effective_routing(&cfg.defaults)
        .max_fix_attempts_per_mr() as usize;

    let entries = ledger::read_entries(cfg).ok()?;
    let active_entries = active_branch_review_entries(&entries, profile, profile_name, branch);
    let recent: Vec<&LedgerEntry> = active_entries
        .iter()
        .rev()
        .filter(|e| {
            e.profile == profile_name
                && JobKind::parse(&e.mode) == Ok(JobKind::Review)
                && e.branch.as_deref() == Some(branch)
                && e.review_contract_version == Some(ledger::CURRENT_REVIEW_CONTRACT_VERSION)
                && super::head::same_head(e, review_generation)
                // Legacy reviews written before reviewed-SHA persistence
                // cannot support a safe repair and must be re-runnable. Do
                // not let them trigger escalation before that migration
                // review has a chance to run.
                && e.review_source_sha.is_some()
                && matches!(
                    e.validation_result.as_deref(),
                    Some("APPROVE")
                        | Some("NEEDS_FIX")
                        | Some("REJECT")
                        | Some("HUMAN_REVIEW")
                        | Some("review_output_invalid")
                )
        })
        .take(repeated_failure_threshold)
        .collect();

    // A real HUMAN_REVIEW verdict and a deterministic evidence-gate hold both
    // use this persisted result. Neither is a reason to abandon automation
    // while a configured second-opinion reviewer remains.
    if recent
        .first()
        .is_some_and(|e| e.validation_result.as_deref() == Some("HUMAN_REVIEW"))
    {
        return Some("human_review");
    }

    if recent
        .first()
        .is_some_and(|e| e.validation_result.as_deref() == Some("review_output_invalid"))
    {
        return Some("review_output_invalid");
    }

    if recent
        .first()
        .is_some_and(|e| e.confidence_impact.as_deref() == Some("low"))
    {
        return Some("low_confidence");
    }

    if recent.len() == repeated_failure_threshold
        && recent.iter().all(|e| {
            matches!(
                e.validation_result.as_deref(),
                Some("NEEDS_FIX") | Some("REJECT")
            )
        })
    {
        return Some("repeated_needs_fix");
    }

    None
}

/// A candidate left without an explicit model is recorded in the ledger
/// under whatever effective model routing backfilled for it (e.g. codex's
/// config-file default, mirroring routing.rs's own decide_route backfill) --
/// compare against that, not the raw config value, or a once-tried
/// backfilled candidate looks perpetually untried and the chain never
/// advances past it.
fn effective_model_for(candidate: &CandidateConfig, profile: &Profile) -> Option<String> {
    if candidate.backend == "codex" && candidate.model.is_none() {
        crate::runner::extract_model_from_args(&profile.codex_args)
    } else {
        candidate.model.clone()
    }
}

/// Live availability (quota/auth) for one candidate, reusing the same
/// state store `routing::decide_route` consults. Fails open (treats the
/// candidate as available) if the store can't be read -- unknown state
/// should not itself stall the escalation chain.
fn candidate_is_available(state_path: &std::path::Path, candidate: &CandidateConfig) -> bool {
    let quota_pool = availability::resolve_candidate_quota_pool(
        &candidate.backend,
        candidate.model.as_deref(),
        candidate.quota_pool.as_deref(),
    );
    let identity = crate::execution_identity::ExecutionIdentity::legacy_candidate(
        &candidate.backend,
        candidate.model.as_deref(),
        quota_pool.as_deref(),
    );
    availability::availability_for_identity(state_path, &identity, crate::clock::now_utc())
        .map(|decision| decision.eligible)
        .unwrap_or(true)
}

/// Among the untried candidates, prefer one that's actually available right
/// now over the ordered list's plain next-in-line. Without this, a candidate
/// under a multi-day quota cooldown (or a permanently broken credential --
/// `authentication_error` never has a reset time) stalls the whole
/// escalation chain waiting on that one backend, even when a later candidate
/// in the same ordered list is eligible immediately. Falls back to the
/// first untried candidate, unavailable or not, so genuine full-exhaustion
/// (nothing left to try) still surfaces exactly as before.
fn pick_next_untried(
    state_path: &std::path::Path,
    candidates: Vec<CandidateConfig>,
    profile: &Profile,
    attempted: &HashSet<(String, Option<String>)>,
) -> Option<CandidateConfig> {
    let untried: Vec<CandidateConfig> = candidates
        .into_iter()
        .filter(|candidate| {
            let effective_model = effective_model_for(candidate, profile);
            !attempted.contains(&(candidate.backend.clone(), effective_model))
        })
        .collect();
    if let Some(available) = untried
        .iter()
        .find(|candidate| candidate_is_available(state_path, candidate))
    {
        return Some(available.clone());
    }
    untried.into_iter().next()
}

/// Invalid structured output is not an opinion, so it advances through the
/// complete ordered review pool (for example AGY account 1 -> AGY account 2
/// -> Claude) before the stronger/paid terminal escalation boundary. This is
/// intentionally broader than `next_escalatory_reviewer`, which handles a
/// valid but uncertain/adverse opinion.
pub(in crate::dispatch) fn next_review_candidate(
    cfg: &GahConfig,
    profile: &Profile,
    profile_name: &str,
    branch: &str,
    current: Option<(&str, Option<&str>)>,
    review_generation: Option<&str>,
    state_path: &std::path::Path,
) -> Option<CandidateConfig> {
    let entries = ledger::read_entries(cfg).ok()?;
    let active_entries = active_branch_review_entries(&entries, profile, profile_name, branch);
    let mut attempted: HashSet<(String, Option<String>)> = active_entries
        .iter()
        .filter(|entry| {
            entry.profile == profile_name
                && JobKind::parse(&entry.mode) == Ok(JobKind::Review)
                && entry.branch.as_deref() == Some(branch)
                && entry.review_contract_version == Some(ledger::CURRENT_REVIEW_CONTRACT_VERSION)
                && super::head::same_head(entry, review_generation)
                && entry.review_source_sha.is_some()
                && entry.validation_result.as_deref() != Some("skipped_duplicate_review")
                && entry.validation_result.as_deref() != Some("cancelled_shutdown")
                // A deferred_capacity entry is a routing-decision failure: no
                // backend ever launched and no verdict was produced. Treating
                // it as a spent attempt strands the escalation chain on the
                // same unreachable candidate forever, even after the
                // candidate's own transient unavailability (e.g. a quota
                // cooldown) has since cleared.
                && entry.validation_result.as_deref() != Some("deferred_capacity")
        })
        .map(|entry| {
            (
                entry.effective_backend.clone(),
                entry.effective_model.clone(),
            )
        })
        .collect();
    if let Some((backend, model)) = current {
        attempted.insert((backend.to_string(), model.map(str::to_string)));
    }

    let routing = profile.effective_routing(&cfg.defaults);
    let candidates = match routing.allowed_models_for("review") {
        Some(allowed) => allowed.to_vec(),
        None => routing.review_candidates.unwrap_or_default(),
    };
    pick_next_untried(state_path, candidates, profile, &attempted)
}

/// Select the next unused reviewer from the explicitly ordered escalation
/// chain. The identity includes both backend instance and model: AGY account
/// 1, AGY account 2, and a paid gateway must remain independently observable
/// and independently eligible for a second opinion.
pub(in crate::dispatch) fn next_escalatory_reviewer(
    cfg: &GahConfig,
    profile: &Profile,
    profile_name: &str,
    branch: &str,
    current: Option<(&str, Option<&str>)>,
    review_generation: Option<&str>,
    state_path: &std::path::Path,
) -> Option<CandidateConfig> {
    let entries = ledger::read_entries(cfg).ok()?;
    let active_entries = active_branch_review_entries(&entries, profile, profile_name, branch);
    let mut attempted: HashSet<(String, Option<String>)> = active_entries
        .iter()
        .filter(|entry| {
            entry.profile == profile_name
                && JobKind::parse(&entry.mode) == Ok(JobKind::Review)
                && entry.branch.as_deref() == Some(branch)
                && entry.review_contract_version
                    == Some(ledger::CURRENT_REVIEW_CONTRACT_VERSION)
                && super::head::same_head(entry, review_generation)
                // A SHA-less legacy opinion is not reusable repair context.
                // Treating its backend as spent would skip directly to the
                // next (possibly paid) reviewer instead of migrating it.
                && entry.review_source_sha.is_some()
                && entry.validation_result.as_deref() != Some("skipped_duplicate_review")
                // An operator-requested shutdown is not a reviewer opinion
                // and must remain retryable after the daemon restarts.
                && entry.validation_result.as_deref() != Some("cancelled_shutdown")
                // A deferred_capacity entry is a routing-decision failure: no
                // backend ever launched and no verdict was produced. Treating
                // it as a spent attempt strands the escalation chain on the
                // same unreachable candidate forever, even after the
                // candidate's own transient unavailability (e.g. a quota
                // cooldown) has since cleared.
                && entry.validation_result.as_deref() != Some("deferred_capacity")
        })
        .map(|entry| {
            (
                entry.effective_backend.clone(),
                entry.effective_model.clone(),
            )
        })
        .collect();
    if let Some((backend, model)) = current {
        attempted.insert((backend.to_string(), model.map(str::to_string)));
    }

    let routing = profile.effective_routing(&cfg.defaults);
    let candidates = routing
        .effective_escalatory_reviewers()
        .into_iter()
        .filter(|c| routing.allows_candidate("review", c))
        .collect();
    pick_next_untried(state_path, candidates, profile, &attempted)
}

/// Return the append-only branch history after the latest operator reset for
/// a work item already attributed to this branch. Review escalation is branch
/// scoped, while `clear-attempts` tombstones are work-item scoped and carry no
/// branch. Deriving aliases from the branch's own review records bridges those
/// identities without allowing an identically numbered ticket in another
/// profile/repository to reset this chain.
fn active_branch_review_entries<'a>(
    entries: &'a [LedgerEntry],
    profile: &Profile,
    profile_name: &str,
    branch: &str,
) -> &'a [LedgerEntry] {
    let work_aliases: HashSet<String> = entries
        .iter()
        .filter(|entry| {
            entry.profile == profile_name
                && entry.repo_id == profile.repo_id
                && JobKind::parse(&entry.mode) == Ok(JobKind::Review)
                && entry.branch.as_deref() == Some(branch)
        })
        .filter_map(|entry| entry.work_id.as_deref())
        .flat_map(ledger::work_id_aliases)
        .collect();

    let reset_index = (!work_aliases.is_empty()).then(|| {
        entries.iter().rposition(|entry| {
            entry.profile == profile_name
                && entry.repo_id == profile.repo_id
                && entry.mode == "clear_attempts"
                && entry.work_id.as_deref().is_some_and(|work_id| {
                    ledger::work_id_aliases(work_id)
                        .iter()
                        .any(|alias| work_aliases.contains(alias))
                })
        })
    });

    reset_index
        .flatten()
        .map_or(entries, |index| &entries[index + 1..])
}

/// Review deduplication normally works at the authority-tier level. An
/// ordered escalation chain deliberately contains several distinct second
/// opinions, so each escalatory backend/model pair gets one review of a
/// source commit rather than the first escalatory reviewer suppressing every
/// later one.
pub(in crate::dispatch) fn reviewer_dedup_class(
    tier: ReviewerTier,
    route: &RouteDecision,
) -> String {
    match tier {
        ReviewerTier::Escalatory => format!(
            "escalatory:{}/{}",
            route.effective_backend,
            route.effective_model.as_deref().unwrap_or("default")
        ),
        _ => tier.as_str().to_string(),
    }
}

/// Facts supplied by the control plane, not the reviewer. An approval must
/// cite these exact facts; free-form reviewer claims alone never make a change
/// safe to merge.
#[derive(Debug, Clone, Default)]
pub(in crate::dispatch) struct ReviewGateContext {
    changed_files: Vec<String>,
    ci_passed: bool,
    ci_failed: bool,
    contract_files: Vec<String>,
    compatibility_mechanisms: Vec<&'static str>,
    acceptance_criteria: Vec<String>,
    source_provider: String,
    enforce_grounding: bool,
    hold_contract_changes: bool,
}

/// Persisted or wire formats that other components or older nodes read.
/// Crate-internal `pub` items and server code are not contracts: treating
/// them as such turned most strong APPROVEs into human handoffs (#1405).
fn is_contract_path(path: &str) -> bool {
    [
        "packages/contracts/",
        "migrations/",
        "src/ledger/",
        "src/telemetry/",
    ]
    .iter()
    .any(|prefix| path.starts_with(prefix))
}

impl ReviewGateContext {
    pub(in crate::dispatch) fn from_diff_bundle(
        bundle: &ReviewDiffBundle,
        ci_status: Option<&str>,
    ) -> Self {
        let changed_files: Vec<String> = bundle
            .files
            .lines()
            .map(str::trim)
            .filter(|path| !path.is_empty())
            .map(str::to_string)
            .collect();
        let diff_lower = bundle.diff.to_ascii_lowercase();
        let contract_files: Vec<String> = changed_files
            .iter()
            .filter(|path| is_contract_path(path))
            .cloned()
            .collect();
        let mut compatibility_mechanisms = Vec::new();
        if diff_lower.contains("schema_version") {
            compatibility_mechanisms.push("schema-version");
        }
        if diff_lower.contains("serde(default)") {
            compatibility_mechanisms.push("backward-compatible-default");
        }
        if diff_lower.contains("migrat") {
            compatibility_mechanisms.push("migration");
        }

        Self {
            changed_files,
            ci_passed: ci_status.is_some_and(|status| {
                matches!(
                    status.trim().to_ascii_lowercase().as_str(),
                    "passed" | "success" | "green"
                )
            }),
            ci_failed: ci_status
                .is_some_and(|status| matches!(status, "failed" | "failure" | "red")),
            contract_files,
            compatibility_mechanisms,
            acceptance_criteria: Vec::new(),
            source_provider: String::new(),
            enforce_grounding: true,
            hold_contract_changes: true,
        }
    }

    /// Profile setting `hold_contract_changes_for_human_review`. Off means a
    /// contract change never turns an APPROVE into a human handoff.
    pub(in crate::dispatch) fn with_contract_hold(mut self, hold: bool) -> Self {
        self.hold_contract_changes = hold;
        self
    }

    /// Instructions for the one bounded same-reviewer retry, when the gate
    /// held an APPROVE for a reason the reviewer can fix itself. `None`
    /// means the hold goes straight to escalation.
    pub(in crate::dispatch) fn repair_instructions(
        &self,
        verdict: &crate::models::ReviewVerdict,
    ) -> Option<String> {
        if verdict.verdict != "HUMAN_REVIEW" {
            return None;
        }
        match verdict.safety_gate_reason.as_deref()? {
            REVIEW_FORMAT_ONLY_VIOLATION_REASON => Some(REVIEW_FORMAT_REPAIR_INSTRUCTIONS.to_string()),
            CONTRACT_GATE_REASON => Some(format!(
                "Your APPROVE changed persisted or wire contract files without compatibility evidence: {}. \
Re-check them. If the change is compatible, keep APPROVE and add compatibility_evidence with file:<one of those paths> \
and mechanism:<{}> naming a mechanism actually present in the diff. If it is not compatible, return NEEDS_FIX with a \
concrete actionable finding. Respond with ONLY the inert heading `Review notes` followed by the JSON object.",
                self.contract_files.join(", "),
                if self.compatibility_mechanisms.is_empty() {
                    "none found in the diff".to_string()
                } else {
                    self.compatibility_mechanisms.join("|")
                },
            )),
            _ => None,
        }
    }

    fn has_contract_surface_change(&self) -> bool {
        !self.contract_files.is_empty()
    }

    pub(in crate::dispatch) fn with_source_acceptance(
        mut self,
        acceptance_criteria: Vec<String>,
        provider: &str,
    ) -> Self {
        self.acceptance_criteria = acceptance_criteria;
        self.source_provider = provider.trim().to_ascii_lowercase();
        self
    }

    fn acceptance_gate_reason(&self, verdict: &crate::models::ReviewVerdict) -> Option<String> {
        if self.acceptance_criteria.is_empty() {
            return None;
        }

        if self
            .acceptance_criteria
            .iter()
            .any(|criterion| criterion_requires_external_state(criterion))
            && verdict
                .non_blocking_findings
                .iter()
                .chain(&verdict.risk_notes)
                .any(|finding| admits_unverified_state(finding))
        {
            return Some(
                "APPROVE admitted that required current/external acceptance state remained unverified"
                    .to_string(),
            );
        }

        for (index, criterion) in self.acceptance_criteria.iter().enumerate() {
            let number = index + 1;
            let prefix = format!("ac:{number}:");
            let mappings = verdict
                .evidence
                .iter()
                .filter_map(|item| item.trim().strip_prefix(&prefix))
                .collect::<Vec<_>>();
            if mappings.is_empty() {
                return Some(format!(
                    "APPROVE omitted evidence for source acceptance criterion {number}: {}",
                    utf8_safe_prefix(criterion, 160)
                ));
            }
            let external = criterion_requires_external_state(criterion);
            let valid = mappings
                .iter()
                .any(|mapping| self.acceptance_mapping_is_grounded(mapping, external));
            if !valid {
                return Some(format!(
                    "APPROVE evidence for source acceptance criterion {number} was not grounded{}",
                    if external {
                        " in direct provider evidence or a testable changed snapshot"
                    } else {
                        " in a changed file or concrete test result"
                    }
                ));
            }
        }
        None
    }

    fn acceptance_mapping_is_grounded(&self, mapping: &str, external: bool) -> bool {
        if let Some(rest) = mapping.strip_prefix("provider:") {
            let Some((provider, reference)) = rest.split_once(':') else {
                return false;
            };
            return external
                && !reference.trim().is_empty()
                && provider.trim().eq_ignore_ascii_case(&self.source_provider);
        }
        if let Some(rest) = mapping.strip_prefix("snapshot:") {
            let Some((path, verification)) = rest.split_once(':') else {
                return false;
            };
            return external
                && !verification.trim().is_empty()
                && self
                    .changed_files
                    .iter()
                    .any(|candidate| candidate == path.trim());
        }
        if external {
            return false;
        }
        if let Some(path) = mapping.strip_prefix("file:") {
            return self.mapping_references_changed_file(path);
        }
        mapping
            .strip_prefix("test:")
            .is_some_and(|detail| !detail.trim().is_empty())
    }

    fn mapping_references_changed_file(&self, mapping: &str) -> bool {
        let mapping = mapping.trim();
        self.changed_files.iter().any(|candidate| {
            let Some(suffix) = mapping.strip_prefix(candidate) else {
                return false;
            };
            suffix.is_empty()
                || suffix.starts_with(" — ")
                || suffix.starts_with(" – ")
                || suffix.starts_with(" - ")
                || suffix.starts_with(" (")
                || suffix.starts_with(" [")
        })
    }

    fn evidence_is_grounded(&self, evidence: &[String]) -> bool {
        evidence.iter().any(|item| {
            let Some(path) = item.trim().strip_prefix("file:") else {
                return false;
            };
            self.changed_files
                .iter()
                .any(|candidate| candidate == path.trim())
        })
    }

    fn falsely_claims_passed_ci(&self, evidence: &[String]) -> bool {
        !self.ci_passed
            && evidence
                .iter()
                .any(|item| item.trim().eq_ignore_ascii_case("ci:passed"))
    }

    fn compatibility_is_grounded(&self, evidence: &[String]) -> bool {
        evidence.iter().any(|item| {
            let Some(path) = item.trim().strip_prefix("file:") else {
                return false;
            };
            self.contract_files
                .iter()
                .any(|candidate| candidate == path.trim())
        }) && evidence.iter().any(|item| {
            let Some(mechanism) = item.trim().strip_prefix("mechanism:") else {
                return false;
            };
            self.compatibility_mechanisms
                .iter()
                .any(|candidate| candidate == &mechanism.trim())
        })
    }
}

#[allow(clippy::too_many_arguments)]
/// TICKET-108: reviewer authority (who is reviewing) kept as a dimension
/// separate from review outcome (verdict/confidence, what they said).
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub(in crate::dispatch) enum ReviewerTier {
    Strong,
    Standard,
    Weak,
    /// Issue #123: an escalatory reviewer (a more-capable model from the
    /// ESCALATORY_REVIEW list) the pipeline escalated to and continued with.
    /// Auto-merge eligible like `Strong`, but recorded distinctly so the
    /// cascade origin is observable.
    Escalatory,
}

impl ReviewerTier {
    pub(in crate::dispatch) fn as_str(self) -> &'static str {
        match self {
            Self::Strong => "strong",
            Self::Standard => "standard",
            Self::Weak => "weak",
            Self::Escalatory => "escalatory",
        }
    }
}

/// Derived from which configured routing field actually selected this
/// backend/model, not from anything the reviewer says about itself -- a
/// weak reviewer cannot self-promote by returning confident-sounding text
/// (TICKET-108's core requirement).
pub(in crate::dispatch) fn derive_reviewer_tier(
    cfg: &GahConfig,
    profile: &Profile,
    route: &RouteDecision,
) -> ReviewerTier {
    let effective_model = route.effective_model.as_deref();
    let selected = |backend_cfg: Option<&str>, model_cfg: Option<&str>| -> bool {
        backend_cfg.is_some_and(|b| b == route.effective_backend)
            && (model_cfg.is_none() || model_cfg == effective_model)
    };
    let routine = profile
        .routing
        .effective_routine_reviewer()
        .or_else(|| cfg.defaults.routing.effective_routine_reviewer());
    let escalatory = profile
        .routing
        .escalatory_reviewers
        .iter()
        .cloned()
        .chain(cfg.defaults.routing.escalatory_reviewers.clone())
        .collect::<Vec<_>>();

    // Issue #233: tier classification must only honor explicitly declared
    // escalatory reviewers. The legacy weak-review keys still feed routing
    // backfill via `effective_escalatory_reviewers()`, but they do not imply
    // the auto-merge-eligible escalatory tier.
    for esc in &escalatory {
        if selected(Some(esc.backend.as_str()), esc.model.as_deref()) {
            // Check if this escalatory reviewer is actually a legacy weak review configuration
            // Legacy weak review configs should be treated as Weak tier, not Escalatory
            let is_legacy_weak_config = profile.routing.escalatory_reviewers.is_empty()
                && profile.routing.weak_review_backend.as_deref() == Some(esc.backend.as_str())
                && profile.routing.weak_review_model.as_deref() == esc.model.as_deref();

            if is_legacy_weak_config {
                return ReviewerTier::Weak;
            }
            return ReviewerTier::Escalatory;
        }
    }
    // Routine reviewer is the STRONG first-line authority.
    if let Some(routine) = &routine {
        if selected(Some(routine.backend.as_str()), routine.model.as_deref()) {
            return ReviewerTier::Strong;
        }
    }
    let strong_backend = profile.routing.strong_review_backend.as_deref().or(cfg
        .defaults
        .routing
        .strong_review_backend
        .as_deref());
    let strong_model = profile.routing.strong_review_model.as_deref().or(cfg
        .defaults
        .routing
        .strong_review_model
        .as_deref());
    let weak_backend = profile.routing.weak_review_backend.as_deref().or(cfg
        .defaults
        .routing
        .weak_review_backend
        .as_deref());
    let weak_model = profile.routing.weak_review_model.as_deref().or(cfg
        .defaults
        .routing
        .weak_review_model
        .as_deref());

    if selected(weak_backend, weak_model) {
        return ReviewerTier::Weak;
    }
    if selected(strong_backend, strong_model) {
        return ReviewerTier::Strong;
    }
    // review_candidates is the operator's actual declared pool of reviewers
    // they consider trustworthy (agy/agy-second/claude serving the same
    // Sonnet-class model are routinely interchangeable fallbacks for each
    // other, not different capability tiers). Requiring strong_review_backend/
    // model to be manually kept in sync with every review_candidates entry
    // is exactly the kind of drift that already produced two real bugs
    // tonight (gah's own strong_review_backend pointed at codex-mini; here,
    // falling back from agy to agy-second/claude silently downgraded a
    // Sonnet reviewer to "standard" tier). Any candidate not already
    // classified weak above is strong.
    let candidates = profile.routing.review_candidates.as_ref().or(cfg
        .defaults
        .routing
        .review_candidates
        .as_ref());
    if let Some(candidates) = candidates {
        let in_candidates = candidates.iter().any(|c| {
            c.backend == route.effective_backend
                && (c.model.is_none() || c.model.as_deref() == effective_model)
        });
        if in_candidates {
            return ReviewerTier::Strong;
        }
    }
    // An allow-listed reviewer is the operator's declared trusted reviewer
    // for this profile, the same standing as a `review_candidates` entry.
    let routing = profile.effective_routing(&cfg.defaults);
    if routing.allowed_models_for("review").is_some()
        && routing.allows_model("review", &route.effective_backend, effective_model)
    {
        return ReviewerTier::Strong;
    }
    ReviewerTier::Standard
}

#[cfg(test)]
fn parse_review_verdict(
    review_text: &str,
    route: &RouteDecision,
    parsed_usage: &crate::ledger::LedgerUsage,
    tier: ReviewerTier,
) -> Result<crate::models::ReviewVerdict> {
    parse_review_verdict_with_context(
        review_text,
        route,
        parsed_usage,
        tier,
        &ReviewGateContext::default(),
    )
}

pub(in crate::dispatch) fn parse_review_verdict_with_context(
    review_text: &str,
    route: &RouteDecision,
    parsed_usage: &crate::ledger::LedgerUsage,
    tier: ReviewerTier,
    gate_context: &ReviewGateContext,
) -> Result<crate::models::ReviewVerdict> {
    let json = extract_first_json_object(review_text)
        .ok_or_else(|| anyhow::anyhow!("reviewer did not return verdict JSON"))?;
    let mut verdict = serde_json::from_str::<crate::models::ReviewVerdict>(&json)?;
    if !ci_wait::defer(&mut verdict, gate_context) {
        normalize_actionable_findings(&mut verdict, gate_context)?;
    }
    enforce_review_evidence_gate(
        &mut verdict,
        review_text,
        &route.effective_backend,
        gate_context,
    );
    // Reviewer identity (tier) and review outcome (verdict text/confidence)
    // are separate dimensions -- the verdict text itself is never rewritten
    // based on who reviewed it (see review_labels for how tier affects
    // labeling instead).
    if tier == ReviewerTier::Weak && verdict.confidence == "high" {
        // Weak approval is deliberately not auto-merge authority. A weak
        // reviewer finding a defect is actionable input for the normal
        // post-review repair budget and must not skip straight to a human.
        verdict.confidence = "medium".into();
    }
    if tier == ReviewerTier::Weak && verdict.verdict == "APPROVE" {
        verdict.human_required = true;
    }
    if verdict.verdict == "HUMAN_REVIEW"
        || (verdict.verdict == "APPROVE" && verdict.confidence == "low")
    {
        verdict.human_required = true;
    }
    verdict.reviewer_tier = Some(tier.as_str().to_string());
    verdict.reviewer_backend = Some(route.effective_backend.clone());
    verdict.reviewer_model = route.effective_model.clone();
    verdict.requested_backend = Some(route.requested_backend.clone());
    verdict.effective_backend = Some(route.effective_backend.clone());
    verdict.requested_model = route.requested_model.clone();
    verdict.effective_model = route.effective_model.clone();
    verdict.fallback_used = Some(route.fallback_used);
    verdict.usage_source = parsed_usage.usage_source.clone();
    verdict.input_tokens = parsed_usage.input_tokens;
    verdict.output_tokens = parsed_usage.output_tokens;
    verdict.total_tokens = parsed_usage.total_tokens;
    verdict.estimated_cost_usd = parsed_usage.estimated_cost_usd;
    verdict.actual_cost_usd = parsed_usage.actual_cost_usd;
    Ok(verdict)
}

fn normalize_actionable_findings(
    verdict: &mut crate::models::ReviewVerdict,
    gate_context: &ReviewGateContext,
) -> Result<()> {
    let repair_verdict = matches!(verdict.verdict.as_str(), "NEEDS_FIX" | "REJECT");
    if repair_verdict && verdict.actionable_findings.is_empty() {
        // The ungrounded context exists only for parser-focused unit tests and
        // historical compatibility helpers. Production review always builds
        // a diff-backed context and therefore takes the strict branch below.
        if !gate_context.enforce_grounding {
            return Ok(());
        }
        return Err(
            ReviewOutputInvalid::new("NEEDS_FIX/REJECT omitted actionable_findings").into(),
        );
    }
    if verdict.actionable_findings.is_empty() {
        return Ok(());
    }

    let mut rendered = Vec::with_capacity(verdict.actionable_findings.len());
    for (index, finding) in verdict.actionable_findings.iter().enumerate() {
        let number = index + 1;
        if !finding.status.trim().eq_ignore_ascii_case("confirmed") {
            return Err(ReviewOutputInvalid::new(format!(
                "actionable finding {number} status must be confirmed"
            ))
            .into());
        }
        let file = finding.file.trim();
        if file.is_empty()
            || (gate_context.enforce_grounding
                && !gate_context.changed_files.iter().any(|path| path == file))
        {
            return Err(ReviewOutputInvalid::new(format!(
                "actionable finding {number} did not name an exact changed file"
            ))
            .into());
        }
        let summary = finding.summary.trim();
        if summary.is_empty() {
            return Err(ReviewOutputInvalid::new(format!(
                "actionable finding {number} omitted its summary"
            ))
            .into());
        }
        if finding_text_disclaims_actionability(summary)
            || finding
                .evidence
                .iter()
                .any(|evidence| finding_text_disclaims_actionability(evidence))
        {
            return Err(ReviewOutputInvalid::new(format!(
                "actionable finding {number} explicitly withdrew, contradicted, or left the finding unverified"
            ))
            .into());
        }
        let grounded = finding.evidence.iter().any(|item| {
            let Some(rest) = item.trim().strip_prefix("diff:") else {
                return false;
            };
            let Some((evidence_file, detail)) = rest.split_once(':') else {
                return false;
            };
            evidence_file.trim() == file && !detail.trim().is_empty()
        });
        if !grounded {
            return Err(ReviewOutputInvalid::new(format!(
                "actionable finding {number} omitted direct diff:{file}:<observation> evidence"
            ))
            .into());
        }

        let location = finding
            .line
            .as_deref()
            .map(str::trim)
            .filter(|line| !line.is_empty())
            .map_or_else(|| file.to_string(), |line| format!("{file}:{line}"));
        rendered.push(format!("{location}: {summary}"));
    }
    verdict.blocking_findings = rendered;
    Ok(())
}

fn finding_text_disclaims_actionability(text: &str) -> bool {
    let normalized = text.to_ascii_lowercase();
    [
        "withdrawn",
        "not blocking",
        "actually fine",
        "no issue here",
        "cannot be confirmed",
        "can't be confirmed",
        "unverified risk",
        "unverified concern",
        "partially unverified",
        "may or may not",
        "not strictly broken",
    ]
    .iter()
    .any(|marker| normalized.contains(marker))
}

pub(in crate::dispatch) const REVIEW_FORMAT_ONLY_VIOLATION_REASON: &str =
    "APPROVE included substantive prose; every finding must be represented in the review JSON";

const REVIEW_FORMAT_REPAIR_INSTRUCTIONS: &str =
    "Retrying: respond with ONLY the inert heading `Review notes` followed by the JSON object. \
Include no extra prose before or after the JSON.";

const CONTRACT_GATE_REASON: &str =
    "APPROVE changed a contract surface without a control-plane-verifiable compatibility mechanism and evidence";

/// A reviewer is advisory; merge safety is deterministic. In particular, an
/// LLM must not be able to write an apparent APPROVE while its own structured
/// findings describe a blocking or unversioned contract change (the exact
/// failure observed in PR #284). The normalized verdict remains visible in
/// the review artifact, ledger, and status payload.
fn enforce_review_evidence_gate(
    verdict: &mut crate::models::ReviewVerdict,
    review_text: &str,
    reviewer_backend: &str,
    gate_context: &ReviewGateContext,
) {
    if verdict.verdict != "APPROVE" {
        return;
    }

    if let Some(reason) = gate_context.acceptance_gate_reason(verdict) {
        verdict.verdict = "NEEDS_FIX".to_string();
        verdict.human_required = false;
        if !verdict.blocking_findings.contains(&reason) {
            verdict.blocking_findings.push(reason.clone());
        }
        verdict.safety_gate_reason = Some(reason);
        return;
    }

    let reason = if !verdict.blocking_findings.is_empty() {
        Some("APPROVE contradicted non-empty blocking_findings".to_string())
    } else if review_text_has_substantive_prose(review_text, reviewer_backend) {
        Some(REVIEW_FORMAT_ONLY_VIOLATION_REASON.to_string())
    } else if verdict.evidence.is_empty() {
        Some("APPROVE omitted required concrete review evidence".to_string())
    } else if gate_context.enforce_grounding
        && gate_context.falsely_claims_passed_ci(&verdict.evidence)
    {
        Some("APPROVE claimed passed CI while the control plane did not report it".to_string())
    } else if gate_context.enforce_grounding
        && !gate_context.evidence_is_grounded(&verdict.evidence)
    {
        Some(
            "APPROVE evidence was not grounded in an exact changed file from the control plane"
                .to_string(),
        )
    } else if gate_context.hold_contract_changes
        && gate_context.has_contract_surface_change()
        && (gate_context.compatibility_mechanisms.is_empty()
            || !gate_context.compatibility_is_grounded(&verdict.compatibility_evidence))
    {
        Some(CONTRACT_GATE_REASON.to_string())
    } else {
        None
    };

    let Some(reason) = reason else {
        return;
    };

    verdict.verdict = "HUMAN_REVIEW".to_string();
    verdict.human_required = true;
    verdict.safety_gate_reason = Some(reason);
}

/// Whether a criterion's *own wording* asserts something about live/current
/// provider state (so only `provider:`/`snapshot:` evidence should satisfy
/// it) rather than merely naming the provider a feature integrates with, or
/// describing present-tense code/design in general terms.
///
/// Deliberately excludes bare "github"/"gitlab": in a tool whose entire
/// purpose is GitHub/GitLab integration, nearly every criterion mentions the
/// provider by name regardless of whether it's asking about live state or
/// just describing what the feature does (e.g. "Unit tests cover GitHub and
/// GitLab issue bodies..." or "Add contract tests ... without GITLAB_PAT").
///
/// Also excludes bare "current": across this repo's real open issues it is
/// used overwhelmingly to describe the present state of the *code/design*
/// ("current behavior", "current implementation", "the page currently
/// depends on") rather than to assert a live external fact. A criterion that
/// truly needs a live check almost always also uses a more specific marker
/// ("latest", "stale", "open issue", "queue", "remaining quota", ...), so
/// dropping the bare, universally generic "current" removes false positives
/// without weakening real detection -- the existing test fixture ("List the
/// current live GitLab issue queue") is still caught via "live" and "queue"
/// alone.
fn criterion_requires_external_state(criterion: &str) -> bool {
    let lower = criterion.to_ascii_lowercase();
    [
        "live",
        "latest",
        "stale",
        "open issue",
        "closed issue",
        "queue",
        "backlog",
        "provider state",
        "remaining quota",
        "availability",
        "without a pat",
    ]
    .iter()
    .any(|marker| lower.contains(marker))
}

fn admits_unverified_state(finding: &str) -> bool {
    let lower = finding.to_ascii_lowercase();
    [
        "not verified",
        "not re-verified",
        "not reverified",
        "unverified",
        "not checked",
        "could be stale",
        "may be stale",
        "might be stale",
        "unable to verify",
        "could not verify",
    ]
    .iter()
    .any(|marker| lower.contains(marker))
}

fn review_text_has_substantive_prose(review_text: &str, reviewer_backend: &str) -> bool {
    let Some(json) = extract_first_json_object(review_text) else {
        return true;
    };
    let Some(start) = review_text.find(&json) else {
        return true;
    };
    let mut residue = String::with_capacity(review_text.len().saturating_sub(json.len()));
    residue.push_str(&review_text[..start]);
    residue.push_str(&review_text[start + json.len()..]);
    let agy_transport_trace = matches!(reviewer_backend, "agy" | "agy-second");
    residue.lines().map(str::trim).any(|line| {
        // `agy --print` writes its execution-plan trace to stdout before
        // the final answer. Those uniform "I will ..." lines are runner
        // transport metadata, not reviewer prose. Preserve fail-closed
        // behavior for every other line, including AGY's final prose.
        let inert = line.is_empty()
            || (agy_transport_trace && line.starts_with("I will "))
            || matches!(
                line.to_ascii_lowercase().trim_end_matches(':').trim(),
                "review notes" | "## review notes" | "### review notes" | "```json" | "```"
            );
        !inert
    })
}

#[cfg(test)]
mod tests;
