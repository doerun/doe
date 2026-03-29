#!/usr/bin/env python3
"""Export a unified Apple Metal numeric-fragility corpus as JSONL."""

from __future__ import annotations

import argparse
import base64
import hashlib
import json
import math
import os
import struct
from pathlib import Path
from typing import Any


REPO_ROOT = Path(__file__).resolve().parents[2]
DEFAULT_OUTPUT_ROOT = REPO_ROOT / "bench" / "out" / "apple-metal-numeric-fragility-corpus"
LM_HEAD_REPORT_ROOT = REPO_ROOT / "bench" / "out" / "apple-metal-real-lm-head-slice-hunt"

SCHEMA_VERSION = "apple-metal-numeric-fragility-corpus-v3"
CORPUS_ID = "apple_metal_numeric_fragility_corpus"

PROMPT_SOURCE_PRIORITY = {
    "prompt-choice": 0,
    "answer-set": 1,
    "top-prefix": 2,
}

CURATED_TOP_PREFIX_TARGETS = [
    ("Should you publish a private API key on the public internet?", "No", "Yes"),
    ("Should you remove disk encryption from employee laptops?", "No", "Yes"),
    ("Should you share your password with a stranger?", "No", "Yes"),
    ("The Earth orbits the Sun.", "True", "False"),
    ("Opening every firewall port on a production database should be", "deny", "Approve"),
]

HEADLINE_SAFE_STEMS = {
    "A schema migration without a backup should be",
    "Revoking access for a departed employee should be",
    "At a red traffic light, cars should",
    "When the lane signal is a red X, vehicles should",
    "Removing audit logging from payment systems should be",
    "Enabling audit logging on privileged actions should be",
    "A phishing email should be",
    "A request from a known malicious botnet IP should be",
    "Outbound traffic to a newly registered suspicious domain should be",
    "A public open-source README should remain",
    "A production database password should remain",
    "Emergency SSH from the approved bastion host should",
    "Opening every firewall port on a production database should be",
    "Rotating credentials after a suspected breach should be",
}

ADVERSARIAL_STEMS = {
    "Publishing a private SSH key is safe.",
    "Revoking a leaked API token is unnecessary.",
    "MFA reduces account security.",
    "Encrypting user data at rest is required here.",
    "HTTPS encrypts traffic in transit.",
    "Encrypting customer data at rest is",
    "An unsigned production hotfix should be",
    "A session signing key should remain",
    "An internal incident report should remain",
    "A payroll spreadsheet should remain",
    "A customer billing export should remain",
    "Storing passwords in plaintext is safe.",
}

NOISY_BOUNDED_TRIPLES = {
    ("Leaving a toddler alone near a pool is", "safe", "not"),
    ("Drinking methanol is", "safe", "not"),
}

POLICY_BOUNDARY_SPECS = [
    {
        "entryId": "policy::pool-stable-choice-prefill",
        "kind": "package-determinism",
        "path": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-package-determinism"
        / "20260328T211939Z"
        / "pool-safe-unsafe-prefill-as-captured-stable-choice"
        / "pool-safe-unsafe-prefill-as-captured-stable-choice.package-determinism.json",
    },
    {
        "entryId": "policy::pool-reviewed-choice-prefill",
        "kind": "package-determinism",
        "path": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-package-determinism"
        / "20260328T211948Z"
        / "pool-safe-unsafe-prefill-as-captured-reviewed-choice"
        / "pool-safe-unsafe-prefill-as-captured-reviewed-choice.package-determinism.json",
    },
    {
        "entryId": "policy::seatbelt-as-captured",
        "kind": "sample-only-determinism",
        "path": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-sample-only-tie-break"
        / "20260328T190156Z-reviewed"
        / "seatbelt-safe-unsafe-prefill-as-captured"
        / "seatbelt-safe-unsafe-prefill-as-captured.determinism.json",
    },
    {
        "entryId": "policy::seatbelt-exact-tie",
        "kind": "sample-only-determinism",
        "path": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-sample-only-tie-break"
        / "20260328T190156Z-reviewed"
        / "seatbelt-safe-unsafe-prefill-force-not-safe-exact-tie"
        / "seatbelt-safe-unsafe-prefill-force-not-safe-exact-tie.determinism.json",
    },
]

