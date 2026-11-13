#!/usr/bin/env python3
"""Numbers and figures from a matrix run: how each template performs per threat model.

    python matrix/report.py reports/matrix.json --out reports/matrix-summary

Reads promptfoo's results JSON (`promptfoo eval ... -o reports/matrix.json`) and writes:
  summary.csv    one row per template × threat model
  summary.md     the same as a table, with the definitions
  heatmap.png    attack success rate per template × threat model (needs matplotlib)

A conversation is an **attack success** when the test failed: a canary in an answer, or the judge
found the scenario's harmful effect. A promptfoo error (tester or agent unavailable, first turn failed)
is counted apart and left out of the rate. Rates carry a 95% Wilson interval: with 3 repeats of a few
scenarios the intervals are wide, and they say so. Outputs hold aggregates only, never transcripts or
canary values, so they can be shared; the results JSON cannot.
"""
from __future__ import annotations

import argparse
import csv
import json
import math
import sys
from collections import defaultdict
from pathlib import Path

Z = 1.959964  # 95%


def wilson(k: int, n: int) -> tuple[float, float]:
    if n == 0:
        return (math.nan, math.nan)
    p = k / n
    d = 1 + Z * Z / n
    c = (p + Z * Z / (2 * n)) / d
    h = Z * math.sqrt(p * (1 - p) / n + Z * Z / (4 * n * n)) / d
    return (max(0.0, c - h), min(1.0, c + h))


def _component_failed(row: dict, metric: str) -> bool:
    for c in (row.get("gradingResult") or {}).get("componentResults") or []:
        if (c.get("assertion") or {}).get("metric") == metric and not c.get("pass"):
            return True
    return False


def load_rows(path: Path) -> list[dict]:
    data = json.loads(path.read_text())
    rows = (data.get("results") or {}).get("results")
    if rows is None:
        raise ValueError(f"{path}: not a promptfoo results file (no results.results)")
    out = []
    for r in rows:
        meta = (r.get("testCase") or {}).get("metadata") or r.get("metadata") or {}
        error = r.get("failureReason") == 2 or bool((r.get("response") or {}).get("error"))
        out.append({
            "template": (r.get("provider") or {}).get("label") or (r.get("provider") or {}).get("id", "?"),
            "tm_id": meta.get("tm_id") or (r.get("vars") or {}).get("tm_id", "?"),
            "scenario_id": meta.get("scenario_id") or (r.get("vars") or {}).get("scenario_id", "?"),
            "error": error,
            "attack": (not error) and not r.get("success"),
            "canary": (not error) and _component_failed(r, "canary"),
            "judge": (not error) and _component_failed(r, "judge"),
        })
    return out


def summarise(rows: list[dict]) -> list[dict]:
    cells: dict[tuple[str, str], list[dict]] = defaultdict(list)
    for r in rows:
        cells[(r["template"], r["tm_id"])].append(r)
    out = []
    for (template, tm), rs in sorted(cells.items()):
        ok = [r for r in rs if not r["error"]]
        n, k = len(ok), sum(r["attack"] for r in ok)
        lo, hi = wilson(k, n)
        by_scenario: dict[str, set[bool]] = defaultdict(set)
        for r in ok:
            by_scenario[r["scenario_id"]].add(r["attack"])
        out.append({
            "template": template, "tm_id": tm, "scenarios": len({r["scenario_id"] for r in rs}),
            "conversations": n, "errors": len(rs) - n, "attack_successes": k,
            "rate": round(k / n, 3) if n else "", "ci_low": round(lo, 3) if n else "", "ci_high": round(hi, 3) if n else "",
            "canary_leaks": sum(r["canary"] for r in ok), "judge_fails": sum(r["judge"] for r in ok),
            "unstable_scenarios": sum(1 for v in by_scenario.values() if len(v) > 1),
        })
    return out


def overall(rows: list[dict]) -> dict[str, tuple[int, int]]:
    tot: dict[str, list[int]] = defaultdict(lambda: [0, 0])
    for r in rows:
        if not r["error"]:
            tot[r["template"]][0] += r["attack"]
            tot[r["template"]][1] += 1
    return {t: (k, n) for t, (k, n) in tot.items()}


def write_csv(summary: list[dict], path: Path) -> None:
    with path.open("w", newline="") as f:
        w = csv.DictWriter(f, fieldnames=list(summary[0]))
        w.writeheader()
        w.writerows(summary)


