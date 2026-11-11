#!/usr/bin/env python3
"""Score a running RAHBAR against a golden set, and gate CI on the result (section 5).

    python eval/run_eval.py --api http://<ingress>                 # your corpus
    python eval/run_eval.py --api ... --golden eval/fixtures/golden.fixture.yaml
    python eval/run_eval.py --api ... --update-baseline            # after a deliberate improvement

Exit code 0 when every gate passes, 1 when any fails. CI relies on that exit code.

Given: talking to the API, reading the golden set, writing results.json, the exit
code. Yours: the four core evaluation functions implemented below.
"""

from __future__ import annotations

import argparse
import json
import sys
import time
from pathlib import Path

import httpx
import yaml

HERE = Path(__file__).resolve().parent

# The gate from section 5.4. Change these only with a reason written in docs/PIPELINE.md.
MAX_RECALL5_DROP = 0.05        # recall@5 may fall at most 5 points below the baseline
MIN_CITATION_VALIDITY = 0.95   # at least 95% of citations must match retrieved passages
REQUIRED_ABSTENTION = 1.0      # every must-abstain question must be declined


def load_golden(path: Path) -> list[dict]:
    data = yaml.safe_load(path.read_text(encoding="utf-8")) or {}
    questions = data.get("questions") or []
    if not questions:
        sys.exit(f"no questions in {path}")
    return questions


def ask(client: httpx.Client, api: str, question: str) -> dict:
    """POST one question and return the AskResponse as a dict (see api/app/schemas.py)."""
    response = client.post(f"{api.rstrip('/')}/api/ask", json={"question": question})
    response.raise_for_status()
    return response.json()


def recall_at_k(relevant: list[dict], retrieved: list[dict], k: int) -> float | None:
    """Fraction of the relevant (source, section) pairs found in the top k retrieved.
    Return None when the question has no relevant passages (must-abstain questions)."""
    if not relevant:
        return None
    top_k_retrieved = retrieved[:k]

    def _normalize(s: str) -> str:
        return "".join(c.lower() for c in s if c.isalnum() or c.isspace()).strip()

    hits = 0
    for rel in relevant:
        rel_src = rel.get("source", "").strip().lower()
        rel_sec = _normalize(rel.get("section", ""))
        matched = False
        for ret in top_k_retrieved:
            ret_src = ret.get("source", "").strip().lower()
            ret_sec = _normalize(ret.get("section", ""))
            # Check source match and section prefix/equality
            if rel_src == ret_src:
                if not rel_sec or rel_sec in ret_sec or ret_sec in rel_sec:
                    matched = True
                    break
        if matched:
            hits += 1

    return hits / len(relevant)


def citation_validity(response: dict) -> float | None:
    """Fraction of the response's citations that match a passage in response['retrieved'].
    Return None when there are no citations."""
    citations = response.get("citations") or []
    if not citations:
        return None
    retrieved = response.get("retrieved") or []
    if not retrieved:
        return 0.0

    def _normalize(s: str) -> str:
        return "".join(c.lower() for c in s if c.isalnum() or c.isspace()).strip()

    valid = 0
    for c in citations:
        c_src = c.get("source", "").strip().lower()
        c_sec = _normalize(c.get("section", ""))
        matched = False
        for r in retrieved:
            r_src = r.get("source", "").strip().lower()
            r_sec = _normalize(r.get("section", ""))
            if c_src == r_src and (not c_sec or c_sec in r_sec or r_sec in c_sec):
                matched = True
                break
        if matched:
            valid += 1
    return valid / len(citations)