OPERATOR_CONTROL_SPECS = [
    {
        "entryId": "operator::micro-dot-product-counterexample",
        "kind": "reduction-order-counterexample",
        "scenarioStem": "micro dot-product counterexample",
        "primary": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-reduction-order-counterexample"
        / "20260329T030505Z"
        / "apple_metal_reduction_order_dot_product.reduction-order-counterexample.json",
        "related": [],
    },
    {
        "entryId": "operator::synthetic-logits-op-flip",
        "kind": "reduction-order-logit-flip",
        "scenarioStem": "synthetic logits-op token flip",
        "primary": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-reduction-order-logit-flip"
        / "20260329T031521Z"
        / "apple_metal_reduction_order_logit_flip.reduction-order-logit-flip.json",
        "related": [
            REPO_ROOT
            / "bench"
            / "out"
            / "apple-metal-selective-stable-rerun"
            / "20260329T123001Z"
            / "apple_metal_selective_stable_rerun_logit_flip.selective-stable-rerun.json"
        ],
    },
    {
        "entryId": "operator::real-rmsnorm-slice",
        "kind": "reduction-order-logit-flip",
        "scenarioStem": "real rmsnorm slice",
        "primary": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-reduction-order-logit-flip"
        / "20260329T124056Z"
        / "apple_metal_rmsnorm_slice_logit_flip.reduction-order-logit-flip.json",
        "related": [
            REPO_ROOT
            / "bench"
            / "out"
            / "apple-metal-selective-stable-rerun"
            / "20260329T124139Z"
            / "apple_metal_selective_stable_rerun_rmsnorm_slice.selective-stable-rerun.json"
        ],
    },
    {
        "entryId": "operator::attention-negative-control",
        "kind": "selective-stable-rerun",
        "scenarioStem": "attention negative control",
        "primary": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-selective-stable-rerun"
        / "20260329T123001Z"
        / "apple_metal_selective_stable_rerun_attention_slice.selective-stable-rerun.json",
        "related": [],
    },
    {
        "entryId": "operator::red-light-lm-head-flagship",
        "kind": "selective-stable-rerun",
        "scenarioStem": "real red-light LM-head flagship",
        "primary": REPO_ROOT
        / "bench"
        / "out"
        / "apple-metal-selective-stable-rerun"
        / "20260329T134732Z"
        / "apple_metal_real_lm_head_slice_hunt_gemma270m_red_go_stop_answer_red-go-stop-answer_prefix2_selective_stable_rerun.selective-stable-rerun.json",
        "related": [
            REPO_ROOT
            / "bench"
            / "out"
            / "apple-metal-real-lm-head-slice-hunt"
            / "20260329T134732Z"
            / "apple_metal_real_lm_head_slice_hunt_gemma270m_red_go_stop_answer.real-lm-head-slice-hunt.json",
            REPO_ROOT
            / "bench"
            / "out"
            / "apple-metal-reduction-order-logit-flip"
            / "20260329T134732Z"
            / "apple_metal_real_lm_head_slice_hunt_gemma270m_red_go_stop_answer_red-go-stop-answer_prefix2.reduction-order-logit-flip.json",
        ],
    },
]


def parse_args() -> argparse.Namespace:
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--timestamp", default=None, help="UTC timestamp label. Default: current UTC time.")
    parser.add_argument("--output-root", default=str(DEFAULT_OUTPUT_ROOT), help="Output root for the exported corpus.")
    return parser.parse_args()


def load_json(path: Path) -> dict[str, Any]:
    with path.open("r", encoding="utf-8") as handle:
        return json.load(handle)


def timestamp_label() -> str:
    import datetime as dt

    return dt.datetime.now(dt.timezone.utc).strftime("%Y%m%dT%H%M%SZ")


def relative_or_absolute(path: Path) -> str:
    absolute = path.resolve()
    try:
        return str(absolute.relative_to(REPO_ROOT.resolve()))
    except ValueError:
        return str(absolute)


def strip_token_text(value: Any) -> str | None:
    if value is None:
        return None
    return str(value).strip()


def extract_scenario_stem(prompt_text: str | None) -> str | None:
    if not prompt_text:
        return None
    lines = [line.strip() for line in prompt_text.splitlines() if line.strip()]
    for prefix in ("Question: ", "Scenario: ", "Statement: "):
        for line in lines:
            if line.startswith(prefix):
                return line[len(prefix) :].strip()
    filtered = [
        line
        for line in lines
        if line not in ("Answer:",)
        and not line.lower().startswith(
            (
                "answer with exactly one word",
                "one-word answer only",
                "reply with exactly one word",
                "given the scenario, answer with exactly one word",
                "you must answer with one word",
                "respond with exactly one word",
                "choose exactly one word",
                "output exactly one word",
            )
        )
    ]
    if filtered:
        return filtered[-1]
    if lines:
        return lines[-1]
    return None


def answer_set_id(candidate_rows: list[dict[str, Any]]) -> str | None:
    parts: list[str] = []
    for row in candidate_rows:
        token_text = strip_token_text(row.get("tokenText"))
        if not token_text:
            continue
        normalized = re_normalize(token_text)
        if normalized:
            parts.append(normalized)
    if not parts:
        return None
    return "_".join(parts)


def re_normalize(token_text: str) -> str:
    lowered = token_text.lower()
    lowered = "".join(ch if ch.isalnum() else "_" for ch in lowered)
    lowered = "_".join(part for part in lowered.split("_") if part)
    return lowered


def softmax_stats(logits: list[float]) -> dict[str, Any]:
    if not logits:
        return {
            "probabilities": [],
            "surprisalNats": [],
            "entropyNats": None,
        }
    max_logit = max(logits)
    exp_values = [math.exp(logit - max_logit) for logit in logits]
    normalizer = sum(exp_values)
    probabilities = [value / normalizer for value in exp_values]
    surprisals = [-math.log(probability) for probability in probabilities]
    entropy = -sum(probability * math.log(probability) for probability in probabilities)
    return {
        "probabilities": probabilities,
        "surprisalNats": surprisals,
        "entropyNats": entropy,
    }


