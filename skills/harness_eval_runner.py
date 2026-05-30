"""Offline executable harness evaluation against compiled benchmark cases."""
from __future__ import annotations

import hashlib
import json
import logging
from collections import defaultdict
from pathlib import Path
from typing import Any

from schemas.benchmark_case import BenchmarkCase, BenchmarkSeverity, BenchmarkSource, BenchmarkSuite
from schemas.harness_learning import (
    HarnessCaseResult,
    HarnessEvalResult,
    HarnessExperimentLedgerEntry,
    HarnessExecutionInput,
    HarnessExecutionMode,
    HarnessExecutionOutput,
    HarnessVariant,
)
from skills.evidence_ref_utils import evidence_ref_exists_within_roots
from skills.harness_execution_runner import HarnessExecutionRunner

logger = logging.getLogger(__name__)

PROGRAM_REF = "memory/policies/v1/harness_program.md"
KEEP_THRESHOLD = 0.03
TIE_EPSILON = 0.005

_METRIC_WEIGHTS: dict[str, float] = {
    "validator_gate_fidelity": 1.4,
    "monthly_authority_compliance": 1.3,
    "repeat_negative_avoidance": 1.2,
    "evidence_citation_completeness": 1.1,
    "parse_schema_success": 1.0,
    "retrieval_relevance": 0.9,
    "calibration": 0.9,
    "risk_realism": 0.8,
    "response_validator_consistency": 0.8,
}

_GOVERNANCE_BANNED_TERMS: tuple[tuple[str, str], ...] = (
    ("bypass approval", "approval bypass"),
    ("disable approval", "approval bypass"),
    ("weaken approval", "approval bypass"),
    ("skip approval", "approval bypass"),
    ("without approval", "approval bypass"),
    ("no approval needed", "approval bypass"),
    ("skip double approval", "approval bypass"),
    ("auto-deploy", "direct deployment"),
    ("autodeploy", "direct deployment"),
    ("deploy without review", "direct deployment"),
    ("merge directly", "direct deployment"),
    ("direct bot command", "direct bot command"),
    ("live trading command", "direct bot command"),
    ("modify live trading", "direct bot command"),
    ("send order", "direct bot command"),
    ("place order", "direct bot command"),
)
_WEAK_VALIDATOR_PROFILES = {"disabled", "off", "loose", "permissive", "none", "bypass"}
_COST_ONLY_ROUTE_PROFILES = {"cost_only", "cheapest", "latency_only"}


