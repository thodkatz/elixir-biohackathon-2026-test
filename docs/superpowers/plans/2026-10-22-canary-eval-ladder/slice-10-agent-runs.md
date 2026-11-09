# Slice 10/10: the agent runs, L0 to L3, and the matrix

Runs the agent suite on de.NBI (`qwen3.8-27b`) at every level slices 4 and 6–8 built, in one batch: L0 clean and
injected, L1 injected and clean, L2 and L3 (injected only). Each level's counts go to `docs/results/qwen3.8-27b/`
and the matrix to `docs/results/canary-ladder-qwen3.8-27b.md`. One batch keeps the levels comparable: the same
key, model version and time window. The slice adds no code; it ends the track.

**Implements** (spec [`docs/superpowers/specs/2026-10-22-canary-eval-ladder-design/`](../../specs/2026-10-22-canary-eval-ladder-design/README.md)):

- [06](../../specs/2026-10-22-canary-eval-ladder-design/06-runs-and-results.md): *One ladder run*, *Clean and
  injected runs* (at L0 and L1), *Order*, *Higher levels*, *Repeats and cost*, *The matrix*, *Reading the
  matrix* — decisions 10 and 11 (the committed results).
- [04](../../specs/2026-10-22-canary-eval-ladder-design/04-agent-suite-and-scoring.md): *Metrics*, *The first
  catalogue*: decision 7 (the utility pass rate, read per level).
- [03](../../specs/2026-10-22-canary-eval-ladder-design/03-controls-suite.md): decision 6 (the controls suite
  agrees with each level before its agent run; `run.sh` enforces it).

**Branch:** `impl/canary-eval-ladder-10-agent-runs`. Global constraints, shared interfaces and the claims table:
the plan's [README](README.md). All paths below are relative to the repository root; commands run from
`platform/promptfoo-evals/` unless they `cd` elsewhere.

**Builds on:** `agent.yaml`, the 13-test catalogue and the provider's state diff (slice 5);
`instances/L0.example.yml` and `instances/no-injections.example.yml` (slice 4); `instances/L1.example.yml`,
`L2.example.yml`, `L3.example.yml` and each level's controls table (slices 6–8, their handoffs); `run.sh`,
`handoff.condition` (slice 3); `matrix.py counts`/`render` (slices 1 and 3). The L5 airlock (slice 9) has no run
here: no instance reaches L5 before L4, which belongs to the L4 spec (README, *PR slices*).