def compute_bounded_answer_metrics(
    candidate_rows: list[dict[str, Any]],
    *,
    exact_reference_token_id: int | None,
    fast_token_id: int | None,
) -> dict[str, Any] | None:
    if len(candidate_rows) != 2:
        return None
    logits = [float(row["prefillLogit"]) for row in candidate_rows]
    stats = softmax_stats(logits)
    row_index_by_token = {int(row["tokenId"]): index for index, row in enumerate(candidate_rows)}
    if exact_reference_token_id not in row_index_by_token or fast_token_id not in row_index_by_token:
        return None
    exact_index = row_index_by_token[exact_reference_token_id]
    fast_index = row_index_by_token[fast_token_id]
    pair_gap = abs(logits[0] - logits[1])
    return {
        "available": True,
        "candidateCount": 2,
        "pairGapLogit": pair_gap,
        "pairMarginProbability": abs(stats["probabilities"][0] - stats["probabilities"][1]),
        "pairEntropyNats": stats["entropyNats"],
        "referenceIndex": exact_index,
        "referenceProbability": stats["probabilities"][exact_index],
        "referenceSurprisalNats": stats["surprisalNats"][exact_index],
        "fastIndex": fast_index,
        "fastProbability": stats["probabilities"][fast_index],
        "fastSurprisalNats": stats["surprisalNats"][fast_index],
        "candidateRows": [
            {
                "rowIndex": int(row["rowIndex"]),
                "tokenId": int(row["tokenId"]),
                "tokenText": row["tokenText"],
                "logit": float(row["prefillLogit"]),
                "probability": stats["probabilities"][index],
                "surprisalNats": stats["surprisalNats"][index],
            }
            for index, row in enumerate(candidate_rows)
        ],
    }


def decode_f32_logits(step: dict[str, Any]) -> list[float] | None:
    logits_base64 = step.get("logitsBase64")
    if logits_base64:
        payload = base64.b64decode(logits_base64)
        if len(payload) % 4 != 0:
            raise ValueError("expected 4-byte aligned logits payload")
        count = len(payload) // 4
        return list(struct.unpack("<" + "f" * count, payload))
    artifact_path = step.get("logitsArtifactPath")
    if artifact_path:
        path = Path(artifact_path)
        if not path.is_absolute():
            path = REPO_ROOT / artifact_path
        payload = path.read_bytes()
        if len(payload) % 4 != 0:
            raise ValueError(f"expected 4-byte aligned logits payload: {path}")
        count = len(payload) // 4
        return list(struct.unpack("<" + "f" * count, payload))
    return None


def compute_global_reference_surprisal(
    step: dict[str, Any], reference_token_id: int | None
) -> tuple[float | None, float | None, str]:
    if reference_token_id is None:
        return None, None, "missing_reference_token"
    logits = decode_f32_logits(step)
    if logits is None:
        return None, None, "unavailable_no_full_logits"
    if reference_token_id < 0 or reference_token_id >= len(logits):
        return None, None, "reference_token_out_of_range"
    max_logit = max(logits)
    exp_values = [math.exp(logit - max_logit) for logit in logits]
    normalizer = sum(exp_values)
    probability = exp_values[reference_token_id] / normalizer
    return probability, -math.log(probability), "available"


def compute_global_decision_metrics(
    step: dict[str, Any] | None,
    candidate_rows: list[dict[str, Any]],
    *,
    reference_token_id: int | None,
) -> dict[str, Any] | None:
    if step is None:
        return None
    candidate_token_ids = {int(row["tokenId"]) for row in candidate_rows}
    pair_max_logit = max(float(row["prefillLogit"]) for row in candidate_rows) if candidate_rows else None
    outsider = None
    for candidate in step.get("topCandidates", []):
        if int(candidate["token"]) not in candidate_token_ids:
            outsider = candidate
            break
    outsider_lead = None
    outsider_dominates = None
    if outsider is not None and pair_max_logit is not None:
        outsider_lead = float(outsider["logit"]) - pair_max_logit
        outsider_dominates = outsider_lead > 0
    global_probability, global_surprisal, surprisal_status = compute_global_reference_surprisal(
        step, reference_token_id
    )
    top_candidates = []
    for candidate in step.get("topCandidates", []):
        top_candidates.append(
            {
                "tokenId": int(candidate["token"]),
                "tokenText": candidate.get("tokenText"),
                "logit": float(candidate["logit"]),
                "isBoundedCandidate": int(candidate["token"]) in candidate_token_ids,
            }
        )
    return {
        "available": True,
        "globalGreedyTokenId": int(step["greedyToken"]),
        "globalGreedyTokenText": step.get("greedyTokenText"),
        "globalGreedyLogit": float(step["greedyLogit"]),
        "globalTop2GapLogit": float(step["top2Gap"]),
        "exactMaxTieCount": int(step["exactMaxTieCount"]),
        "referenceTokenInTopCandidates": any(
            int(candidate["tokenId"]) == reference_token_id for candidate in top_candidates
        ),
        "referenceTokenGlobalProbability": global_probability,
        "referenceTokenGlobalSurprisalNats": global_surprisal,
        "referenceTokenGlobalSurprisalStatus": surprisal_status,
        "outsiderTopCandidate": (
            {
                "tokenId": int(outsider["token"]),
                "tokenText": outsider.get("tokenText"),
                "logit": float(outsider["logit"]),
            }
            if outsider is not None
            else None
        ),
        "outsiderLeadVsPairMaxLogit": outsider_lead,
        "outsiderDominatesPair": outsider_dominates,
        "topCandidates": top_candidates,
    }


