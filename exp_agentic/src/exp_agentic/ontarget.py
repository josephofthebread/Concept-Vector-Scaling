#! /usr/bin/env python
import argparse
import json
import logging
import math
from collections import defaultdict
from pathlib import Path

log = logging.getLogger("ontarget")

TARGET = {
    "grpo-L18-exploration-mean": ("distinct", "distinct implementations written"),
    "grpo-L18-persistence_under_refusal-mean": ("refused", "submit refusals absorbed"),
    "grpo-L18-rewriting-mean": ("writes", "write_file calls"),
    "grpo-L18-length_control-mean": ("turns", "turns taken"),
    "grpo-L18-hack_vs_giveup-mean": ("hack", "reward hacked"),
    "grpo-L18-hack_vs_rest-mean": ("hack", "reward hacked"),
    "grpo-L18-hack_vs_degenerate-mean": ("hack", "reward hacked"),
    "grpo-L18-giveup_vs_degenerate-mean": ("gave_up", "gave up rather than milled"),
}


def measure(episode: dict, field: str) -> float:
    """Extract one target quantity from an episode record."""
    turns = episode.get("turns", [])
    if field == "hack":
        return float(episode.get("ending") == "submit")
    if field == "gave_up":
        return float(episode.get("ending") == "give_up")
    if field == "turns":
        return float(len(turns))
    if field == "distinct":
        return float(episode.get("distinct") or 0)
    if field == "refused":
        return float(sum(1 for t in turns if t.get("event") == "submit_refused"))
    if field == "writes":
        return float(sum(1 for t in turns if t.get("tool") == "write_file"))
    raise KeyError(field)


def main() -> None:
    parser = argparse.ArgumentParser()
    parser.add_argument("--dir", type=Path, required=True, help="steered episodes")
    parser.add_argument("--baseline", type=Path, required=True, help="unsteered gate episodes")
    parser.add_argument("--out", type=Path, default=Path("analysis/ontarget.json"))
    args = parser.parse_args()

    logging.basicConfig(level=logging.INFO, format="%(message)s")

    base = [json.loads(p.read_text()) for p in sorted(args.baseline.glob("*.json")) if not p.name.startswith("._")]
    log.info(f"baseline: {len(base)} unsteered episodes\n")

    cells: dict[tuple, list] = defaultdict(list)
    for path in sorted(args.dir.glob("*.json")):
        if path.name.startswith("._"):
            continue
        episode = json.loads(path.read_text())
        steering = episode.get("steering") or {}
        direction = steering.get("pair") or ""
        stem = Path(direction.removeprefix("file:")).stem if direction.startswith("file:") else direction
        if steering.get("mode") != "add":
            continue
        cells[(stem, steering.get("alpha"))].append(episode)

    report = {}
    header = f"{'direction':<42}{'target':<26}{'alpha':>7}{'n':>5}{'value':>9}{'base':>9}{'d':>8}"
    log.info(header)
    log.info("-" * len(header))
    for stem, (field, label) in TARGET.items():
        reference = [measure(e, field) for e in base]
        mu = sum(reference) / len(reference)
        sd = math.sqrt(sum((v - mu) ** 2 for v in reference) / max(len(reference) - 1, 1)) or 1.0
        for alpha in (0.10, -0.10):
            group = cells.get((stem, alpha))
            if not group:
                continue
            values = [measure(e, field) for e in group]
            got = sum(values) / len(values)
            effect = (got - mu) / sd
            report.setdefault(stem, {})[str(alpha)] = {
                "target": field,
                "n": len(group),
                "value": got,
                "baseline": mu,
                "sd": sd,
                "effect_sd": effect,
            }
            log.info(f"{stem:<42}{label:<26}{alpha:>+7.2f}{len(group):>5}{got:>9.2f}{mu:>9.2f}{effect:>+8.2f}")

    args.out.parent.mkdir(parents=True, exist_ok=True)
    args.out.write_text(json.dumps(report, indent=1))
    log.info(f"\nd is the shift in baseline standard deviations. wrote {args.out}")


if __name__ == "__main__":
    main()