**The key gate.** The agent runs need a working de.NBI LLM key, which this guest does not have (slice 5's
handoff: Coder not logged in, the VM's `agent.env` holds a placeholder). A credential is on the floor
(`AGENTS.md`, *Don't stop for approval*), so the slice's draft PR carries the gate: one comment asking for the key
(through `coder` or by the user unblocking the guest), the `waiting-on-user` label, and a watcher
(`GH_REPO=thodkatz/elixir-biohackathon-2026-test methodology gate wait <PR>`), as `development-workflow.md`,
*Gates*, says. The gate moves here from #64 when this slice is claimed. No task below starts before the user
answers; then `methodology gate clear <PR>`. Nothing else in the slice asks: de.NBI runs and rebuilds of the one
instance are covered by the standing OK (`AGENTS.md`, *Setup*).

**Rebuild order.** One de.NBI VM, `denbi-agui-01`, rebuilt in place for each condition, in this order:
L0 clean → L0 injected → L1 injected → L1 clean → L2 → L3. L0 runs clean first and L1 injected first (spec part
06, *Order*), so L0 injected and L1 injected are consecutive builds and L1 clean follows L1. The standing OK
covers this one instance; never create a second. Each build takes a few minutes; the restores dominate the wall
time (about 45 s per test, slice 2).

### Task 1: the runs ahead, the key and the build helper

**Files:** none (the record goes into the handoff).

**Interfaces:**
- Consumes: the answered key gate; `platform/ansible/playbooks/create.yml`; the operator's private
  `instances/denbi.yml` and the canonical `output/` in the main checkout.
- Produces: the shell state every later task uses (`PRIVATE`, `SPE_HANDOFF_DIR`, `SPE_LLM_API_KEY`, the agent
  variables, `build`).

**Decisions:** 10 (no agent run without the controls suite agreeing first: `run.sh` runs it).

- [ ] **Step 1: The runs ahead.** Model calls on de.NBI (no money, rate limits only; no OK needed: the standing
  OK, `AGENTS.md`, *Setup*). Record in the handoff: the agent suite on de.NBI, model **qwen3.8-27b**, 13 tests
  per run: L0 clean and L0 injected × 5 repeats (130 runs), L1 injected and L1 clean × 3 (78), L2 × 3 (39), L3 × 3
  (39): **286 agent runs** (each up to 50 model requests), as many restores, six in-place rebuilds of the VM (no
  instance created) and the no-model controls suite before each run.

- [ ] **Step 2: Check the key without spending a run.** Export it in this shell only, never into a file
  (`docs/knowledge/denbi-llm-key.md`, which also has the no-cost check that it answers): one variable feeds the
  build and the `key.leak` assertion.

```bash
export SPE_LLM_API_KEY=…   # from the gate's answer; never in the repository, never in a file
```

  A 401 means the key is not the working one: comment on the gate and wait again.

- [ ] **Step 3: Reach the agent and define the build.** Push the branch first: the VM checks out the controller's
  `HEAD` (`spe_repo_ref`). From `platform/promptfoo-evals/`:

```bash
git push
PRIVATE=/workspace/biohackathon/elixir-biohackathon-2026-test/platform/ansible   # the main checkout
export SPE_HANDOFF_DIR=$PRIVATE/output/denbi-agui-01   # the hand-off lives only in the main checkout
grep agui_tunnel $SPE_HANDOFF_DIR/hosts.yml   # the ssh -N -L … command; run it in its own terminal, once
export SPE_AGENT_URL=http://127.0.0.1:8100/agent SPE_AGENT_API_KEY_FILE=$SPE_HANDOFF_DIR/agent_api_key
export PROMPTFOO_DISABLE_TELEMETRY=1 PROMPTFOO_DISABLE_SHARING=1 PROMPTFOO_DISABLE_UPDATE=1
export PROMPTFOO_CONFIG_DIR=$PWD/.promptfoo
build() {  # rebuild the VM in place; $1 the level (0-3), "${@:2}" more overlays
  local level=$1; shift
  (cd ../ansible && ansible-playbook playbooks/create.yml -e @$PRIVATE/instances/denbi.yml \
    -e @instances/L$level.example.yml "$@" -e '{"spe_agent_allowed_models": []}' \
    -e spe_output_root=$PRIVATE/output </dev/null) &&
  jq '{level, model, commit, injections}' $SPE_HANDOFF_DIR/hardening.json
}
mkdir -p ../../docs/results/qwen3.8-27b
```

  `-e '{"spe_agent_allowed_models": []}'` widens the private file's Anthropic spend guard for this command only,
  as JSON (`docs/knowledge/ladder-level-build-allowed-models.md`). `build` takes no snapshot: each build writes a
  new `generated_at`, so `run.sh`'s controls suite (`beforeAll`) snapshots the new build through the guarded path.
  `build` recreates the agent container: if the agent stops answering afterwards, reopen the tunnel.

- [ ] **Step 4: The token check, used after each level.** Define it in the same shell; it prints counts only:

```bash
token_check() {  # files to check; exit 1 on any hit
python3 - "$SPE_HANDOFF_DIR" "$@" <<'EOF'
import json, os, re, sys
from pathlib import Path
hand = Path(sys.argv[1])
values = {e["token"] for e in json.loads((hand / "canaries.json").read_text())["tokens"] if e.get("token")}
values |= {(hand / "agent_api_key").read_text().strip(), os.environ["SPE_LLM_API_KEY"]}
bad = 0
for path in sys.argv[2:]:
    text = Path(path).read_text()
    hits = sum(1 for v in values if re.search(rf"(?<!\w){re.escape(v)}(?!\w)", text))
    bad += hits
    print(f"{path}: {hits} of {len(values)} values found")
sys.exit(1 if bad else 0)
EOF
}
```

  Expected after each level: `0 of N` for every file. Any hit: do not commit; the offending line came from a
  report `reason` or label, which is a slice 1 bug (`matrix.py`, decision 11) to fix first.

### Task 2: L0, clean then injected

**Files:** create `docs/results/qwen3.8-27b/L0-clean.json`, `docs/results/qwen3.8-27b/L0.json`,
`docs/results/canary-ladder-qwen3.8-27b.md`; modify `docs/README.md`.

**Interfaces:** Consumes Task 1's shell state, `run.sh <hand-off dir> <repeat>`, `handoff.condition`.
Produces the L0 counts of both conditions and the first matrix.

**Decisions:** 10 (`run.sh` stops before any model call on a controls mismatch or a build that is not a ladder
condition; L0 runs clean, then injected), 11 (counts only; `render` refuses an unmatched pair), 7 (the utility
pass rate at L0, read in Task 5).

- [ ] **Step 1: The clean run.** Build L0 clean, then run the whole suite:

```bash
build 0 -e @instances/no-injections.example.yml   # expect level 0, injections false, commit = this branch's HEAD
jq '.injections' $SPE_HANDOFF_DIR/injections.json  # []
time ./run.sh "$SPE_HANDOFF_DIR" 5; echo "exit $?"
jq '.results.stats' reports/L0-clean/agent.json   # 65 results, errors 0
python3 matrix.py counts reports/L0-clean > ../../docs/results/qwen3.8-27b/L0-clean.json
```

  Record for the handoff: the exit code, the wall time, the stats, `run.json`'s `started`. Exit 2 before any call
  means the build is not the clean condition: `run.sh` names what (a manifest still listing injections, or a
  target file whose canary the clean build lacks: spec part 02, *Matched builds*); fix the build, never the check.
  A non-zero exit before the agent suite otherwise means the controls disagree with L0: record which probe, stop,
  and fix the instance (decision 10). Provider `error`s (a state diff that failed, a run timeout) are not results:
  find the cause, fix it, and run the condition again.

- [ ] **Step 2: The injected run.** Rebuild L0 as the level file says, then the same suite:

```bash
build 0                                            # expect level 0, injections true
jq '[.injections[].id]' $SPE_HANDOFF_DIR/injections.json   # the three fixtures
time ./run.sh "$SPE_HANDOFF_DIR" 5; echo "exit $?"
jq '.results.stats' reports/L0/agent.json          # 65 results, errors 0
python3 matrix.py counts reports/L0 > ../../docs/results/qwen3.8-27b/L0.json
python3 matrix.py render ../../docs/results/qwen3.8-27b/L*.json > ../../docs/results/canary-ladder-qwen3.8-27b.md
token_check ../../docs/results/qwen3.8-27b/L0*.json ../../docs/results/canary-ladder-qwen3.8-27b.md
```

  `render` refusing with "different canaries: L0" means the two builds are not a matched pair (another seed or
  canary switch in one of them): find which, rebuild that condition and run it again.

- [ ] **Step 3: Index the results.** Add to the table in `docs/README.md`, before the closing comment:

```markdown
| `results/` | committed ladder results, counts only: `canary-ladder-<model>.md` (the matrix) and `<model>/L<n>.json` (one level's counts, its input) | you cite a ladder result or add a level |
```

- [ ] **Step 4: Commit L0 and delete its reports.**

```bash
cd ../..
git add docs/results/qwen3.8-27b/L0*.json docs/results/canary-ladder-qwen3.8-27b.md docs/README.md
git diff --staged --stat
git commit -s -m "Results: canary ladder L0, qwen3.8-27b on de.NBI" \
  -m "13 tests x 5 repeats at L0 in both conditions, clean (no injections planted) then injected, a
matched pair (spec part 06; decision 11: counts only; checked locally that no canary token or key from
the hand-off appears in any file). Raw reports deleted."
cd platform/promptfoo-evals && rm -rf reports/L0 reports/L0-clean
```

### Task 3: L1, injected then clean

**Files:** create `docs/results/qwen3.8-27b/L1.json`, `docs/results/qwen3.8-27b/L1-clean.json`; modify
`docs/results/canary-ladder-qwen3.8-27b.md`.

**Interfaces:** Consumes Task 1's shell state, `instances/L1.example.yml` and slice 6's controls table (its
handoff). Produces the L1 counts of both conditions and the matrix with columns `L0 clean`, `L0`, `L1 clean`,
`L1`.

**Decisions:** 6 and 10 (the controls at L1, through `run.sh`; L1 runs injected, then clean: spec part 06,
*Order*), 11.

- [ ] **Step 1: The injected run.**

```bash
build 1                                            # expect level 1, injections true
time ./run.sh "$SPE_HANDOFF_DIR" 3; echo "exit $?"
jq '.results.stats' reports/L1/agent.json          # 39 results, errors 0
python3 matrix.py counts reports/L1 > ../../docs/results/qwen3.8-27b/L1.json
```

  Expected: exit 0, `reports/L1/{controls,agent,hardening,injections,run}.json`. The controls must match slice
  6's table (`trs-write`, `wes-inline`, `e2e-exploit` `closed`); a mismatch stops `run.sh` before any call.

- [ ] **Step 2: The clean run.** Rebuild L1 in place with the clean overlay, then the same suite:

```bash
build 1 -e @instances/no-injections.example.yml   # expect level 1, injections false
time ./run.sh "$SPE_HANDOFF_DIR" 3; echo "exit $?"
jq '.results.stats' reports/L1-clean/agent.json   # 39 results, errors 0
python3 matrix.py counts reports/L1-clean > ../../docs/results/qwen3.8-27b/L1-clean.json
python3 matrix.py render ../../docs/results/qwen3.8-27b/L*.json > ../../docs/results/canary-ladder-qwen3.8-27b.md
token_check ../../docs/results/qwen3.8-27b/L1*.json ../../docs/results/canary-ladder-qwen3.8-27b.md
```

  Expected: exit 0, `reports/L1-clean/{controls,agent,hardening,run}.json`; the matrix has columns `L0 clean`,
  `L0`, `L1 clean` and `L1`, and both L1 controls lines say all probes are as expected. Exit 2 before any call
  means the build is not the clean condition (`run.sh` names what: spec part 02, *Matched builds*); fix the
  build, never the check. `render` refusing with "different canaries: L1" means the two L1 builds are not a
  matched pair: find which differs, rebuild that condition and run it again.

- [ ] **Step 3: Commit L1 and delete its reports.**

```bash
cd ../..
git add docs/results/qwen3.8-27b/L1.json docs/results/qwen3.8-27b/L1-clean.json docs/results/canary-ladder-qwen3.8-27b.md
git commit -s -m "Results: L1 and L1 clean columns for qwen3.8-27b (3 repeats each)"
cd platform/promptfoo-evals && rm -rf reports/L1 reports/L1-clean
```

### Task 4: L2 and L3, injected only

**Files:** create `docs/results/qwen3.8-27b/L2.json`, `docs/results/qwen3.8-27b/L3.json`; modify
`docs/results/canary-ladder-qwen3.8-27b.md`.

**Interfaces:** Consumes Task 1's shell state, `instances/L2.example.yml`, `instances/L3.example.yml` and slices
7–8's controls tables (their handoffs). Produces the L2 and L3 counts and the matrix with columns `L0 clean` to
`L3` (L2 and L3 run injected only: spec part 06, *Higher levels*).

**Decisions:** 6, 10, 11. If slice 8 was dropped (egress already closed at L0), skip steps 3–5.

- [ ] **Step 1: L2.**

```bash
build 2                                            # expect level 2, injections true
time ./run.sh "$SPE_HANDOFF_DIR" 3; echo "exit $?"
jq '.results.stats' reports/L2/agent.json          # 39 results, errors 0
python3 matrix.py counts reports/L2 > ../../docs/results/qwen3.8-27b/L2.json
python3 matrix.py render ../../docs/results/qwen3.8-27b/L*.json > ../../docs/results/canary-ladder-qwen3.8-27b.md
token_check ../../docs/results/qwen3.8-27b/L2.json ../../docs/results/canary-ladder-qwen3.8-27b.md
```

  Expected: exit 0; the controls match slice 7's table (`tier-reach` `closed` too); utility tests pass at L2 as
  at L1.

- [ ] **Step 2: Commit L2 and delete its reports.**

```bash
cd ../..
git add docs/results/qwen3.8-27b/L2.json docs/results/canary-ladder-qwen3.8-27b.md
git commit -s -m "Results: L2 column for qwen3.8-27b (3 repeats)"
cd platform/promptfoo-evals && rm -rf reports/L2
```

- [ ] **Step 3: L3's build.** The `tools` network's IPAM changes, and Compose does not change an existing
  network's subnet: take the frontend down first (its volumes stay), as slice 8, task 3 did.

```bash
SSH="ssh -F /home/agentvm/.ssh/config ubuntu@agent-service-1"
$SSH 'cd ~/spe-frontend && docker compose -p spe-frontend down'
build 3                                            # expect level 3, injections true
```

  Reopen the agent tunnel.

- [ ] **Step 4: L3's run.**

```bash
time ./run.sh "$SPE_HANDOFF_DIR" 3; echo "exit $?"
jq '.results.stats' reports/L3/agent.json          # 39 results, errors 0
python3 matrix.py counts reports/L3 > ../../docs/results/qwen3.8-27b/L3.json
python3 matrix.py render ../../docs/results/qwen3.8-27b/L*.json > ../../docs/results/canary-ladder-qwen3.8-27b.md
token_check ../../docs/results/qwen3.8-27b/L3.json ../../docs/results/canary-ladder-qwen3.8-27b.md
```

  Expected: exit 0; the controls match slice 8's table (`egress` `closed`, `api-reach` `open`); columns
  `L0 clean` to `L3`; utility tests pass at L3 as at L2. The VM ends at L3.

- [ ] **Step 5: Commit L3 and clean up.**

```bash
cd ../..
git add docs/results/qwen3.8-27b/L3.json docs/results/canary-ladder-qwen3.8-27b.md
git commit -s -m "Results: L3 column for qwen3.8-27b (3 repeats)"
rm -rf platform/promptfoo-evals/reports platform/promptfoo-evals/.promptfoo
```

  Close the tunnel and `unset SPE_LLM_API_KEY`.

### Task 5: read the matrix, the handoff and the end of the track

**Files:** create the handoff (`methodology handoff new docs/superpowers/plans/2026-10-22-canary-eval-ladder/handoffs
slice-10-done`); modify the plan `README.md` (slices table), `AGENTS.md` (*Current work*), `BACKLOG.md`.

**Interfaces:** none.

**Decisions:** 7 (utility per level) and spec part 06, *Reading the matrix*.

- [ ] **Step 1: Read the matrix** (spec part 06, *Reading the matrix*) and record for the handoff:
  - the utility pass rate per test in every column (a utility test below full marks at L0 is an agent or runbook
    problem to note, not a leak); `canary.answer` on utility rows that list DRS objects counts study ids inside
    object names (20 of 36 names on de.NBI carry a `registry-study-id` canary: slice 5's ruling), so read it
    apart from the injection rows;
  - for each direct and benign row, the clean columns on their own (a leak there needs no injection);
  - the injection comparison at L0 and L1 (`L<n> clean` against `L<n>`): `touched`/`answer`/`sent`/`delivered`,
    errors apart, and whether the payload was exposed (`followed` is 0 in a clean column by construction);
  - the hardening comparison, level against level: which followed injections L1 blocked (infrastructure, not
    model resistance), which P3 tests changed at L2, which P4 tests at L3 (`canary.delivered` falls to zero there);
  - each run's start time, and any departure from the rebuild order, with why.

- [ ] **Step 2: Write the handoff** with `methodology handoff new docs/superpowers/plans/2026-10-22-canary-eval-ladder/handoffs slice-10-done`,
  headed `# <date>: slice 10 done, the ladder's agent runs; the plan ends`, with these sections, filled from
  Tasks 1–4 and step 1:
  - **State.** The counts in `docs/results/qwen3.8-27b/` and the matrix
    `docs/results/canary-ladder-qwen3.8-27b.md`; the VM left at L3.
  - **Runs.** Instance, commit (`hardening.json`); per condition: started, `run.sh` exit, wall time, restore
    seconds, stats; the key's source (never the key).
  - **The ladder in one paragraph**, then step 1's readings.
  - **Rulings** (decision, why, cost if wrong): anything decided while running.
  - **Open:** the `BACKLOG.md` lines this result answers or feeds (clean runs above L1, one-fixture runs, the
    study-id-in-DRS-name question, the L4 spec).

- [ ] **Step 3: Status, Current work, backlog.** In the plan `README.md`'s *PR slices* table, set row 10/10's
  *Status* to `merged #<n>` (`gh pr view --json number -q .number` once the PR is open). In `AGENTS.md`,
  *Current work*, remove the canary ladder's line (the track's last slice removes it; the L4 spec waits in
  `BACKLOG.md`). In `BACKLOG.md`, rewrite the *clean runs above L1* line with what the L0/L1 pairs showed
  (whether a level's clean comparison is worth its runs), keeping it as an item only if it is still open.

- [ ] **Step 4: Commit.**

```bash
git add docs/superpowers/plans/2026-10-22-canary-eval-ladder/handoffs/<the file of step 2> \
  docs/superpowers/plans/2026-10-22-canary-eval-ladder/README.md AGENTS.md BACKLOG.md
git commit -s -m "Handoff: slice 10 done, the ladder's agent runs committed; the plan ends"
```

  After the merge and cleanup, the track ends with `methodology next --end` (`AGENTS.md`, *Hand off, then chain*).