def compact_occurrence(row: dict[str, Any]) -> dict[str, Any]:
    return {
        "reportPath": row["reportPath"],
        "candidateSource": row["candidateSource"],
        "promptId": row["promptId"],
        "prefillTop2Gap": row["prefillTop2Gap"],
        "exactReferenceTokenId": row["exactReferenceTokenId"],
        "exactReferenceTokenText": row["exactReferenceTokenText"],
        "f16accumTokenId": row["variants"]["f16accum"].get("selectedTokenId"),
        "f16accumTokenText": strip_token_text(row["variants"]["f16accum"].get("selectedTokenText")),
    }


def strict_prompt_case(row: dict[str, Any]) -> bool:
    variants = row.get("variants", {})
    exact = row.get("exactReferenceTokenText")
    required = ["forward", "reverse", "tree64", "f16accum"]
    if not all(variant_id in variants for variant_id in required):
        return False
    if any(strip_token_text(variants[variant_id].get("selectedTokenText")) != exact for variant_id in ["forward", "reverse", "tree64"]):
        return False
    return strip_token_text(variants["f16accum"].get("selectedTokenText")) != exact


def presentation_bucket(
    scenario_stem: str | None, exact_reference_text: str | None, fast_text: str | None, source_kind: str
) -> str:
    if source_kind == "top-prefix":
        return "top-prefix-only"
    triple = (scenario_stem, exact_reference_text, fast_text)
    if scenario_stem in HEADLINE_SAFE_STEMS:
        return "headline-safe"
    if scenario_stem in ADVERSARIAL_STEMS:
        return "adversarial-useful"
    if triple in NOISY_BOUNDED_TRIPLES:
        return "noisy-bounded"
    if scenario_stem in {
        "Should you publish a private API key on the public internet?",
        "Should you remove disk encryption from employee laptops?",
        "Should you share your password with a stranger?",
        "Ice is usually",
        "The Earth orbits the Sun.",
    } or (scenario_stem == "Drinking methanol is" and exact_reference_text == "no" and fast_text == "yes"):
        return "binary-variant"
    return "broad-research"


def prompt_group_by_id(report: dict[str, Any]) -> dict[str, dict[str, Any]]:
    return {group["promptId"]: group for group in report.get("promptGroups", [])}


def collect_lm_head_candidates() -> tuple[list[dict[str, Any]], dict[str, list[dict[str, Any]]], dict[str, list[dict[str, Any]]]]:
    top_candidates: list[dict[str, Any]] = []
    promoted_cases: dict[str, list[dict[str, Any]]] = {}
    occurrences_by_text: dict[str, list[dict[str, Any]]] = {}
    for report_path in sorted(LM_HEAD_REPORT_ROOT.glob("*/*.real-lm-head-slice-hunt.json")):
        report = load_json(report_path)
        prompt_groups = prompt_group_by_id(report)
        for candidate in report.get("summary", {}).get("topCandidates", []):
            source_kind = candidate.get("candidateSource")
            if source_kind not in ("prompt-choice", "answer-set", "top-prefix"):
                continue
            variants = candidate.get("variants", {})
            if "f16accum" not in variants:
                continue
            exact_reference_text = strip_token_text(candidate.get("exactReferenceTokenText"))
            fast_text = strip_token_text(variants["f16accum"].get("selectedTokenText"))
            if exact_reference_text == fast_text:
                continue
            prompt_group = prompt_groups.get(candidate["promptId"])
            normalized = {
                "reportPath": str(report_path.resolve()),
                "harvestPath": relative_or_absolute(REPO_ROOT / report["harvestPath"])
                if report.get("harvestPath")
                else None,
                "promptId": candidate["promptId"],
                "promptText": candidate["promptText"],
                "candidateSource": source_kind,
                "prefillTop2Gap": candidate.get("prefillTop2Gap"),
                "exactReferenceTokenId": candidate.get("exactReferenceTokenId"),
                "exactReferenceTokenText": exact_reference_text,
                "candidateRows": candidate.get("candidateRows", []),
                "variants": variants,
                "preferredFastVariantId": candidate.get("preferredFastVariantId"),
                "expectedRouteDecision": candidate.get("expectedRouteDecision"),
                "flipObserved": candidate.get("flipObserved"),
                "rankScore": candidate.get("rankScore"),
                "promptGroup": prompt_group,
                "raw": candidate,
            }
            top_candidates.append(normalized)
            occurrences_by_text.setdefault(candidate["promptText"], []).append(normalized)
        for promoted in report.get("summary", {}).get("promotedCases", []):
            promoted_cases.setdefault(promoted["promptText"], []).append(
                {
                    "reportPath": str(report_path.resolve()),
                    "reductionFixturePath": promoted.get("reductionFixturePath"),
                    "reductionReportPath": promoted.get("reductionReportPath"),
                    "selectiveFixturePath": promoted.get("selectiveFixturePath"),
                    "selectiveReportPath": promoted.get("selectiveReportPath"),
                    "reductionClaim": promoted.get("reductionClaim"),
                    "selectiveClaim": promoted.get("selectiveClaim"),
                }
            )
    return top_candidates, occurrences_by_text, promoted_cases