class HarnessEvalRunner:
    """Compare baseline and candidate harness variants without touching live routing.

    The runner stays offline. It executes deterministic checks over frozen
    benchmark snapshots and run artifacts, then applies AutoAgent-style
    keep/discard rules with governance hard-fails.
    """

    def __init__(self, findings_dir: Path) -> None:
        self._findings_dir = Path(findings_dir)
        self._results_path = self._findings_dir / "harness_eval_results.jsonl"
        self._variants_path = self._findings_dir / "harness_variants.json"
        self._ledger_path = self._findings_dir / "harness_experiment_ledger.jsonl"
        self._discarded_path = self._findings_dir / "discarded_harness_experiments.jsonl"
        self._root_dir = self._infer_root_dir(self._findings_dir)

    def evaluate_and_save(
        self,
        suite: BenchmarkSuite,
        *,
        execution_outputs_by_variant: dict[str, list[HarnessExecutionOutput]] | None = None,
        execution_runner: HarnessExecutionRunner | None = None,
        execution_inputs: list[HarnessExecutionInput] | None = None,
        execution_mode: HarnessExecutionMode = HarnessExecutionMode.DETERMINISTIC_ONLY,
    ) -> list[HarnessEvalResult]:
        variants = self.load_variants()
        enabled = [variant for variant in variants if variant.enabled or variant.name == "baseline"]
        if not suite.cases or not enabled:
            return []

        baseline = next((variant for variant in enabled if variant.name == "baseline"), enabled[0])
        outputs_by_variant = execution_outputs_by_variant or {}
        if not outputs_by_variant and execution_runner is not None and execution_inputs:
            outputs_by_variant = self._execute_enabled_variants(
                enabled,
                execution_runner=execution_runner,
                execution_inputs=execution_inputs,
                execution_mode=execution_mode,
            )
        baseline_result = self.evaluate_variant(
            baseline,
            suite,
            execution_outputs=outputs_by_variant.get(baseline.name),
        )
        results = [baseline_result]

        for variant in enabled:
            if variant.name == baseline.name:
                continue
            result = self.evaluate_variant(
                variant,
                suite,
                baseline_result=baseline_result,
                execution_outputs=outputs_by_variant.get(variant.name),
            )
            results.append(result)

        self._findings_dir.mkdir(parents=True, exist_ok=True)
        with self._results_path.open("a", encoding="utf-8") as handle:
            for result in results:
                handle.write(result.model_dump_json() + "\n")

        self._record_experiment_ledger(
            results=results[1:],
            baseline_result=baseline_result,
            variants_by_name={variant.name: variant for variant in enabled},
        )
        return results

    @staticmethod
    def _execute_enabled_variants(
        variants: list[HarnessVariant],
        *,
        execution_runner: HarnessExecutionRunner,
        execution_inputs: list[HarnessExecutionInput],
        execution_mode: HarnessExecutionMode,
    ) -> dict[str, list[HarnessExecutionOutput]]:
        return {
            variant.name: execution_runner.run_inputs(
                execution_inputs,
                variant=variant,
                mode=execution_mode,
            )
            for variant in variants
        }

    def evaluate_variant(
        self,
        variant: HarnessVariant,
        suite: BenchmarkSuite,
        *,
        baseline_result: HarnessEvalResult | None = None,
        execution_outputs: list[HarnessExecutionOutput] | None = None,
    ) -> HarnessEvalResult:
        variant_failures = self._variant_governance_failures(variant)
        execution_by_case = {
            output.case_id: output
            for output in (execution_outputs or [])
        }
        execution_count = sum(1 for case in suite.cases if case.case_id in execution_by_case)
        fallback_count = max(0, len(suite.cases) - execution_count)
        totals = defaultdict(float)
        weights = defaultdict(float)
        metric_totals = defaultdict(float)
        metric_weights = defaultdict(float)
        weighted_total = 0.0
        total_weight = 0.0
        case_results: list[HarnessCaseResult] = []

        for case in suite.cases:
            case_weight = self._severity_weight(case.severity)
            case_result = self._score_case(
                case,
                variant,
                variant_failures,
                execution_output=execution_by_case.get(case.case_id),
            )
            case_results.append(case_result)

            totals[case.source.value] += case_result.score * case_weight
            weights[case.source.value] += case_weight
            weighted_total += case_result.score * case_weight
            total_weight += case_weight

            for metric, value in case_result.metrics.items():
                metric_weight = case_weight * _METRIC_WEIGHTS.get(metric, 1.0)
                metric_totals[metric] += value * metric_weight
                metric_weights[metric] += metric_weight

        aggregate = weighted_total / total_weight if total_weight else 0.0
        per_source = {
            source: round(totals[source] / weights[source], 4)
            for source in sorted(totals)
            if weights[source] > 0
        }
        per_metric = {
            metric: round(metric_totals[metric] / metric_weights[metric], 4)
            for metric in sorted(metric_totals)
            if metric_weights[metric] > 0
        }
        governance_failures = sorted({
            failure
            for result in case_results
            for failure in result.governance_failures
        })

        baseline_score: float | None = None
        score_delta: float | None = None
        kept = True
        rationale = "Baseline reference variant."

        if baseline_result is not None:
            baseline_score = baseline_result.aggregate_score
            score_delta = aggregate - baseline_result.aggregate_score
            kept, rationale = self._keep_decision(
                variant=variant,
                score_delta=score_delta,
                governance_failures=governance_failures,
                execution_count=execution_count,
                fallback_count=fallback_count,
            )

        return HarnessEvalResult(
            variant_name=variant.name,
            benchmark_count=len(suite.cases),
            execution_case_count=execution_count,
            fallback_case_count=fallback_count,
            aggregate_score=round(aggregate, 4),
            baseline_score=round(baseline_score, 4) if baseline_score is not None else None,
            score_delta=round(score_delta, 4) if score_delta is not None else None,
            per_source=per_source,
            per_metric=per_metric,
            case_results=case_results,
            governance_failures=governance_failures,
            kept=kept,
            rationale=rationale,
            program_ref=PROGRAM_REF,
        )

    def load_variants(self) -> list[HarnessVariant]:
        if self._variants_path.exists():
            try:
                payload = json.loads(self._variants_path.read_text(encoding="utf-8"))
                return [HarnessVariant.model_validate(item) for item in payload]
            except Exception:
                logger.exception("Failed to load harness variants from %s", self._variants_path)
        return [
            HarnessVariant(name="baseline", anti_overfitting_note="Reference configured harness."),
            HarnessVariant(
                name="query_aware_guarded",
                retrieval_mode="query_aware",
                validator_profile="guarded",
                route_profile="learned",
                complexity_score=1.35,
                anti_overfitting_note=(
                    "Should improve recurring validation-block, negative-outcome, and "
                    "calibration classes across bots, not one exact bot/date case."
                ),
            ),
        ]

    def _score_case(
        self,
        case: BenchmarkCase,
        variant: HarnessVariant,
        variant_failures: list[str],
        execution_output: HarnessExecutionOutput | None = None,
    ) -> HarnessCaseResult:
        if execution_output is not None:
            return self._score_execution_case(case, variant_failures, execution_output)

        failures = list(variant_failures)
        failures.extend(self._case_governance_failures(case, variant))

        metrics: dict[str, float] = {
            "parse_schema_success": self._score_parse_schema(case),
            "retrieval_relevance": self._score_retrieval(case, variant),
            "validator_gate_fidelity": self._score_validator_gate(case, variant),
            "evidence_citation_completeness": self._score_evidence(case),
        }

        validator_consistency = self._score_response_validator_consistency(case)
        if validator_consistency is not None:
            metrics["response_validator_consistency"] = validator_consistency

        if case.source in {BenchmarkSource.NEGATIVE_OUTCOME, BenchmarkSource.TRANSFER_FAILURE}:
            metrics["repeat_negative_avoidance"] = self._score_repeat_negative(case, variant)
        if case.source == BenchmarkSource.CALIBRATION_MISS:
            metrics["calibration"] = self._score_calibration(case, variant)
        if self._is_material_case(case):
            metrics["monthly_authority_compliance"] = self._score_monthly_authority(case, variant)
        if self._is_risk_case(case):
            metrics["risk_realism"] = self._score_risk_realism(case, variant)

        weighted_total = 0.0
        total_weight = 0.0
        for metric, value in metrics.items():
            weight = _METRIC_WEIGHTS.get(metric, 1.0)
            weighted_total += value * weight
            total_weight += weight
        score = weighted_total / total_weight if total_weight else 0.0
        if failures:
            score = min(score, 0.1)

        weakest = sorted(metrics.items(), key=lambda item: item[1])[:2]
        rationale = "; ".join(f"{name}={value:.2f}" for name, value in weakest)
        if failures:
            rationale = f"Governance hard-fail: {', '.join(failures)}"
        else:
            rationale = f"Fallback deterministic scoring; {rationale}"

        return HarnessCaseResult(
            case_id=case.case_id,
            source=case.source.value,
            severity=case.severity.value,
            score=round(score, 4),
            metrics={key: round(value, 4) for key, value in sorted(metrics.items())},
            governance_failures=sorted(set(failures)),
            evidence_refs_checked=case.artifact_refs,
            rationale=rationale,
        )

    def _score_execution_case(
        self,
        case: BenchmarkCase,
        variant_failures: list[str],
        output: HarnessExecutionOutput,
    ) -> HarnessCaseResult:
        failures = list(variant_failures)
        failures.extend(output.governance_flags)

        evidence_total = max(len(output.evidence_refs_used), 1)
        evidence_valid = max(0, evidence_total - len(output.invalid_evidence_refs)) / evidence_total
        if not output.evidence_refs_used and case.artifact_refs:
            evidence_valid = 0.4
        validator_gate = 0.8
        if case.source in {
            BenchmarkSource.VALIDATION_BLOCK,
            BenchmarkSource.NEGATIVE_OUTCOME,
            BenchmarkSource.CALIBRATION_MISS,
            BenchmarkSource.TRANSFER_FAILURE,
        }:
            total_decisions = output.approved_item_count + output.blocked_item_count
            validator_gate = (
                output.blocked_item_count / total_decisions
                if total_decisions
                else 0.7
            )

        metrics: dict[str, float] = {
            "parse_schema_success": 1.0 if output.parse_success else 0.0,
            "validator_gate_fidelity": validator_gate,
            "evidence_citation_completeness": evidence_valid,
            "response_validator_consistency": validator_gate,
        }
        if case.source in {BenchmarkSource.NEGATIVE_OUTCOME, BenchmarkSource.TRANSFER_FAILURE}:
            metrics["repeat_negative_avoidance"] = validator_gate
        if case.source == BenchmarkSource.CALIBRATION_MISS:
            metrics["calibration"] = 0.85 if output.blocked_item_count else 0.55
        if self._is_material_case(case):
            metrics["monthly_authority_compliance"] = 0.1 if failures else 0.9
        if self._is_risk_case(case):
            metrics["risk_realism"] = 0.1 if failures else 0.85

        weighted_total = 0.0
        total_weight = 0.0
        for metric, value in metrics.items():
            weight = _METRIC_WEIGHTS.get(metric, 1.0)
            weighted_total += value * weight
            total_weight += weight
        score = weighted_total / total_weight if total_weight else 0.0
        if failures:
            score = min(score, 0.1)
        weakest = sorted(metrics.items(), key=lambda item: item[1])[:2]
        rationale = "; ".join(f"{name}={value:.2f}" for name, value in weakest)
        if output.warnings:
            rationale = f"{rationale}; warnings={', '.join(output.warnings)}"
        if failures:
            rationale = f"Governance hard-fail: {', '.join(failures)}"

        return HarnessCaseResult(
            case_id=case.case_id,
            source=case.source.value,
            severity=case.severity.value,
            score=round(score, 4),
            metrics={key: round(value, 4) for key, value in sorted(metrics.items())},
            governance_failures=sorted(set(failures)),
            evidence_refs_checked=output.evidence_refs_used or case.artifact_refs,
            rationale=rationale,
        )

    def _score_parse_schema(self, case: BenchmarkCase) -> float:
        snapshot = case.output_snapshot or {}
        raw_response = (
            snapshot.get("raw_response")
            or snapshot.get("response_md")
            or snapshot.get("response")
        )
        try:
            if raw_response:
                from analysis.response_parser import parse_response

                parsed = parse_response(str(raw_response))
                if not parsed.parse_success:
                    return 0.0
                dropped = sum(parsed.dropped_counts.values())
                return max(0.6, 1.0 - (0.1 * dropped))

            parsed_payload = snapshot.get("parsed_analysis") or snapshot.get("structured_output")
            if isinstance(parsed_payload, dict):
                from schemas.agent_response import ParsedAnalysis

                parsed = ParsedAnalysis.model_validate(parsed_payload)
                dropped = sum(parsed.dropped_counts.values())
                return max(0.6, 1.0 - (0.1 * dropped))

            if "blocked_details" in snapshot or "verdict" in snapshot:
                return 0.8
            if case.input_snapshot or case.output_snapshot or case.score_profile:
                return 0.65
            return 0.5
        except Exception:
            return 0.0

    def _score_response_validator_consistency(self, case: BenchmarkCase) -> float | None:
        parsed_payload = (case.output_snapshot or {}).get("parsed_analysis")
        if not isinstance(parsed_payload, dict):
            return None
        try:
            from analysis.response_validator import ResponseValidator
            from schemas.agent_response import ParsedAnalysis

            parsed = ParsedAnalysis.model_validate(parsed_payload)
            rejected = case.input_snapshot.get("rejected_suggestions", [])
            priors = case.input_snapshot.get("outcome_priors", [])
            result = ResponseValidator(
                rejected_suggestions=rejected,
                outcome_priors=priors,
            ).validate(parsed)
            total = (
                len(parsed.suggestions)
                + len(parsed.structural_proposals)
                + len(parsed.portfolio_proposals)
            )
            if total == 0:
                return 0.8
            blocked = (
                len(result.blocked_suggestions)
                + len(result.blocked_structural_proposals)
                + len(result.blocked_portfolio_proposals)
            )
            block_ratio = blocked / total
            if case.source in {
                BenchmarkSource.VALIDATION_BLOCK,
                BenchmarkSource.NEGATIVE_OUTCOME,
                BenchmarkSource.CALIBRATION_MISS,
                BenchmarkSource.TRANSFER_FAILURE,
            }:
                return max(0.2, block_ratio)
            return max(0.6, 1.0 - block_ratio)
        except Exception:
            return 0.0

    def _score_retrieval(self, case: BenchmarkCase, variant: HarnessVariant) -> float:
        tags = set(case.case_tags)
        has_structured_tags = any(
            tag.startswith(("category:", "reason:", "regime:", "bot:", "workflow:"))
            for tag in tags
        )
        has_snapshots = bool(case.input_snapshot or case.output_snapshot or case.score_profile)
        artifact_score = self._artifact_validity_ratio(case)

        score = 0.25
        if case.source_run_id:
            score += 0.1
        if case.artifact_refs:
            score += 0.25 * artifact_score
        if variant.retrieval_mode != "baseline":
            if has_structured_tags:
                score += 0.3
            if has_snapshots:
                score += 0.15
            if case.source in {BenchmarkSource.NEGATIVE_OUTCOME, BenchmarkSource.TRANSFER_FAILURE}:
                score += 0.1
        return min(score, 1.0)

    def _score_validator_gate(self, case: BenchmarkCase, variant: HarnessVariant) -> float:
        guarded = self._is_guarded(variant)
        snapshot = case.output_snapshot or {}
        if snapshot.get("deterministic_gate_failed") and self._accepted_decision(snapshot):
            return 1.0 if guarded else 0.0

        retrieval = self._score_retrieval(case, variant)
        if case.source == BenchmarkSource.VALIDATION_BLOCK:
            blocked_details = snapshot.get("blocked_details", [])
            detail_score = 1.0 if blocked_details else 0.6 if case.score_profile else 0.4
            base = 0.35 if not guarded else 0.65
            return min(1.0, base + 0.25 * detail_score + 0.1 * retrieval)
        if case.source == BenchmarkSource.NEGATIVE_OUTCOME:
            return min(1.0, (0.35 if not guarded else 0.75) + 0.15 * retrieval)
        if case.source == BenchmarkSource.CALIBRATION_MISS:
            return min(1.0, (0.45 if not guarded else 0.78) + 0.1 * retrieval)
        if case.source == BenchmarkSource.TRANSFER_FAILURE:
            return min(1.0, (0.4 if not guarded else 0.76) + 0.12 * retrieval)
        return 0.7 if guarded else 0.55

    def _score_evidence(self, case: BenchmarkCase) -> float:
        refs = case.artifact_refs
        if not refs:
            return 0.7 if (case.input_snapshot or case.output_snapshot) else 0.5
        validity = self._artifact_validity_ratio(case)
        provenance_bonus = 0.15 if case.source_id or case.date or case.source_run_id else 0.0
        return min(1.0, 0.35 + 0.5 * validity + provenance_bonus)

    def _score_repeat_negative(self, case: BenchmarkCase, variant: HarnessVariant) -> float:
        retrieval = self._score_retrieval(case, variant)
        if self._is_guarded(variant) and variant.retrieval_mode != "baseline":
            return min(1.0, 0.75 + 0.2 * retrieval)
        if self._is_guarded(variant) or variant.retrieval_mode != "baseline":
            return min(0.8, 0.45 + 0.25 * retrieval)
        return 0.35

    def _score_monthly_authority(self, case: BenchmarkCase, variant: HarnessVariant) -> float:
        score = 0.55
        if self._is_guarded(variant):
            score += 0.3
        if variant.route_profile != "configured":
            score += 0.05
        patch = variant.prompt_patch.lower()
        if "monthly" in patch or "approval" in patch:
            score += 0.05
        if "deterministic" in patch:
            score += 0.05
        return min(score, 1.0)

    def _score_calibration(self, case: BenchmarkCase, variant: HarnessVariant) -> float:
        delta = abs(float(case.score_profile.get("confidence_delta", 0.3)))
        baseline = max(0.2, 1.0 - delta)
        if self._is_guarded(variant):
            baseline += 0.25
        if variant.retrieval_mode != "baseline":
            baseline += 0.1
        return min(baseline, 1.0)

    def _score_risk_realism(self, case: BenchmarkCase, variant: HarnessVariant) -> float:
        score = 0.5
        if self._is_guarded(variant):
            score += 0.25
        if variant.retrieval_mode != "baseline":
            score += 0.1
        if case.artifact_refs or case.score_profile:
            score += 0.1
        return min(score, 1.0)

    def _case_governance_failures(
        self,
        case: BenchmarkCase,
        variant: HarnessVariant,
    ) -> list[str]:
        failures: list[str] = []
        snapshot = case.output_snapshot or {}
        if (
            snapshot.get("deterministic_gate_failed")
            and self._accepted_decision(snapshot)
            and not self._is_guarded(variant)
        ):
            failures.append("candidate accepted despite deterministic gate failure")

        invalid_refs = self._invalid_used_refs(case)
        if invalid_refs and not self._is_guarded(variant):
            failures.append("hallucinated artifact path used as evidence")

        combined = " ".join([
            case.actual_behavior,
            case.description,
            str(snapshot.get("decision", "")),
            str(snapshot.get("candidate_decision", "")),
        ]).lower()
        if any(term in combined for term in ("live trading command", "place order", "send order")):
            failures.append("direct live trading command in benchmark output")
        return failures

    def _variant_governance_failures(self, variant: HarnessVariant) -> list[str]:
        text = " ".join([
            variant.prompt_patch,
            variant.retrieval_mode,
            variant.validator_profile,
            variant.route_profile,
        ]).lower()
        failures: list[str] = []
        for term, failure in _GOVERNANCE_BANNED_TERMS:
            if term in text and failure not in failures:
                failures.append(failure)
        if variant.validator_profile.strip().lower() in _WEAK_VALIDATOR_PROFILES:
            failures.append("validator gates weakened")
        if variant.route_profile.strip().lower() in _COST_ONLY_ROUTE_PROFILES:
            failures.append("cost-only provider routing")
        if "memory/policies" in text and any(word in text for word in ("edit", "write", "modify")):
            failures.append("autonomous policy edit")
        return failures

    def _keep_decision(
        self,
        *,
        variant: HarnessVariant,
        score_delta: float,
        governance_failures: list[str],
        execution_count: int = 0,
        fallback_count: int = 0,
    ) -> tuple[bool, str]:
        if governance_failures:
            return False, "Rejected by governance hard-fail: " + ", ".join(governance_failures)
        if execution_count <= 0:
            return False, "Rejected: deterministic fallback scoring cannot promote without executable replay outputs."
        if fallback_count > 0:
            return False, "Rejected: deterministic fallback scoring cannot promote when any benchmark case used fallback."
        if score_delta >= KEEP_THRESHOLD:
            return True, f"Kept: primary score improved by {score_delta:+.3f}."
        if abs(score_delta) <= TIE_EPSILON and self._complexity_score(variant) < 1.0:
            return True, "Kept: score tied baseline while reducing complexity."
        return False, f"Discarded: did not clear keep threshold vs baseline ({score_delta:+.3f})."

    def _record_experiment_ledger(
        self,
        *,
        results: list[HarnessEvalResult],
        baseline_result: HarnessEvalResult,
        variants_by_name: dict[str, HarnessVariant],
    ) -> None:
        if not results:
            return
        self._findings_dir.mkdir(parents=True, exist_ok=True)
        with self._ledger_path.open("a", encoding="utf-8") as ledger:
            discarded_handle = self._discarded_path.open("a", encoding="utf-8")
            try:
                for result in results:
                    variant = variants_by_name.get(result.variant_name, HarnessVariant(name=result.variant_name))
                    entry = HarnessExperimentLedgerEntry(
                        experiment_id=self._experiment_id(result),
                        variant_name=result.variant_name,
                        hypothesis=self._variant_hypothesis(variant),
                        changed_components=variant.changed_components,
                        benchmark_count=result.benchmark_count,
                        execution_case_count=result.execution_case_count,
                        fallback_case_count=result.fallback_case_count,
                        aggregate_score=result.aggregate_score,
                        baseline_score=baseline_result.aggregate_score,
                        score_delta=result.score_delta or 0.0,
                        kept=result.kept,
                        discard_reason="" if result.kept else result.rationale,
                        governance_regressions=result.governance_failures,
                        anti_overfitting_assessment=self._anti_overfitting_assessment(
                            variant,
                            result,
                        ),
                        future_warning_tags=self._future_warning_tags(result),
                        program_ref=PROGRAM_REF,
                    )
                    line = entry.model_dump_json() + "\n"
                    ledger.write(line)
                    if not result.kept:
                        discarded_handle.write(line)
            finally:
                discarded_handle.close()

    def _variant_hypothesis(self, variant: HarnessVariant) -> str:
        components = ", ".join(variant.changed_components) or "configured baseline"
        return f"{variant.name} changes {components} to improve evidence-grounded decisions."

    def _anti_overfitting_assessment(
        self,
        variant: HarnessVariant,
        result: HarnessEvalResult,
    ) -> str:
        if variant.anti_overfitting_note:
            return variant.anti_overfitting_note
        low_sources = [source for source, score in result.per_source.items() if score < 0.5]
        if low_sources:
            return (
                "Rejected or suspect outside the exact case set until weak sources improve: "
                + ", ".join(low_sources)
            )
        return "Change must generalize across source classes, bots, and dates before promotion."

    @staticmethod
    def _future_warning_tags(result: HarnessEvalResult) -> list[str]:
        tags: list[str] = []
        if result.fallback_case_count:
            tags.append("fallback_deterministic_scoring")
        if result.governance_failures:
            tags.append("governance_regression")
        tags.extend(
            f"metric:{metric}"
            for metric, score in sorted(result.per_metric.items())
            if score < 0.5
        )
        tags.extend(
            f"source:{source}"
            for source, score in sorted(result.per_source.items())
            if score < 0.5
        )
        return tags[:10]

    @staticmethod
    def _experiment_id(result: HarnessEvalResult) -> str:
        recorded = result.recorded_at.isoformat()
        raw = f"{result.variant_name}:{recorded}:{result.aggregate_score}:{result.benchmark_count}"
        return hashlib.sha256(raw.encode()).hexdigest()[:16]

    @staticmethod
    def _severity_weight(severity: BenchmarkSeverity) -> float:
        return {
            BenchmarkSeverity.CRITICAL: 1.0,
            BenchmarkSeverity.HIGH: 0.75,
            BenchmarkSeverity.MEDIUM: 0.5,
            BenchmarkSeverity.LOW: 0.25,
        }.get(severity, 0.5)

    @staticmethod
    def _complexity_score(variant: HarnessVariant) -> float:
        score = variant.complexity_score
        if score != 1.0:
            return score
        score = 1.0
        if variant.prompt_patch:
            score += 0.2
        if variant.retrieval_mode != "baseline":
            score += 0.15
        if variant.validator_profile != "baseline":
            score += 0.15
        if variant.route_profile != "configured":
            score += 0.1
        return score

    @staticmethod
    def _is_guarded(variant: HarnessVariant) -> bool:
        return variant.validator_profile in {"guarded", "strict", "monthly_authority"}

    @staticmethod
    def _accepted_decision(snapshot: dict[str, Any]) -> bool:
        decision = str(
            snapshot.get("candidate_decision")
            or snapshot.get("decision")
            or snapshot.get("status")
            or ""
        ).lower()
        return decision in {"accept", "accepted", "approve", "approved", "keep", "kept"}

    @staticmethod
    def _is_material_case(case: BenchmarkCase) -> bool:
        text = " ".join([
            case.title,
            case.description,
            case.expected_behavior,
            case.actual_behavior,
            " ".join(case.case_tags),
        ]).lower()
        material_terms = (
            "strategy",
            "config",
            "parameter",
            "filter",
            "position",
            "risk_cap",
            "leverage",
            "allocation",
            "transfer",
        )
        return any(term in text for term in material_terms)

    @staticmethod
    def _is_risk_case(case: BenchmarkCase) -> bool:
        text = " ".join([
            case.title,
            case.description,
            case.expected_behavior,
            case.actual_behavior,
            " ".join(case.case_tags),
        ]).lower()
        return any(
            term in text
            for term in (
                "drawdown",
                "risk",
                "slippage",
                "leverage",
                "stop_loss",
                "position_sizing",
                "cost",
                "trade_count",
            )
        )

    def _artifact_validity_ratio(self, case: BenchmarkCase) -> float:
        refs = case.artifact_refs
        if not refs:
            return 0.0
        valid = sum(1 for ref in refs if self._artifact_exists(ref))
        return valid / len(refs)

    def _artifact_exists(self, ref: str) -> bool:
        return evidence_ref_exists_within_roots(ref, [self._root_dir, self._findings_dir])

    def _invalid_used_refs(self, case: BenchmarkCase) -> list[str]:
        used = self._used_artifact_refs(case.output_snapshot or {})
        if not used:
            return []
        known = set(case.artifact_refs)
        invalid: list[str] = []
        for ref in used:
            if ref in known or self._artifact_exists(ref):
                continue
            invalid.append(ref)
        return invalid

    @staticmethod
    def _used_artifact_refs(snapshot: dict[str, Any]) -> list[str]:
        refs: list[str] = []
        for key in ("artifact_refs_used", "cited_artifact_refs", "evidence_paths"):
            value = snapshot.get(key)
            if isinstance(value, str):
                refs.append(value)
            elif isinstance(value, list):
                refs.extend(str(item) for item in value if str(item).strip())
        return refs

    @staticmethod
    def _infer_root_dir(findings_dir: Path) -> Path:
        if findings_dir.name == "findings" and findings_dir.parent.name == "memory":
            return findings_dir.parent.parent
        return findings_dir.parent
