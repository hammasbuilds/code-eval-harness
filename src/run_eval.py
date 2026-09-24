"""Generate solutions once per (model, problem), then score them under every strategy.

Writes results/scores.json. Generation is cached on disk, so re-running to add a new
extraction strategy costs no model time at all.
"""

from __future__ import annotations

import json
import sys
from pathlib import Path

sys.path.insert(0, str(Path(__file__).resolve().parent))

from core import STRATEGIES, generate, load_problems, run_tests

RESULTS = Path(__file__).resolve().parent.parent / "results"
# The two 14B models, because those are what anyone actually deploys. A 3B was in here
# as a convenience and it made the comparison weaker: a toy model's output is not
# evidence about how an extraction rule behaves on the output people really parse.
MODELS = ["qwen2.5-coder:14b", "qwen2.5:14b-instruct"]


def main(limit: int = 50, models: list[str] | None = None) -> None:
    models = models or MODELS
    problems = load_problems(limit)
    RESULTS.mkdir(exist_ok=True)
    print(f"problems: {len(problems)}   models: {', '.join(models)}")

    records = []
    for model in models:
        for i, problem in enumerate(problems, 1):
            try:
                output = generate(model, problem)
            except Exception as exc:  # noqa: BLE001 - a dead model should not lose the run
                print(f"  [{model}] {problem.task_id} generation failed: {type(exc).__name__}")
                continue

            row = {"model": model, "task_id": problem.task_id, "chars": len(output)}
            for name, strategy in STRATEGIES.items():
                ok, detail = run_tests(strategy(problem.prompt, output), problem)
                row[name] = ok
                row[f"{name}__why"] = detail
            records.append(row)
            marks = "".join("P" if row[s] else "." for s in STRATEGIES)
            print(f"  [{model:20}] {i:3}/{len(problems)} {problem.task_id:18} {marks}")

    # A run where nothing generated is not a run with a low score, it is a run that did not
    # happen - a stopped Ollama, a model that was never pulled, a name misspelled on the
    # command line. Continuing past a single dead generation is right; writing a results
    # file and exiting 0 after losing every one of them is not, because the next thing to
    # read scores.json cannot tell the difference between "the model is bad" and "the model
    # was never reached". This exact case produced 492 skipped generations, an empty table
    # and exit code 0.
    if not records:
        raise SystemExit(
            f"every generation failed for {', '.join(models)} - nothing was scored.\n"
            "Check that ollama is running and each model name is pulled: ollama list"
        )
    expected = len(models) * len(problems)
    if len(records) < expected:
        print(f"\n  WARNING: {expected - len(records)} of {expected} generations failed")

    RESULTS.joinpath("scores.json").write_text(
        json.dumps({"models": models, "n_problems": len(problems), "records": records}, indent=2),
        encoding="utf-8",
    )

    print(f"\n{'model':22} " + "  ".join(f"{s:>12}" for s in STRATEGIES))
    print("-" * (22 + 14 * len(STRATEGIES)))
    for model in models:
        rows = [r for r in records if r["model"] == model]
        if not rows:
            continue
        cells = "  ".join(f"{sum(r[s] for r in rows) / len(rows):>11.1%}" for s in STRATEGIES)
        print(f"{model:22} {cells}")

    # The headline: same generations, different harness, different answer.
    for model in models:
        rows = [r for r in records if r["model"] == model]
        if not rows:
            continue
        rates = {s: sum(r[s] for r in rows) / len(rows) for s in STRATEGIES}
        best, worst = max(rates.values()), min(rates.values())
        print(
            f"\n{model}: best {best:.1%} vs worst {worst:.1%} -> "
            f"spread of {best - worst:.1%} from extraction alone "
            f"({len(rows)} problems, identical generations)"
        )


if __name__ == "__main__":
    n = int(sys.argv[1]) if len(sys.argv) > 1 else 40
    # A second positional: a comma-separated model list. The extraction rules only differ
    # on output that is not a clean fenced block, and the coder model almost always emits
    # one - so on its records `first_fence`, `all_fences` and `smart` agree everywhere and
    # the comparison between rules has nothing to compare. The instruct model of the same
    # size is the useful contrast: it explains itself, and that prose is what a rule has
    # to survive.
    picked = sys.argv[2].split(",") if len(sys.argv) > 2 else None
    main(n, picked)