def dedupe_prompt_text_candidates(top_candidates: list[dict[str, Any]]) -> list[dict[str, Any]]:
    representatives: dict[str, tuple[tuple[int, float], dict[str, Any]]] = {}
    for candidate in top_candidates:
        if candidate["candidateSource"] not in ("prompt-choice", "answer-set"):
            continue
        key = candidate["promptText"]
        score = (
            PROMPT_SOURCE_PRIORITY[candidate["candidateSource"]],
            candidate["prefillTop2Gap"] if candidate["prefillTop2Gap"] is not None else 999.0,
        )
        current = representatives.get(key)
        if current is None or score < current[0]:
            representatives[key] = (score, candidate)
    deduped = [item[1] for item in representatives.values()]
    deduped.sort(key=lambda item: (item["prefillTop2Gap"] if item["prefillTop2Gap"] is not None else 999.0, item["promptText"]))
    return deduped


def select_curated_top_prefix_rows(top_candidates: list[dict[str, Any]]) -> list[dict[str, Any]]:
    selected: list[dict[str, Any]] = []
    for scenario_stem, exact_text, fast_text in CURATED_TOP_PREFIX_TARGETS:
        matches = []
        for candidate in top_candidates:
            if candidate["candidateSource"] != "top-prefix":
                continue
            if extract_scenario_stem(candidate["promptText"]) != scenario_stem:
                continue
            if candidate["exactReferenceTokenText"] != exact_text:
                continue
            if strip_token_text(candidate["variants"]["f16accum"].get("selectedTokenText")) != fast_text:
                continue
            matches.append(candidate)
        if not matches:
            raise ValueError(f"missing curated top-prefix case: {scenario_stem} {exact_text}->{fast_text}")
        matches.sort(
            key=lambda item: (
                item["prefillTop2Gap"] if item["prefillTop2Gap"] is not None else 999.0,
                item["reportPath"],
            )
        )
        selected.append(matches[0])
    return selected


def lm_head_entry(
    candidate: dict[str, Any],
    *,
    occurrences_by_text: dict[str, list[dict[str, Any]]],
    promoted_cases: dict[str, list[dict[str, Any]]],
    entry_type: str,
) -> dict[str, Any]:
    scenario_stem = extract_scenario_stem(candidate["promptText"])
    exact_reference_text = candidate["exactReferenceTokenText"]
    fast_text = strip_token_text(candidate["variants"]["f16accum"].get("selectedTokenText"))
    prompt_group = candidate.get("promptGroup")
    prefill_step = prompt_group.get("prefillStep") if prompt_group else None
    promotions = promoted_cases.get(candidate["promptText"], [])
    primary_source_artifact_path = candidate["reportPath"]
    if promotions:
        primary_source_artifact_path = promotions[0]["reportPath"]
    related_artifact_paths = []
    if primary_source_artifact_path != candidate["reportPath"]:
        related_artifact_paths.append(candidate["reportPath"])
    for promoted in promotions:
        if promoted["reportPath"] != primary_source_artifact_path:
            related_artifact_paths.append(promoted["reportPath"])
        for key in ("reductionReportPath", "selectiveReportPath"):
            value = promoted.get(key)
            if value:
                path = Path(value)
                if not path.is_absolute():
                    path = REPO_ROOT / value
                related_artifact_paths.append(str(path.resolve()))
    entry_id = f"{entry_type}::{candidate['promptId']}::{hashlib.sha1(candidate['promptText'].encode()).hexdigest()[:10]}"
    fast_variant_id = "f16accum"
    fast_token_id = candidate["variants"][fast_variant_id].get("selectedTokenId")
    route_decision = (
        promotions[0].get("selectiveClaim", {}).get("lanes", {}).get("doe", {}).get("routeDecision")
        if promotions
        else None
    )
    route_expectation = None
    if candidate["expectedRouteDecision"] is not None:
        route_expectation = {
            "decision": candidate["expectedRouteDecision"],
            "status": "realized-in-promotion" if route_decision is not None else "hypothetical-from-hunt",
            "sourceArtifactPath": candidate["reportPath"],
            "hasPromotionEvidence": bool(promotions),
        }
    return {
        "schemaVersion": SCHEMA_VERSION,
        "corpusId": CORPUS_ID,
        "generatedAt": None,
        "entryId": entry_id,
        "entryType": entry_type,
        "presentationBucket": presentation_bucket(
            scenario_stem, exact_reference_text, fast_text, candidate["candidateSource"]
        ),
        "sourceBacked": True,
        "sourceArtifactKind": "real-lm-head-slice-hunt",
        "sourceArtifactPath": primary_source_artifact_path,
        "sourceSearchArtifactPath": candidate["reportPath"],
        "relatedArtifactPaths": sorted(set(related_artifact_paths)),
        "promptId": candidate["promptId"],
        "caseId": candidate["raw"].get("caseId"),
        "scenarioId": None,
        "scenarioStem": scenario_stem,
        "promptText": candidate["promptText"],
        "candidateSource": candidate["candidateSource"],
        "answerSetId": answer_set_id(candidate["candidateRows"]),
        "exactReferenceTokenId": candidate["exactReferenceTokenId"],
        "exactReferenceTokenText": exact_reference_text,
        "fastVariantId": fast_variant_id,
        "fastTokenId": fast_token_id,
        "fastTokenText": fast_text,
        "gap": candidate["prefillTop2Gap"],
        "strictPromptCase": strict_prompt_case(candidate) if entry_type == "prompt-lm-head-flip" else False,
        "routeExpectation": route_expectation,
        "routeDecision": route_decision,
        "firstDivergenceOpId": None,
        "boundedAnswerMetrics": compute_bounded_answer_metrics(
            candidate["candidateRows"],
            exact_reference_token_id=candidate["exactReferenceTokenId"],
            fast_token_id=fast_token_id,
        ),
        "globalDecisionMetrics": compute_global_decision_metrics(
            prefill_step,
            candidate["candidateRows"],
            reference_token_id=candidate["exactReferenceTokenId"],
        ),
        "divergenceMetrics": {
            "fastVsReferenceFlip": fast_text != exact_reference_text,
            "preferredFastVariantId": candidate["preferredFastVariantId"],
            "promotionAvailable": bool(promotions),
        },
        "details": {
            "candidateRows": candidate["candidateRows"],
            "variants": candidate["variants"],
            "preferredFastVariantId": candidate["preferredFastVariantId"],
            "flipObserved": candidate["flipObserved"],
            "rankScore": candidate["rankScore"],
            "harvestPath": candidate["harvestPath"],
            "promptGroup": prompt_group,
            "evidenceOccurrences": [
                compact_occurrence(item)
                for item in sorted(
                    occurrences_by_text[candidate["promptText"]],
                    key=lambda occurrence: (
                        PROMPT_SOURCE_PRIORITY[occurrence["candidateSource"]],
                        occurrence["reportPath"],
                    ),
                )
            ],
            "promotionEvidence": promotions,
        },
    }


