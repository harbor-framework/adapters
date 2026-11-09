"""Upstream-compatible zero-shot extraction and original aggregation metrics."""

from __future__ import annotations

from collections import defaultdict
from typing import Any

try:
    from .upstream_parser import extract_option_content, extract_option_labels
except ImportError:  # Copied into /tests as a standalone verifier module.
    from upstream_parser import extract_option_content, extract_option_labels


def score_response(record: dict[str, Any], response: str) -> dict[str, Any]:
    if not isinstance(response, str):
        raise TypeError(
            "Model response must be text; infrastructure failures are not answers"
        )
    # Keep upstream's A-J parsing, fallback and case behavior verbatim.
    predict = extract_option_labels(response, "ABCDEFGHIJ")
    if predict is None:
        predict = extract_option_content(response, record["options"])
        predict = chr(record["options"].index(predict) + 65) if predict else None
    return {
        "uuid": record["uuid"],
        "extracted_answer": predict,
        "reward": int(bool(predict) and record["answer_letter"] == predict),
        "status": "correct"
        if record["answer_letter"] == predict
        else (
            "miss"
            if predict is None or predict == ""
            else "error"
            if predict == "error"
            else "incorrect"
        ),
    }


def aggregate(
    records: list[dict[str, Any]], scores: list[dict[str, Any]]
) -> dict[str, Any]:
    """Match upstream's micro, taxonomy-macro and difficulty accuracies."""
    by_id = {row["uuid"]: row for row in records}
    score_ids = [score["uuid"] for score in scores]
    if (
        len(by_id) != len(records)
        or len(set(score_ids)) != len(scores)
        or set(score_ids) != set(by_id)
    ):
        raise ValueError("Scores must cover every selected UUID exactly once")
    if not records:
        raise ValueError("Cannot aggregate an empty dataset")
    dimensions: dict[str, dict[tuple[str, ...], list[int]]] = {
        name: defaultdict(list)
        for name in ("discipline", "field", "subfield", "difficulty")
    }
    rewards = []
    for score in scores:
        reward = score["reward"]
        if reward not in (0, 1):
            raise ValueError("SuperGPQA reward must be 0 or 1")
        row = by_id[score["uuid"]]
        rewards.append(reward)
        for dimension, key in (
            ("discipline", (row["discipline"],)),
            ("field", (row["discipline"], row["field"])),
            ("subfield", (row["discipline"], row["field"], row["subfield"])),
            ("difficulty", (row["difficulty"],)),
        ):
            dimensions[dimension][key].append(reward)
    result: dict[str, Any] = {
        "sample_accuracy": sum(rewards) / len(rewards),
        "count": len(rewards),
    }
    for name in ("discipline", "field", "subfield"):
        values = [sum(group) / len(group) for group in dimensions[name].values()]
        result[f"{name}_accuracy"] = sum(values) / len(values)
    result["difficulty_accuracy"] = {
        key[0]: sum(values) / len(values)
        for key, values in dimensions["difficulty"].items()
    }
    return result
