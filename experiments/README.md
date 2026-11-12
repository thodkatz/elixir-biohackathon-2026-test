# Experiments

An experiment is one Coder preset of the `spe-experiments` template: a threat and the path it takes,
measured with no mitigation (the baseline arm) against one mitigation under test, built from the
threats, paths and mitigations catalogued in `../threats/`, `../paths/` and `../mitigations/`. Each
file here is `<name>.yml`, checked by `../validate.py`, and offered by name in the template's
`experiment` parameter (`../platform/coder/experiments-template/`).

Index, one line per file:

| File | Threat | Paths | Mitigation under test |
|---|---|---|---|
| `ladder-l0.yml` | TM-001 | P1, P2, P3, P4 | none (baseline only) |
| `ladder-l1.yml` | TM-001 | P2 | `trs-read-only`: TRS read-only |
| `ladder-l2.yml` | TM-001 | P3 | `data-tiers`: Data tiers (on top of `trs-read-only`) |
| `ladder-l3.yml` | TM-001 | P4 | `egress-allowlist`: Egress (on top of `trs-read-only`, `data-tiers`) |

The ladder (`ladder-l0`..`ladder-l3`) is the first set of experiments, the hardening ladder's levels
read as a path through the threat model; `ladder-l0` is the template's default preset. A new
experiment file needs a line added here.

## Running one

Build a `spe-experiments` workspace with the preset named above (`../platform/coder/README.md`), then run
`spe-eval` in it: `../platform/instance/workspace/AGENTS.md`, *Experiments*, has every command (`new`, `test`,
`arm`, `run`, `status`, `wait`, `runs`, `results`, `pr-body`), its success output, and where results land.

## Adding one

`spe-eval new <name>` writes a skeleton; fill it in, check it with `check_experiment.py <name>` until it exits
0, and add a line for it to the index above. `../CONTRIBUTING.md` is the full path, for a person; the same
steps, for a coding agent, are `../platform/instance/workspace/AGENTS.md`'s *Experiments* section.