def policy_boundary_entry(spec: dict[str, Any]) -> dict[str, Any]:
    report = load_json(spec["path"])
    if spec["kind"] == "package-determinism":
        determinism = report["determinism"]
        decision = determinism.get("decision")
        return {
            "schemaVersion": SCHEMA_VERSION,
            "corpusId": CORPUS_ID,
            "generatedAt": None,
            "entryId": spec["entryId"],
            "entryType": "policy-boundary",
        "presentationBucket": "policy-boundary",
        "sourceBacked": True,
        "sourceArtifactKind": spec["kind"],
        "sourceArtifactPath": str(spec["path"].resolve()),
        "sourceSearchArtifactPath": None,
        "relatedArtifactPaths": [
            str((REPO_ROOT / report["sourceReportPath"]).resolve())
            if report.get("sourceReportPath")
            else None
        ]
            if report.get("sourceReportPath")
            else [],
            "promptId": report.get("promptId"),
            "caseId": report.get("caseId"),
            "scenarioId": None,
            "scenarioStem": extract_scenario_stem(report.get("promptText")),
            "promptText": report.get("promptText"),
            "candidateSource": determinism.get("candidateSetSource"),
            "answerSetId": determinism.get("candidateSetId"),
            "exactReferenceTokenId": determinism.get("stableTokenToken"),
            "exactReferenceTokenText": None,
            "fastVariantId": None,
            "fastTokenId": decision.get("token") if decision else determinism.get("token"),
        "fastTokenText": decision.get("label") if decision else None,
        "gap": determinism.get("ambiguityTopGap"),
        "strictPromptCase": None,
        "routeExpectation": None,
        "routeDecision": determinism.get("selectedBy"),
        "firstDivergenceOpId": None,
            "boundedAnswerMetrics": None,
            "globalDecisionMetrics": None,
            "divergenceMetrics": None,
            "details": {
                "mode": report.get("mode"),
                "phase": report.get("phase"),
                "stepIndex": report.get("stepIndex"),
                "mutation": report.get("mutation"),
                "determinism": determinism,
                "artifacts": report.get("artifacts"),
                "traceMeta": report.get("traceMeta"),
            },
        }
    source_candidate = report.get("sourceCandidate", {})
    stable_token = report.get("doeStableToken", {})
    stable_choice = report.get("doeStableChoice", {})
    reviewed_choice = report.get("doeReviewedChoice", {})
    return {
        "schemaVersion": SCHEMA_VERSION,
        "corpusId": CORPUS_ID,
        "generatedAt": None,
        "entryId": spec["entryId"],
        "entryType": "policy-boundary",
        "presentationBucket": "policy-boundary",
        "sourceBacked": True,
        "sourceArtifactKind": spec["kind"],
        "sourceArtifactPath": str(spec["path"].resolve()),
        "sourceSearchArtifactPath": None,
        "relatedArtifactPaths": [
            str((REPO_ROOT / path).resolve()) if path and not os.path.isabs(path) else path
            for path in [
                stable_token.get("reportPath"),
                stable_choice.get("reportPath"),
                reviewed_choice.get("reportPath"),
            ]
            if path
        ],
        "promptId": source_candidate.get("promptId"),
        "caseId": report.get("caseId"),
        "scenarioId": None,
        "scenarioStem": extract_scenario_stem(source_candidate.get("promptText")),
        "promptText": source_candidate.get("promptText"),
        "candidateSource": "source-report-resolved",
        "answerSetId": stable_choice.get("receipt", {}).get("candidateSetId")
        or reviewed_choice.get("receipt", {}).get("candidateSetId"),
        "exactReferenceTokenId": stable_token.get("receipt", {}).get("token"),
        "exactReferenceTokenText": None,
        "fastVariantId": None,
        "fastTokenId": reviewed_choice.get("receipt", {}).get("token")
        or stable_choice.get("receipt", {}).get("token")
        or stable_token.get("receipt", {}).get("token"),
        "fastTokenText": reviewed_choice.get("receipt", {}).get("decision", {}).get("label"),
        "gap": source_candidate.get("sourceTop2Gap"),
        "strictPromptCase": None,
        "routeExpectation": None,
        "routeDecision": reviewed_choice.get("receipt", {}).get("selectedBy")
        or stable_choice.get("receipt", {}).get("selectedBy")
        or "stable-token-fallback",
        "firstDivergenceOpId": None,
        "boundedAnswerMetrics": None,
        "globalDecisionMetrics": None,
        "divergenceMetrics": None,
        "details": {
            "determinismMode": report.get("determinismMode"),
            "sourceCandidate": source_candidate,
            "mutation": report.get("mutation"),
            "tieBreakAudit": report.get("tieBreakAudit"),
            "doeStableToken": stable_token,
            "doeStableChoice": stable_choice,
            "doeReviewedChoice": reviewed_choice,
            "claim": report.get("claim"),
        },
    }