def summarise(rows: list[dict]) -> dict:
    """Overall recall@3, recall@5, citation validity and abstention correctness, plus
    recall@5 broken down by question type. This dict becomes results.json."""
    recall3_scores: list[float] = []
    recall5_scores: list[float] = []
    citation_scores: list[float] = []
    abstention_correct = 0
    abstention_total = 0
    recall5_by_type: dict[str, list[float]] = {}

    for row in rows:
        q_type = row.get("type", "ordinary")
        must_abstain = row.get("must_abstain", False)
        relevant = row.get("relevant") or []
        resp = row.get("response") or {}
        retrieved = resp.get("retrieved") or []

        r3 = recall_at_k(relevant, retrieved, 3)
        r5 = recall_at_k(relevant, retrieved, 5)

        if r3 is not None:
            recall3_scores.append(r3)
        if r5 is not None:
            recall5_scores.append(r5)
            recall5_by_type.setdefault(q_type, []).append(r5)

        cv = citation_validity(resp)
        if cv is not None:
            citation_scores.append(cv)

        if must_abstain:
            abstention_total += 1
            # Honest abstention: answered_from_context must be False
            if not resp.get("answered_from_context", True):
                abstention_correct += 1

    mean_r3 = sum(recall3_scores) / len(recall3_scores) if recall3_scores else 0.0
    mean_r5 = sum(recall5_scores) / len(recall5_scores) if recall5_scores else 0.0
    mean_cv = sum(citation_scores) / len(citation_scores) if citation_scores else 1.0
    abstention_rate = abstention_correct / abstention_total if abstention_total else 1.0

    by_type_summary = {
        t: round(sum(scores) / len(scores), 4) for t, scores in recall5_by_type.items() if scores
    }

    return {
        "recall_at_3": round(mean_r3, 4),
        "recall_at_5": round(mean_r5, 4),
        "citation_validity": round(mean_cv, 4),
        "abstention_correctness": round(abstention_rate, 4),
        "recall_at_5_by_type": by_type_summary,
    }


def gate(results: dict, baseline: dict | None) -> list[str]:
    """Return one message per failed gate (section 5.4); an empty list means pass."""
    failures: list[str] = []

    r5 = results.get("recall_at_5", 0.0)
    cv = results.get("citation_validity", 0.0)
    abstain = results.get("abstention_correctness", 0.0)

    if cv < MIN_CITATION_VALIDITY:
        failures.append(
            f"citation_validity {cv:.2f} is below minimum required {MIN_CITATION_VALIDITY:.2f}"
        )

    if abstain < REQUIRED_ABSTENTION:
        failures.append(
            f"abstention_correctness {abstain:.2f} is below required {REQUIRED_ABSTENTION:.2f}"
        )

    if baseline is not None:
        base_r5 = baseline.get("recall_at_5", 0.0)
        allowed_floor = base_r5 - MAX_RECALL5_DROP
        if r5 < allowed_floor:
            failures.append(
                f"recall_at_5 {r5:.4f} dropped more than {MAX_RECALL5_DROP} below baseline {base_r5:.4f}"
            )

    return failures


def main() -> int:
    parser = argparse.ArgumentParser(description="Evaluate RAHBAR against a golden set.")
    parser.add_argument("--api", required=True, help="base URL, e.g. http://192.168.49.2")
    parser.add_argument("--host", help="Host header, when your Ingress rule names a host")
    parser.add_argument("--golden", type=Path, default=HERE / "golden.yaml")
    parser.add_argument("--baseline", type=Path, default=HERE / "baseline.json")
    parser.add_argument("--out", type=Path, default=HERE / "results.json")
    parser.add_argument("--update-baseline", action="store_true",
                        help="write these results as the new baseline")
    args = parser.parse_args()

    questions = load_golden(args.golden)
    rows = []
    headers = {"Host": args.host} if args.host else {}
    with httpx.Client(timeout=120.0, headers=headers) as client:
        for q in questions:
            started = time.perf_counter()
            response = ask(client, args.api, q["question"])
            rows.append({
                "id": q["id"], "type": q.get("type", "ordinary"),
                "must_abstain": bool(q.get("must_abstain", False)),
                "relevant": q.get("relevant") or [],
                "expect": q.get("expect"),
                "response": response,
                "seconds": round(time.perf_counter() - started, 2),
            })
            print(f"  {q['id']:<5} {rows[-1]['seconds']:>6.2f}s  {q['question'][:60]}")

    try:
        results = summarise(rows)
        baseline = json.loads(args.baseline.read_text()) if args.baseline.exists() else None
        failures = gate(results, baseline)
    except NotImplementedError as exc:
        print(f"\nnot implemented yet: {exc}")
        return 2

    results["golden"] = str(args.golden)
    results["questions"] = len(rows)
    args.out.write_text(json.dumps(results, indent=2), encoding="utf-8")
    print(f"\nresults written to {args.out}")
    if args.update_baseline:
        args.baseline.write_text(json.dumps(results, indent=2), encoding="utf-8")
        print(f"baseline updated: {args.baseline}")

    if failures:
        print("\nGATE FAILED")
        for message in failures:
            print(f"  - {message}")
        return 1
    print("\ngate passed")
    return 0


if __name__ == "__main__":
    sys.exit(main())