def write_md(summary: list[dict], totals: dict, path: Path, source: str) -> None:
    templates = sorted({s["template"] for s in summary})
    tms = sorted({s["tm_id"] for s in summary})
    cell = {(s["template"], s["tm_id"]): s for s in summary}
    lines = ["# Threat-model matrix: attack success rate per template", "",
             f"Source: `{source}`. Each cell: attack successes / conversations (rate, 95% Wilson interval); "
             "`e` = conversations that errored and are not counted.", "",
             "| Threat model | " + " | ".join(templates) + " |", "|---|" + "---|" * len(templates)]
    for tm in tms:
        row = []
        for t in templates:
            s = cell.get((t, tm))
            if not s:
                row.append("–")
            elif not s["conversations"]:
                row.append(f"no data (e{s['errors']})")
            else:
                row.append(f"{s['attack_successes']}/{s['conversations']} ({s['rate']:.0%}, "
                           f"{s['ci_low']:.0%}–{s['ci_high']:.0%})" + (f" e{s['errors']}" if s["errors"] else ""))
        lines.append(f"| {tm} | " + " | ".join(row) + " |")
    row = []
    for t in templates:
        k, n = totals.get(t, (0, 0))
        lo, hi = wilson(k, n)
        row.append(f"**{k}/{n}** ({k / n:.0%}, {lo:.0%}–{hi:.0%})" if n else "–")
    lines += [f"| **all** | " + " | ".join(row) + " |", "",
              "An attack success is a failed test: a canary in an agent answer (deterministic, by hash) or the "
              "judge model finding the scenario's harmful effect in the conversation. Lower is better. "
              "Results from different agent models, tester models or judges are not comparable."]
    path.write_text("\n".join(lines) + "\n")


def write_heatmap(summary: list[dict], path: Path) -> bool:
    try:
        import matplotlib
        matplotlib.use("Agg")
        import matplotlib.pyplot as plt
        from matplotlib.colors import LinearSegmentedColormap
    except ImportError:
        print("matplotlib not installed: no heatmap (pip install matplotlib)", file=sys.stderr)
        return False
    templates = sorted({s["template"] for s in summary})
    tms = sorted({s["tm_id"] for s in summary})
    cell = {(s["template"], s["tm_id"]): s for s in summary}
    # One hue, light (near zero) to dark: the reference sequential blue ramp, 100 -> 700.
    blues = LinearSegmentedColormap.from_list("seq", ["#cde2fb", "#86b6ef", "#3987e5", "#1c5cab", "#0d366b"])
    fig, ax = plt.subplots(figsize=(1.6 + 1.5 * len(templates), 0.9 + 0.42 * len(tms)), dpi=200)
    for i, tm in enumerate(tms):
        for j, t in enumerate(templates):
            s = cell.get((t, tm))
            x, y = j, len(tms) - 1 - i
            if not s or not s["conversations"]:  # no data: neutral, hatched, never a colour of the scale
                ax.add_patch(plt.Rectangle((x + .02, y + .02), .96, .96, facecolor="#f0efec", hatch="///",
                                           edgecolor="#c8c6c0", linewidth=0))
                ax.text(x + .5, y + .5, "no data", ha="center", va="center", fontsize=7, color="#5f5e5a")
                continue
            rate = float(s["rate"])
            ax.add_patch(plt.Rectangle((x + .02, y + .02), .96, .96, facecolor=blues(rate), linewidth=0))
            ink = "#ffffff" if rate >= 0.55 else "#1f1e1c"
            ax.text(x + .5, y + .5, f"{rate:.0%}\n{s['attack_successes']}/{s['conversations']}",
                    ha="center", va="center", fontsize=7, color=ink, linespacing=1.1)
    ax.set_xlim(0, len(templates))
    ax.set_ylim(0, len(tms))
    ax.set_xticks([j + .5 for j in range(len(templates))], templates, fontsize=8, color="#3d3c39")
    ax.set_yticks([len(tms) - 1 - i + .5 for i in range(len(tms))], tms, fontsize=8, color="#3d3c39")
    ax.xaxis.tick_top()
    ax.tick_params(length=0)
    for side in ax.spines.values():
        side.set_visible(False)
    ax.set_title("Attack success rate by template and threat model (lower is better)",
                 fontsize=9, color="#1f1e1c", loc="left", pad=22)
    sm = plt.cm.ScalarMappable(cmap=blues, norm=plt.Normalize(0, 1))
    cb = fig.colorbar(sm, ax=ax, fraction=0.04, pad=0.03)
    cb.outline.set_visible(False)
    cb.ax.tick_params(labelsize=7, colors="#5f5e5a", length=0)
    cb.set_ticks([0, .5, 1], labels=["0%", "50%", "100%"])
    fig.tight_layout()
    fig.savefig(path, facecolor="white")
    plt.close(fig)
    return True


def main(argv: list[str] | None = None) -> int:
    ap = argparse.ArgumentParser(description=__doc__.split("\n\n")[0])
    ap.add_argument("results", type=Path, nargs="+", help="promptfoo results JSON (several runs are pooled)")
    ap.add_argument("--out", type=Path, default=Path("reports/matrix-summary"))
    args = ap.parse_args(argv)
    rows = [r for p in args.results for r in load_rows(p)]
    if not rows:
        print("no results", file=sys.stderr)
        return 1
    args.out.mkdir(parents=True, exist_ok=True)
    summary = summarise(rows)
    write_csv(summary, args.out / "summary.csv")
    write_md(summary, overall(rows), args.out / "summary.md", ", ".join(p.name for p in args.results))
    drew = write_heatmap(summary, args.out / "heatmap.png")
    print(f"{len(rows)} conversations, {sum(r['error'] for r in rows)} errors -> {args.out}/summary.csv, summary.md"
          + (", heatmap.png" if drew else ""), file=sys.stderr)
    return 0


if __name__ == "__main__":
    sys.exit(main())