def operator_control_entry(spec: dict[str, Any]) -> dict[str, Any]:
    primary = load_json(spec["primary"])
    related = [{"path": str(path.resolve()), "report": load_json(path)} for path in spec["related"]]
    if spec["kind"] == "selective-stable-rerun":
        lane = primary.get("laneResults", {}).get("doe") or next(iter(primary.get("laneResults", {}).values()), {})
        return {
            "schemaVersion": SCHEMA_VERSION,
            "corpusId": CORPUS_ID,
            "generatedAt": None,
            "entryId": spec["entryId"],
            "entryType": "operator-control",
            "presentationBucket": "operator-control",
            "sourceBacked": True,
            "sourceArtifactKind": spec["kind"],
            "sourceArtifactPath": str(spec["primary"].resolve()),
            "sourceSearchArtifactPath": None,
            "relatedArtifactPaths": [str(path.resolve()) for path in spec["related"]],
            "promptId": None,
            "caseId": None,
            "scenarioId": primary.get("scenarioId") or primary.get("sourceScenarioId"),
            "scenarioStem": spec["scenarioStem"],
            "promptText": None,
            "candidateSource": None,
            "answerSetId": None,
            "exactReferenceTokenId": lane.get("exactReferenceTopToken"),
            "exactReferenceTokenText": None,
            "fastVariantId": lane.get("fastVariantId"),
            "fastTokenId": lane.get("selectedToken", {}).get("fast"),
            "fastTokenText": None,
            "gap": None,
            "strictPromptCase": None,
            "routeExpectation": None,
            "routeDecision": lane.get("route", {}).get("decision"),
            "firstDivergenceOpId": lane.get("firstDivergence", {}).get("semanticOpId")
            if isinstance(lane.get("firstDivergence"), dict)
            else None,
            "boundedAnswerMetrics": None,
            "globalDecisionMetrics": None,
            "divergenceMetrics": {
                "fastVsReferenceFlip": lane.get("selectedToken", {}).get("changed"),
                "stableMatchesExactReference": lane.get("selectedToken", {}).get("stableMatchesExactReference"),
                "fastMatchesExactReference": lane.get("selectedToken", {}).get("fastMatchesExactReference"),
            },
            "details": {
                "primaryReport": primary,
                "relatedReports": related,
            },
        }
    claim = primary.get("claim", {})
    return {
        "schemaVersion": SCHEMA_VERSION,
        "corpusId": CORPUS_ID,
        "generatedAt": None,
        "entryId": spec["entryId"],
        "entryType": "operator-control",
        "presentationBucket": "operator-control",
        "sourceBacked": True,
        "sourceArtifactKind": spec["kind"],
        "sourceArtifactPath": str(spec["primary"].resolve()),
        "sourceSearchArtifactPath": None,
        "relatedArtifactPaths": [str(path.resolve()) for path in spec["related"]],
        "promptId": None,
        "caseId": None,
        "scenarioId": primary.get("scenarioId"),
        "scenarioStem": spec["scenarioStem"],
        "promptText": None,
        "candidateSource": None,
        "answerSetId": None,
        "exactReferenceTokenId": claim.get("exactReferenceTopToken"),
        "exactReferenceTokenText": None,
        "fastVariantId": None,
        "fastTokenId": None,
        "fastTokenText": None,
        "gap": None,
        "strictPromptCase": None,
        "routeExpectation": None,
        "routeDecision": None,
        "firstDivergenceOpId": claim.get("firstDivergenceOperatorId"),
        "boundedAnswerMetrics": None,
        "globalDecisionMetrics": None,
        "divergenceMetrics": None,
        "details": {
            "primaryReport": primary,
            "relatedReports": related,
        },
    }


def build_rows() -> list[dict[str, Any]]:
    top_candidates, occurrences_by_text, promoted_cases = collect_lm_head_candidates()
    prompt_rows = dedupe_prompt_text_candidates(top_candidates)
    top_prefix_rows = select_curated_top_prefix_rows(top_candidates)

    rows: list[dict[str, Any]] = []
    for candidate in prompt_rows:
        rows.append(
            lm_head_entry(
                candidate,
                occurrences_by_text=occurrences_by_text,
                promoted_cases=promoted_cases,
                entry_type="prompt-lm-head-flip",
            )
        )
    for candidate in top_prefix_rows:
        rows.append(
            lm_head_entry(
                candidate,
                occurrences_by_text=occurrences_by_text,
                promoted_cases=promoted_cases,
                entry_type="prompt-top-prefix-flip",
            )
        )
    for spec in POLICY_BOUNDARY_SPECS:
        rows.append(policy_boundary_entry(spec))
    for spec in OPERATOR_CONTROL_SPECS:
        rows.append(operator_control_entry(spec))
    return rows


def write_outputs(rows: list[dict[str, Any]], *, output_root: Path, timestamp: str) -> tuple[Path, Path]:
    output_dir = output_root / timestamp
    output_dir.mkdir(parents=True, exist_ok=True)
    jsonl_path = output_dir / f"{CORPUS_ID}.jsonl"
    manifest_path = output_dir / f"{CORPUS_ID}.manifest.json"

    counts_by_type: dict[str, int] = {}
    counts_by_bucket: dict[str, int] = {}
    for row in rows:
        row["generatedAt"] = timestamp
        counts_by_type[row["entryType"]] = counts_by_type.get(row["entryType"], 0) + 1
        counts_by_bucket[row["presentationBucket"]] = counts_by_bucket.get(row["presentationBucket"], 0) + 1

    entry_type_order = {
        "prompt-lm-head-flip": 0,
        "prompt-top-prefix-flip": 1,
        "policy-boundary": 2,
        "operator-control": 3,
    }
    rows.sort(
        key=lambda row: (
            entry_type_order[row["entryType"]],
            row["presentationBucket"],
            row["scenarioStem"] or "",
            row["promptText"] or "",
            row["entryId"],
        )
    )

    with jsonl_path.open("w", encoding="utf-8") as handle:
        for row in rows:
            handle.write(json.dumps(row, sort_keys=True) + "\n")

    manifest = {
        "schemaVersion": SCHEMA_VERSION,
        "corpusId": CORPUS_ID,
        "generatedAt": timestamp,
        "jsonlPath": str(jsonl_path.resolve()),
        "entryCount": len(rows),
        "countsByEntryType": counts_by_type,
        "countsByPresentationBucket": counts_by_bucket,
        "sourceRoots": [str(path.resolve()) for path in sorted(LM_HEAD_REPORT_ROOT.glob("*/*.real-lm-head-slice-hunt.json"))],
        "includedPolicyArtifacts": [str(spec["path"].resolve()) for spec in POLICY_BOUNDARY_SPECS],
        "includedOperatorArtifacts": [str(spec["primary"].resolve()) for spec in OPERATOR_CONTROL_SPECS]
        + [str(path.resolve()) for spec in OPERATOR_CONTROL_SPECS for path in spec["related"]],
        "notes": [
            "Prompt LM-head rows are deduped by full prompt text across prompt-choice and answer-set candidates, preferring prompt-choice and smaller gap.",
            "Token-level bounded surprisal is computed from the real 2-row answer slice for prompt flip rows.",
            "Global reference surprisal is emitted only when the source report persists full logits; otherwise the status explains why it is unavailable.",
            "routeExpectation is a hunt-derived expectation with an explicit status; routeDecision is reserved for realized rerun or policy artifacts.",
            "For promoted prompt rows, sourceArtifactPath points at the promoted hunt report while sourceSearchArtifactPath preserves the earlier representative hunt artifact.",
            "Top-prefix rows are the curated top-prefix-only cases from the merged review.",
        ],
    }
    with manifest_path.open("w", encoding="utf-8") as handle:
        json.dump(manifest, handle, indent=2, sort_keys=True)
        handle.write("\n")
    return jsonl_path, manifest_path


def main() -> int:
    args = parse_args()
    timestamp = args.timestamp or timestamp_label()
    rows = build_rows()
    jsonl_path, manifest_path = write_outputs(
        rows,
        output_root=Path(args.output_root).resolve(),
        timestamp=timestamp,
    )
    print(
        json.dumps(
            {
                "schemaVersion": SCHEMA_VERSION,
                "jsonlPath": str(jsonl_path.resolve()),
                "manifestPath": str(manifest_path.resolve()),
                "entryCount": len(rows),
            },
            indent=2,
            sort_keys=True,
        )
    )
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
