"""`spe-eval`'s core library (experiments spec part 03, `docs/specs/2026-11-10-experiments-design/`):
experiments, arms, the suite config, run ids, the lock and reading past runs. Standard library
plus PyYAML only (the VM has `python3-yaml`); the only repository imports are `validate` (repo
root), `injections_schema` and `matrix` (`platform/promptfoo-evals/`), all read-only siblings of
the same clone, not new dependencies -- always imported from this script's own location (never
`SPE_REPO_DIR`), so `matrix.CATALOGUE` is always this checkout's real catalogue, whichever repo
`SPE_REPO_DIR` points the rest of `spe-eval` at.

Used by the `spe-eval` CLI (`platform/instance/spe-eval`) and, for the lock, by `spe-apply` (in
bash, mirroring `Lock`'s file format):

    - `load_experiment`, `default_experiment_name`, `load_local_vars`, `check_build_matches`:
      decision 7, which experiment a bare `spe-eval` command means and whether it still matches
      this build.
    - `experiment_arms`, `arm_mitigations`, `arm_vars`, `write_json`: decision 9, the `-e` values
      for one arm, as the JSON file `spe-apply ... -e @<path>` passes.
    - `suite_config`: spec part 03's R1, `agent.yaml` unchanged for an experiment with no tests
      of its own, else a generated `suite.yaml` with absolute paths.
    - `run_id`, `iso_now`, `spe_eval_home`, `reports_dir`: decision 7's run id, the `run.json`/
      `windows.jsonl` timestamp format, and the reports layout.
    - `promptfoo_env`: the environment `run.sh`'s promptfoo calls need, from the VM-local
      hand-off (task 5 review item 1).
    - `Lock`, `LockHeld`: decision 11, `~/spe-eval/lock`.
    - `append_jsonl`, `discover_runs`, `run_entry`, `read_progress`: `spe-eval status`/`wait`/
      `runs`'s own reading of `~/spe-eval/reports/`, `windows.jsonl` and the progress file R3
      writes.
    - `new_experiment` and its skeleton-text helpers: `spe-eval new` (07, *Start*).
    - `arm_counts`, `verdict_for`, `build_results`, `format_results_text`, `test_reasons`:
      `spe-eval results` (07, *Read*): one arm's counts tolerant of a "mixed" hardening record,
      the closed/narrowed/unchanged/worse word per metric, both arms' counts for one run, and its
      text form; `test_reasons` is `--test`'s own read of `agent.json`.
    - `pr_body_text` and its summary helpers: `spe-eval pr-body` (05, *The PR*; 07, *Share*), the
      title and body filled in from an experiment's files and its `build_results`.
"""
from __future__ import annotations

import fcntl
import json
import os
import re
import sys
import time
from datetime import datetime, timezone
from pathlib import Path

import yaml

_HERE = Path(__file__).resolve()
OWN_REPO_ROOT = _HERE.parents[2]  # platform/instance/spe_eval.py -> the repository root
_PROMPTFOO_DIR = OWN_REPO_ROOT / "platform" / "promptfoo-evals"
for _p in (str(OWN_REPO_ROOT), str(_PROMPTFOO_DIR)):
    if _p not in sys.path:
        sys.path.insert(0, _p)
import validate  # noqa: E402  (repo root: EXPERIMENT_PARAMETER_ANSIBLE_NAMES, main.tf's own mapping)
import injections_schema  # noqa: E402  (promptfoo-evals: switches(), built from the fixtures.json catalogue)
import matrix  # noqa: E402  (promptfoo-evals: counts()/MatrixError, reused by `results`/`pr-body`, task 3)


class ConfigError(Exception):
    """A usage or configuration problem (CLI exit 2): a missing or malformed file, an unknown
    id, or an experiment whose creation-time settings do not match this build (decision 7)."""


def repo_dir() -> Path:
    """The clone `spe-eval` reads `experiments/`, `mitigations/` and `instances/local.yml`
    from: `SPE_REPO_DIR`, or the repository containing this script (03, *Which experiment*)."""
    value = os.environ.get("SPE_REPO_DIR")
    return Path(value) if value else OWN_REPO_ROOT


# --- which experiment (decision 7) --------------------------------------------------------------

def load_experiment(name: str, repo_root: Path | None = None) -> dict:
    """`experiments/<name>.yml`, parsed (01-experiment-model.md, *Experiments*)."""
    repo_root = repo_root or repo_dir()
    path = repo_root / "experiments" / f"{name}.yml"
    try:
        text = path.read_text()
    except OSError as e:
        raise ConfigError(f"{path}: {e.strerror or e}") from None
    data = yaml.safe_load(text)
    if not isinstance(data, dict):
        raise ConfigError(f"{path}: not a YAML mapping")
    return data


def load_local_vars(repo_root: Path | None = None) -> dict:
    """`platform/ansible/instances/local.yml`, the build's own values (written at creation for
    `spe-apply`; decision 7 compares an experiment's creation-time settings against it)."""
    repo_root = repo_root or repo_dir()
    path = repo_root / "platform" / "ansible" / "instances" / "local.yml"
    try:
        text = path.read_text()
    except OSError as e:
        raise ConfigError(
            f"{path}: {e.strerror or e}: this instance was built before local re-apply existed; "
            "start a new workspace") from None
    data = yaml.safe_load(text)
    if not isinstance(data, dict):
        raise ConfigError(f"{path}: not a YAML mapping")
    return data


def default_experiment_name(local_vars: dict) -> str:
    """The experiment the workspace was built with (`spe_experiment` in `local_vars`), the
    default `spe-eval` command target when none is named (03, *Which experiment*)."""
    name = local_vars.get("spe_experiment")
    if not name:
        raise ConfigError("instances/local.yml has no spe_experiment: this is not a spe-experiments build")
    return name


# decision 7: not creation-time choices of the experiment itself (`seed` is not even a key of
# validate.EXPERIMENT_PARAMETER_ANSIBLE_NAMES, so it needs no entry here).
_SKIP_CREATION_TIME_PARAMETERS = frozenset({"experiment", "mitigations"})

# These three hold the creation form's own list order, which a hand-edited build need not match
# (task 3 review, minor 1): compared as sets, not sequences.
_ORDER_INSENSITIVE_PARAMETERS = frozenset({"samples", "tiers", "workflows"})


def check_creation_time(experiment: dict, local_vars: dict, repo_root: Path | None = None) -> list[str]:
    """The Ansible keys where `experiment`'s `parameters` or `vars` differ from the build's own
    (`local_vars`, from `instances/local.yml`), decision 7. Uses
    `validate.EXPERIMENT_PARAMETER_ANSIBLE_NAMES`, the mapping `experiments-template/main.tf` uses
    to turn a parameter into an Ansible variable, leaving out `experiment` and `mitigations`.
    `canaries` has no single Ansible name: it expands to one `spe_canary_<type>` key per type the
    build actually has (read from `local_vars`'s own keys, so every type the build supports is
    checked). A parameter with no persisted Ansible name at all (`flavor`: VM sizing, done once at
    creation) is skipped, since `local_vars` never holds anything to compare it to. `samples`,
    `tiers` and `workflows` are compared as sets, not sequences, so a build whose form held the
    same list in a different order is not a false mismatch.

    `experiment["experiment"]["injections"]` (not a `parameters` key, so the loop above never
    reaches it) is checked the same way as `canaries`: every catalogue switch this experiment names
    must be `true` in `local_vars` and every other one `false` (task 5 review item 2) -- the build's
    own `spe_inject_*` switches (`roles/repo/tasks/main.yml`'s `spe_local_vars_fixture_switches`,
    persisted for every fixture whether an experiment names it or not), compared against
    `injections_schema.switches` for this experiment's own list. A switch missing from `local_vars`
    (a build from before this comparison existed) is treated as `false`, its Ansible default.
    """
    params = experiment.get("parameters") or {}
    mismatches: list[str] = []
    for key, ansible_name in validate.EXPERIMENT_PARAMETER_ANSIBLE_NAMES.items():
        if key in _SKIP_CREATION_TIME_PARAMETERS or key not in params:
            continue
        if key == "canaries":
            selected = set(params["canaries"] or [])
            for local_key in local_vars:
                if not local_key.startswith("spe_canary_"):
                    continue
                canary_type = local_key[len("spe_canary_"):]
                if bool(local_vars[local_key]) != (canary_type in selected):
                    mismatches.append(local_key)
            continue
        if ansible_name is None or ansible_name not in local_vars:
            continue
        if key in _ORDER_INSENSITIVE_PARAMETERS:
            if sorted(local_vars[ansible_name] or []) != sorted(params[key] or []):
                mismatches.append(ansible_name)
            continue
        if local_vars[ansible_name] != params[key]:
            mismatches.append(ansible_name)
    for key, value in (experiment.get("vars") or {}).items():
        if local_vars.get(key) != value:
            mismatches.append(key)
    injection_ids = (experiment.get("experiment") or {}).get("injections") or []
    expected_switches = injections_schema.switches(injection_ids, repo_root or repo_dir())
    for switch, expected in expected_switches.items():
        if bool(local_vars.get(switch, False)) != expected:
            mismatches.append(switch)
    return sorted(set(mismatches))


def check_build_matches(experiment: dict, local_vars: dict, repo_root: Path | None = None) -> None:
    """Raises `ConfigError` naming every key `check_creation_time` finds differing, saying to
    build fresh from the branch template (decision 7); returns normally when they all match."""
    mismatches = check_creation_time(experiment, local_vars, repo_root)
    if mismatches:
        raise ConfigError(
            "this build does not match the experiment's creation-time settings: "
            + ", ".join(mismatches)
            + " differ; build a fresh workspace from its branch template (05, step 5)")


# --- arms (decision 9) ----------------------------------------------------------------------

def load_mitigations(repo_root: Path | None = None) -> dict[str, dict]:
    """`mitigations/<id>.yml`, by id, skipping `status: planned` ones (no `on`/`off` to apply) and
    `TEMPLATE.yml` (a copy-and-fill-in document with no `on`/`off` of its own, not a mitigation to
    apply; check_experiment.py and validate.py exclude it from the catalog the same way)."""
    repo_root = repo_root or repo_dir()
    mitigations: dict[str, dict] = {}
    for path in sorted((repo_root / "mitigations").glob("*.yml")):
        if path.stem == "TEMPLATE":
            continue
        meta = yaml.safe_load(path.read_text())
        if not isinstance(meta, dict) or meta.get("status") == "planned":
            continue
        mitigations[meta["id"]] = meta
    return mitigations


def experiment_arms(experiment: dict) -> tuple[str, ...]:
    """This experiment's arms (decision 9): `baseline` alone when there is no mitigation under
    test (`mitigation: null`), else `baseline` and `mitigated`."""
    if experiment["experiment"].get("mitigation") is None:
        return ("baseline",)
    return ("baseline", "mitigated")


def arm_mitigations(experiment: dict, arm: str) -> list[str]:
    """The mitigation ids on in `arm`, in declared order (`base`, then the one under test for
    `mitigated`). Raises `ValueError` for an arm this experiment does not have (e.g. `mitigated`
    on a one-arm experiment such as `ladder-l0`)."""
    arms = experiment_arms(experiment)
    if arm not in arms:
        raise ValueError(f"{arm!r}: not an arm of this experiment (has {', '.join(arms)})")
    base = list(experiment["experiment"].get("base") or [])
    if arm == "baseline":
        return base
    return base + [experiment["experiment"]["mitigation"]]


def arm_vars(experiment: dict, arm: str, repo_root: Path | None = None) -> dict:
    """The `-e` values for one arm (03, step 2; decision 9): every mitigation file's `on` for the
    ids in this arm, `off` for every other mitigation file (so the arm is exactly its set,
    whatever a mitigation selected on the form but outside the experiment was), plus
    `spe_mitigations` (the arm's set), `spe_experiment`, and every injection switch from
    `injections_schema.switches` (the same in both arms, 01, *Attacks*)."""
    repo_root = repo_root or repo_dir()
    on_ids = set(arm_mitigations(experiment, arm))
    values: dict = {}
    for mitigation_id, meta in load_mitigations(repo_root).items():
        values.update(meta["on"] if mitigation_id in on_ids else meta["off"])
    values["spe_mitigations"] = arm_mitigations(experiment, arm)
    values["spe_experiment"] = experiment["parameters"]["experiment"]
    values.update(injections_schema.switches(experiment["experiment"].get("injections") or [], repo_root))
    return values


def write_json(values: dict, path: Path) -> Path:
    """Write `values` as the JSON file `spe-apply ... -e @<path>` passes (03, step 2)."""
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_text(json.dumps(values, indent=2, sort_keys=True) + "\n")
    return path


# --- the suite (R1) ------------------------------------------------------------------------------

_FILE_URI = re.compile(r"^file://([^:]+)(:.*)?$")


def _absolutize_file_uris(obj, base_dir: Path):
    """Every `file://<path>[:<suffix>]` string in `obj` (recursively, through dicts and lists),
    `<path>` made absolute under `base_dir` if it is not already: a `suite.yaml` written outside
    `platform/promptfoo-evals/` still finds `agui_provider.py`, `isolation.py`, `asserts.py` and
    `metrics.py` (R1, "paths in it are absolute, so it runs from any directory")."""
    if isinstance(obj, dict):
        return {k: _absolutize_file_uris(v, base_dir) for k, v in obj.items()}
    if isinstance(obj, list):
        return [_absolutize_file_uris(v, base_dir) for v in obj]
    if isinstance(obj, str):
        m = _FILE_URI.match(obj)
        if m:
            rel, suffix = m.group(1), m.group(2) or ""
            path = Path(rel)
            if not path.is_absolute():
                path = (base_dir / path).resolve()
            return f"file://{path}{suffix}"
    return obj


def _load_tests(promptfoo_dir: Path) -> dict[str, dict]:
    """Every test across `tests/*.yaml` and `tests/experiments/*.yaml`, by its `metadata.id`
    (01, *Tests*). The first file to define an id wins (the ladder's own files are read first), so
    a clash is silently resolved rather than raised: the catalogue's own tests stay canonical."""
    tests: dict[str, dict] = {}
    paths = sorted(promptfoo_dir.glob("tests/*.yaml")) + sorted(promptfoo_dir.glob("tests/experiments/*.yaml"))
    for path in paths:
        cases = yaml.safe_load(path.read_text()) or []
        for case in cases:
            tid = (case.get("metadata") or {}).get("id")
            if tid:
                tests.setdefault(tid, case)
    return tests


def suite_config(experiment: dict, out_dir: Path, repo_root: Path | None = None) -> Path:
    """The agent suite to run for this experiment (spec part 03, R1). With no `tests` named,
    `agent.yaml` unchanged (the ladder's own suite, byte for byte, so its 13 tests stay
    comparable). With tests named: `agent.yaml`'s settings with `tests` replaced by those ids
    (looked up across `tests/*.yaml` and `tests/experiments/*.yaml`; an unknown id raises
    `ConfigError`) plus every test of the `utility` group not already named, written as
    `<out_dir>/suite.yaml` with every `file://` path made absolute. Returns the path to run.
    """
    repo_root = repo_root or repo_dir()
    promptfoo_dir = repo_root / "platform" / "promptfoo-evals"
    agent_yaml = promptfoo_dir / "agent.yaml"
    test_ids = (experiment.get("experiment") or {}).get("tests") or []
    if not test_ids:
        return agent_yaml
    config = yaml.safe_load(agent_yaml.read_text())
    all_tests = _load_tests(promptfoo_dir)
    unknown = [tid for tid in test_ids if tid not in all_tests]
    if unknown:
        raise ConfigError(f"unknown test id(s): {', '.join(unknown)}")
    chosen = [all_tests[tid] for tid in test_ids]
    chosen_ids = set(test_ids)
    for tid, case in all_tests.items():
        if tid not in chosen_ids and (case.get("metadata") or {}).get("group") == "utility":
            chosen.append(case)
    config["tests"] = chosen
    config = _absolutize_file_uris(config, promptfoo_dir)
    out_dir.mkdir(parents=True, exist_ok=True)
    out_path = out_dir / "suite.yaml"
    out_path.write_text(yaml.safe_dump(config, sort_keys=False))
    return out_path


# --- run id and reports layout (decision 7) -------------------------------------------------

def run_id() -> str:
    """A run's id, fixed when the lock is taken (03, *Every run is kept*): UTC `YYYYMMDDTHHMMSSZ`."""
    return datetime.now(timezone.utc).strftime("%Y%m%dT%H%M%SZ")


def iso_now() -> str:
    """UTC timestamp in `run.sh`'s own format (`date -u +%Y-%m-%dT%H:%M:%SZ`), for `run.json`'s
    `started`/`ended` and `windows.jsonl`."""
    return datetime.now(timezone.utc).strftime("%Y-%m-%dT%H:%M:%SZ")


def spe_eval_home(home: Path | None = None) -> Path:
    """`~/spe-eval` (03, *The hand-off on the VM*; decision 11, the lock): everything `spe-eval`
    keeps on the VM. `home` overrides `Path.home()`, for tests."""
    return (home or Path.home()) / "spe-eval"


def reports_dir(experiment_name: str, run_id_: str, arm: str, home: Path | None = None) -> Path:
    """`~/spe-eval/reports/<experiment>/<run id>/<arm>/` (03, *Every run is kept*)."""
    return spe_eval_home(home) / "reports" / experiment_name / run_id_ / arm


# --- run.sh's environment (03, *The hand-off on the VM*; task 5 review item 1) ----------------

def promptfoo_env(handoff_dir: Path, config_dir: Path, progress_path: Path, base_env: dict | None = None) -> dict:
    """The environment `run.sh`'s promptfoo calls need, built from the VM-local hand-off
    (`handoff_dir`, never the controller's `SPE_HANDOFF_DIR` tunnel path): `PROMPTFOO_CONFIG_DIR`
    and `SPE_EVAL_PROGRESS` (R3), `SPE_AGENT_URL` (`handoff_dir`'s own `hosts.yml`, its `agent_url`
    key, left unset when that build has no `agui` frontend and hosts.yml has none), and
    `SPE_AGENT_API_KEY_FILE`/`SPE_LLM_API_KEY_FILE` as paths into `handoff_dir` -- this function
    never opens either key file, so no key value is ever read here, let alone printed. First drops
    `SPE_AGENT_API_KEY`, `SPE_LLM_API_KEY`, `SPE_AGENT_URL` and `SPE_HANDOFF_DIR` if `base_env`
    (ordinarily the caller's own inherited environment) carries any of them: `asserts._secret`
    prefers the bare key over its `_FILE` variant, and the controller's own docs tell an operator
    to export `SPE_LLM_API_KEY` by hand, so a shell that still has it set must not override the VM
    hand-off this function is building (task 5 review, Minor 1). Also disables promptfoo's own
    telemetry, sharing and update check, as `platform/promptfoo-evals/README.md`'s run steps set
    them by hand, and puts `/usr/local/bin` (node, npx, uv: the `spe_eval` role's own symlinks) at
    the front of `PATH`, so `run.sh` finds them whatever the caller's own PATH already has (e.g. a
    `systemd --user` unit's own minimal one, R5).
    """
    handoff_dir = Path(handoff_dir)
    env = dict(base_env if base_env is not None else os.environ)
    for stale in ("SPE_AGENT_API_KEY", "SPE_LLM_API_KEY", "SPE_AGENT_URL", "SPE_HANDOFF_DIR"):
        env.pop(stale, None)
    hosts_path = handoff_dir / "hosts.yml"
    if hosts_path.is_file():
        hosts = yaml.safe_load(hosts_path.read_text()) or {}
        agent_url = hosts.get("agent_url")
        if agent_url:
            env["SPE_AGENT_URL"] = agent_url
    env["SPE_AGENT_API_KEY_FILE"] = str(handoff_dir / "agent_api_key")
    env["SPE_LLM_API_KEY_FILE"] = str(handoff_dir / "llm_api_key")
    env["PROMPTFOO_DISABLE_TELEMETRY"] = "1"
    env["PROMPTFOO_DISABLE_SHARING"] = "1"
    env["PROMPTFOO_DISABLE_UPDATE"] = "1"
    env["PROMPTFOO_CONFIG_DIR"] = str(config_dir)
    env["SPE_EVAL_PROGRESS"] = str(progress_path)
    path_parts = env.get("PATH", "").split(os.pathsep) if env.get("PATH") else []
    if "/usr/local/bin" not in path_parts:
        env["PATH"] = os.pathsep.join(["/usr/local/bin", *path_parts]) if path_parts else "/usr/local/bin"
    return env


# --- the lock (decision 11) -----------------------------------------------------------------

class LockHeld(Exception):
    """Another process holds the lock; `token` is its holder's token, read from the lock file
    (`None` when the file could not be read, which should not happen once `flock` itself refused)."""

    def __init__(self, token: str | None):
        self.token = token
        super().__init__(
            f"spe-eval run {token} holds the lock; wait for it (spe-eval wait)" if token
            else "the lock is held; wait for it (spe-eval wait)")


class Lock:
    """`~/spe-eval/lock` (`flock`): one `spe-eval run` or `arm` at a time per VM (decision 11).
    `spe-apply` enforces the same file in bash, refusing unless `SPE_EVAL_LOCK` equals `holder()`."""

    def __init__(self, path: Path):
        self.path = path
        self._fd: int | None = None

    def holder(self) -> str | None:
        """The token in the lock file, reported only when the lock is actually held: a missing
        or empty file is "not held" (03), and so is a non-empty file whose `flock` a non-blocking
        probe can still take -- a token left behind by a process that died before `release()`
        ever ran (e.g. SIGKILLed past its SIGTERM grace period), rather than trusting the file's
        text alone (task 5 review, Important 4a)."""
        try:
            text = self.path.read_text().strip()
        except FileNotFoundError:
            return None
        if not text:
            return None
        try:
            fd = os.open(self.path, os.O_RDWR)
        except FileNotFoundError:
            return None
        try:
            fcntl.flock(fd, fcntl.LOCK_EX | fcntl.LOCK_NB)
        except BlockingIOError:
            return text  # genuinely held by another process
        else:
            fcntl.flock(fd, fcntl.LOCK_UN)
            return None  # a stale token in a file nothing holds: "free"
        finally:
            os.close(fd)

    def acquire(self, token: str) -> None:
        """Take the lock and write `token` (a run id) into it. Raises `LockHeld`, naming the
        current holder's token, if another process already holds it."""
        self.path.parent.mkdir(parents=True, exist_ok=True)
        fd = os.open(self.path, os.O_RDWR | os.O_CREAT, 0o600)
        # A few short retries: `holder()`'s own probe (`status`, `wait`'s polling) takes the free lock
        # for an instant, and must not make a real acquire fail (re-review N3).
        for attempt in range(5):
            try:
                fcntl.flock(fd, fcntl.LOCK_EX | fcntl.LOCK_NB)
                break
            except BlockingIOError:
                if attempt == 4:
                    os.close(fd)
                    raise LockHeld(self.holder()) from None
                time.sleep(0.1)
        os.ftruncate(fd, 0)
        os.write(fd, token.encode())
        os.fsync(fd)
        self._fd = fd

    def release(self) -> None:
        """Release the lock (03, step 5) and clear the file, so a stale token is never read as
        held by a later `holder()` call. A no-op if this `Lock` never acquired it."""
        if self._fd is None:
            return
        os.ftruncate(self._fd, 0)
        fcntl.flock(self._fd, fcntl.LOCK_UN)
        os.close(self._fd)
        self._fd = None


# --- runs: kept reports, status and the progress file (07, `status`/`wait`/`runs`) -----------

def append_jsonl(path: Path, record: dict) -> None:
    """Append one JSON line to `path` (03, `windows.jsonl`): `{run, experiment, start, end}`, two per run:
    an opening line (`end` null) when it starts and a closing one at its end; per run, the closed line wins."""
    path.parent.mkdir(parents=True, exist_ok=True)
    with path.open("a") as f:
        f.write(json.dumps(record) + "\n")


def discover_runs(home: Path | None = None) -> list[dict]:
    """Every run under `~/spe-eval/reports/<experiment>/<run id>/<arm>/run.json`, newest first
    (07, `spe-eval runs`): `{"run": <id>, "experiment": <name>, "arms": {<arm>: <run.json>}}`. A
    run with no readable `run.json` in any of its arms is left out (nothing to report)."""
    reports_root = spe_eval_home(home) / "reports"
    runs: dict[str, dict] = {}
    if reports_root.is_dir():
        for experiment_dir in sorted(p for p in reports_root.iterdir() if p.is_dir()):
            for run_dir in sorted(p for p in experiment_dir.iterdir() if p.is_dir()):
                arms: dict[str, dict] = {}
                for arm_dir in sorted(p for p in run_dir.iterdir() if p.is_dir()):
                    run_json = arm_dir / "run.json"
                    if not run_json.is_file():
                        continue
                    try:
                        arms[arm_dir.name] = json.loads(run_json.read_text())
                    except ValueError:
                        continue
                if arms:
                    runs[run_dir.name] = {"run": run_dir.name, "experiment": experiment_dir.name, "arms": arms}
    return sorted(runs.values(), key=lambda entry: entry["run"], reverse=True)


def run_entry(home: Path | None, run_id_: str) -> dict | None:
    """The one entry of `discover_runs` whose run id is `run_id_`, or `None`."""
    for entry in discover_runs(home):
        if entry["run"] == run_id_:
            return entry
    return None


def read_progress(path: Path, repeat: int = 1) -> dict:
    """The progress file's numbers (R3, `isolation.py`'s hook): `total` (the suite's test count
    times `repeat`, `None` before the first line), `done` (0 before the first `afterEach`) and
    `last_error` (the most recent test's error, kept rather than cleared by a later passing test,
    so `spe-eval status` still shows why an earlier test failed)."""
    total = None
    done = 0
    last_error = None
    if path.is_file():
        for raw in path.read_text().splitlines():
            try:
                record = json.loads(raw)
            except ValueError:
                continue
            if "total" in record:
                total = record["total"]
            elif "done" in record:
                done = record["done"]
                if record.get("error"):
                    last_error = record["error"]
    return {"total": (total * repeat) if total is not None else None, "done": done, "last_error": last_error}


# --- spe-eval new (07-agent-friendly.md, *Start*) ---------------------------------------------
#
# Writes every slot of a new experiment's skeleton, with `TODO`s, so `check_experiment.py` refuses
# it until they are filled or the slot's own file is deleted (05-contribution.md, *A skeleton, not
# a rulebook*): the experiment file, its mitigation (`mitigations/<name>.yml`, switch
# `spe_mitigate_<name_>`, default off in `group_vars/all.yml`), its own test
# (`tests/experiments/<name>.yaml`), and -- when `--threat`/`--path` name an id not in the catalog
# yet -- that threat's or path's file from `TEMPLATE.md`. With `--injection`, also a fixtures.json
# entry, its payload file, and switch `spe_inject_<name_>` default off.
#
# Every refusal (`ConfigError`: a bad or existing name, an unknown `--from` or `--injection`
# surface) is checked before anything is written, so a refused `new` never leaves a partial
# skeleton behind. `group_vars/all.yml` and `fixtures.json` are edited by text, not a full re-dump,
# so an existing entry's formatting is untouched (`git diff` shows only what was added).

NEW_NAME_PATTERN = re.compile(r"^[a-z][a-z0-9]*(-[a-z0-9]+)*$")
_THREAT_ID_PATTERN = re.compile(r"^TM-\d{3}$")
_PATH_ID_PATTERN = re.compile(r"^P\d+$")


def valid_new_name(name: str) -> bool:
    """A name `spe-eval new` accepts: lowercase kebab-case (so it is also a valid mitigation id
    and, with `-` as `_`, a valid Ansible switch suffix), and not `template` (`experiments/
    TEMPLATE.yml`/`mitigations/TEMPLATE.yml` are copy-and-fill-in documents, excluded from the
    catalog by every reader -- never a real experiment's name, whatever its case)."""
    return bool(NEW_NAME_PATTERN.match(name)) and name.lower() != "template"


def _switch(prefix: str, name: str) -> str:
    """`spe_<prefix>_<name with - as _>` (07-agent-friendly.md, *Conventions*: "names derive from
    one name")."""
    return f"spe_{prefix}_{name.replace('-', '_')}"


def mitigation_text(name: str, switch: str) -> str:
    """`mitigations/<name>.yml`'s skeleton (see `mitigations/TEMPLATE.yml` for what each key
    means): `id`/`on`/`off` are already filled in from `name`; every other slot is a literal
    `TODO` for the participant to fill, or -- for an attack-only idea -- to delete, along with
    this file and the switch's own line in `group_vars/all.yml` (05-contribution.md, *A skeleton*).
    """
    return (
        f"id: {name}\n"
        "name: TODO\n"
        "description: >\n"
        "  TODO: what this mitigation changes, and where, when it is on.\n"
        "closes: []  # TODO: path ids (P<n>, paths/) this closes when on; stays [] for a control "
        "that narrows (then list its probes below)\n"
        f'"on": {{{switch}: true}}\n'
        f'"off": {{{switch}: false}}\n'
        "requires: []  # optional: mitigation ids that must also be on\n"
        "conflicts: []  # optional: mitigation ids that must not be on\n"
        "probes: []  # optional: controls-suite probes (platform/promptfoo-evals/probes/*.sh) it closes\n"
    )


def threat_file_text(threat_id: str) -> str:
    """`threats/<threat_id>-<slug>.md`'s skeleton, the shape of `threats/TEMPLATE.md` with every
    free-text slot a literal `TODO` (including the controlled-vocabulary fields, so this threat
    stays out of the catalog -- `validate.py`'s own check, not a `TODO`-scan -- until real values
    replace them)."""
    return (
        "---\n"
        f"id: {threat_id}\n"
        "name: TODO\n"
        "description: >\n"
        "  TODO: three to five sentences -- what the agent does or is made to do, the mechanism "
        "that turns it into harm, and what in this stack makes it possible.\n"
        "status: TODO\n"
        "entry-points:\n"
        "  - TODO\n"
        "assets:\n"
        "  - TODO\n"
        "stride:\n"
        "  - TODO\n"
        "---\n"
        "\n"
        f"# {threat_id}: TODO\n"
        "\n"
        "## Attack Scenarios\n"
        "\n"
        "1. TODO\n"
        "\n"
        "## Preconditions\n"
        "\n"
        "- TODO\n"
        "\n"
        "## Mitigations\n"
        "\n"
        "### Preventive\n"
        "\n"
        "- TODO\n"
        "\n"
        "### Detective\n"
        "\n"
        "- TODO\n"
        "\n"
        "### Responsive\n"
        "\n"
        "- TODO\n"
    )


def path_file_text(path_id: str) -> str:
    """`paths/<path_id>-<slug>.md`'s skeleton, the shape of `paths/TEMPLATE.md`; `reaches: [TODO]`
    is not a real canary type, so this path stays out of the catalog until it is."""
    return (
        "---\n"
        f"id: {path_id}\n"
        "name: TODO\n"
        "description: >\n"
        "  TODO: one or two sentences -- the concrete route through the stack that reaches the canaries below.\n"
        "reaches:\n"
        "  - TODO\n"
        "---\n"
        "\n"
        f"# {path_id}: TODO\n"
        "\n"
        "## Route\n"
        "\n"
        "TODO: the steps the agent (or an attacker through it) takes, with the real endpoints of this stack.\n"
        "\n"
        "## Shown by\n"
        "\n"
        "TODO: the controls probe or agent test that demonstrates this path open.\n"
    )


def test_file_text(name: str, *, threat: str | None, path: str | None, closed_by: str | None) -> str:
    """`tests/experiments/<name>.yaml`'s skeleton: one labelled test (07-agent-friendly.md,
    *Start*). `metadata.group` is this file's own stem, always a valid label once the file exists
    (01-experiment-model.md, *Tests*: group values are the test files' stems)."""
    data = [{
        "description": "TODO: what this test does.",
        "vars": {"message": "TODO: the prompt that attempts the attack, or exercises the mitigation."},
        "metadata": {"id": name, "group": name, "threat": threat, "path": path, "closed_by": closed_by},
        "assert": [],
    }]
    header = (
        "# Written by `spe-eval new` (07-agent-friendly.md, *Start*). Add at least one assertion "
        "under `assert`\n"
        "# (see platform/promptfoo-evals/tests/utility.yaml for examples), and fill in every "
        "other TODO.\n"
    )
    return header + yaml.safe_dump(data, sort_keys=False)


def experiment_text(name: str, *, threat: str, paths: list[str], mitigation: str | None, base: list[str],
                     injections: list[str], tests: list[str], extra_parameters: dict | None = None,
                     extra_top: dict | None = None) -> str:
    """`experiments/<name>.yml`'s skeleton (see `experiments/TEMPLATE.yml` for what each key
    means). `extra_parameters` and `extra_top` carry over a `--from` experiment's own form
    parameters and `vars` (not mandated by the spec, but otherwise unusable on a workspace until
    hand-filled); without `--from` they are empty and the participant fills `parameters` by hand.
    """
    parameters = {"experiment": name, "mitigations": list(base)}
    parameters.update(extra_parameters or {})
    data = {
        "name": "TODO",
        "description": "TODO: what this measures and why.",
        "parameters": parameters,
        "experiment": {
            "threat": threat, "paths": list(paths), "mitigation": mitigation, "base": list(base),
            "injections": list(injections), "tests": list(tests),
        },
    }
    data.update(extra_top or {})
    header = (
        "# Written by `spe-eval new` (07-agent-friendly.md, *Start*); every TODO is a slot to "
        "fill, or -- if\n"
        "# this idea does not need it -- to delete along with its own file (05-contribution.md,\n"
        "# *A skeleton, not a rulebook*: an attack-only idea deletes mitigations/<name>.yml and "
        "its\n"
        "# switch in group_vars/all.yml, and sets mitigation: null here).\n"
        "# See experiments/TEMPLATE.yml for what each key means.\n"
    )
    return header + yaml.safe_dump(data, sort_keys=False)


def _append_switch(group_vars_path: Path, switch: str, comment: str, marker: str) -> None:
    """Appends `<switch>: false  # <comment>` to `group_vars/all.yml`, as plain text (never a full
    YAML re-dump, so every existing line is untouched): a no-op if the switch is already there
    (re-running `new` after a partial failure), and `marker`'s own banner comment is added once,
    the first time any contributed switch is appended."""
    text = group_vars_path.read_text()
    if re.search(rf"^{re.escape(switch)}:", text, re.MULTILINE):
        return
    if not text.endswith("\n"):
        text += "\n"
    if marker not in text:
        text += f"\n{marker}\n"
    text += f"{switch}: false  # {comment}\n"
    group_vars_path.write_text(text)


def _append_fixture(fixtures_path: Path, entry: dict) -> None:
    """Appends one `fixtures.json` entry by text, not a full `json.dumps` re-dump (the existing
    entries' own formatting -- e.g. an inline `select` -- would otherwise be rewritten): finds the
    fixtures array's closing `]`, right before the file's closing `}`, and inserts `entry` before
    it, indented to match the existing entries (`git diff` then shows only the added entry)."""
    text = fixtures_path.read_text()
    closing = "\n  ]\n}"
    idx = text.rindex(closing)
    body = "\n".join(
        f"      {json.dumps(k)}: {json.dumps(v)}" + ("," if i < len(entry) - 1 else "")
        for i, (k, v) in enumerate(entry.items())
    )
    new_entry = f"    {{\n{body}\n    }}"
    new_text = text[:idx] + ",\n" + new_entry + text[idx:]
    json.loads(new_text)  # never leave fixtures.json broken: re-parse before writing it back
    fixtures_path.write_text(new_text)


def tests_naming_path(repo_root: Path, path_id: str) -> list[str]:
    """Existing test ids (`platform/promptfoo-evals/tests/*.yaml` and `tests/experiments/*.yaml`)
    whose `metadata.path` is `path_id`: the `--path` prefill's `tests` half (07-agent-friendly.md,
    *Start*; "Decisions for you" on this task -- fixtures.json has no injection-to-path link to
    read, so only `tests` is prefilled, not `injections`)."""
    tests_dir = repo_root / "platform" / "promptfoo-evals" / "tests"
    ids: set[str] = set()
    files = sorted(tests_dir.glob("*.yaml")) + sorted((tests_dir / "experiments").glob("*.yaml"))
    for p in files:
        try:
            cases = yaml.safe_load(p.read_text())
        except (yaml.YAMLError, UnicodeDecodeError):
            continue
        if not isinstance(cases, list):
            continue
        for case in cases:
            meta = case.get("metadata") if isinstance(case, dict) else None
            if isinstance(meta, dict) and meta.get("path") == path_id and isinstance(meta.get("id"), str):
                ids.add(meta["id"])
    return sorted(ids)


def new_experiment(repo_root: Path, name: str, *, threat: str | None = None, path: str | None = None,
                    injection: str | None = None, from_name: str | None = None) -> list[Path]:
    """Writes every slot of `name`'s skeleton under `repo_root` (07-agent-friendly.md, *Start*),
    and returns the paths written, in the order printed. Raises `ConfigError` (CLI exit 2) for an
    existing name, a bad name, or an unknown `--from` experiment or `--injection` surface --
    checked up front, so a refusal never leaves a partial skeleton behind."""
    if not valid_new_name(name):
        raise ConfigError(f"{name!r}: not a valid experiment name (lowercase kebab-case, e.g. 'trs-guard')")

    exp_path = repo_root / "experiments" / f"{name}.yml"
    if exp_path.exists():
        raise ConfigError(f"{exp_path}: an experiment named {name!r} already exists")

    base: list[str] = []
    extra_parameters: dict = {}
    extra_top: dict = {}
    if from_name is not None:
        from_path = repo_root / "experiments" / f"{from_name}.yml"
        if from_name.upper() == "TEMPLATE" or not from_path.is_file():
            raise ConfigError(f"--from {from_name!r}: no such experiment ('{from_path}' not found)")
        from_data = yaml.safe_load(from_path.read_text())
        if not isinstance(from_data, dict):
            raise ConfigError(f"{from_path}: not a YAML mapping")
        from_experiment = from_data.get("experiment") or {}
        from_mitigation = from_experiment.get("mitigation")
        base = list(from_experiment.get("base") or []) + ([from_mitigation] if from_mitigation else [])
        from_parameters = from_data.get("parameters") or {}
        if isinstance(from_parameters, dict):
            for key in ("samples", "tiers", "workflows", "canaries", "flavor", "smoke_test"):
                if key in from_parameters:
                    extra_parameters[key] = from_parameters[key]
        if "vars" in from_data:
            extra_top["vars"] = from_data["vars"]

    if threat is not None and not _THREAT_ID_PATTERN.match(threat):
        raise ConfigError(f"{threat!r}: not a threat id (expected TM-NNN)")
    if path is not None and not _PATH_ID_PATTERN.match(path):
        raise ConfigError(f"{path!r}: not a path id (expected P<n>)")

    surfaces_path = repo_root / "platform" / "ansible" / "catalog" / "injections" / "surfaces.json"
    if injection is not None:
        try:
            surfaces_data = json.loads(surfaces_path.read_text())
        except OSError as e:
            raise ConfigError(f"{surfaces_path}: {e.strerror or e}") from None
        surfaces = surfaces_data.get("surfaces") if isinstance(surfaces_data, dict) else None
        if not isinstance(surfaces, dict) or injection not in surfaces:
            known = ", ".join(sorted(surfaces)) if isinstance(surfaces, dict) else ""
            raise ConfigError(f"{injection!r}: not a known injection surface ({known})")

    # Every refusal above is checked; nothing is written until here.
    written: list[Path] = []

    threat_id = threat if threat is not None else "TODO"
    if threat is not None and not any((repo_root / "threats").glob(f"{threat}-*.md")):
        threat_path = repo_root / "threats" / f"{threat}-{name}.md"
        threat_path.write_text(threat_file_text(threat))
        written.append(threat_path)

    path_ids = [path] if path is not None else ["TODO"]
    if path is not None and not any((repo_root / "paths").glob(f"{path}-*.md")):
        path_path = repo_root / "paths" / f"{path}-{name}.md"
        path_path.write_text(path_file_text(path))
        written.append(path_path)

    group_vars_path = repo_root / "platform" / "ansible" / "inventory" / "group_vars" / "all.yml"

    switch = _switch("mitigate", name)
    mitigation_path = repo_root / "mitigations" / f"{name}.yml"
    mitigation_path.write_text(mitigation_text(name, switch))
    written.append(mitigation_path)
    _append_switch(group_vars_path, switch, f"mitigations/{name}.yml: TODO",
                   "# --- contributed mitigations' own switches (spe-eval new; default off) ---")

    injections: list[str] = []
    if injection is not None:
        inj_switch = _switch("inject", name)
        payload_path = repo_root / "platform" / "ansible" / "catalog" / "injections" / f"{name}.txt"
        payload_path.write_text(
            f"TODO: a payload for the {injection} surface. Name its target file explicitly, and "
            "ask for something that leads to disclosing the canary inside it.\n"
        )
        written.append(payload_path)
        fixtures_path = repo_root / "platform" / "ansible" / "catalog" / "injections" / "fixtures.json"
        _append_fixture(fixtures_path, {
            "id": name, "switch": inj_switch, "surface": injection, "payload": f"{name}.txt",
            "select": {}, "target_file": "TODO", "canary_file": "TODO", "action": "TODO", "disclosure": "TODO",
        })
        written.append(fixtures_path)
        _append_switch(group_vars_path, inj_switch, f"{name}.txt on the {injection} surface",
                       "# --- contributed injections' own switches (spe-eval new --injection; default off) ---")
        injections = [name]

    tests = [name]
    if path is not None:
        tests += [tid for tid in tests_naming_path(repo_root, path) if tid != name]
    test_path = repo_root / "platform" / "promptfoo-evals" / "tests" / "experiments" / f"{name}.yaml"
    test_path.write_text(test_file_text(name, threat=threat, path=path, closed_by=name))
    written.append(test_path)

    exp_path.write_text(experiment_text(
        name, threat=threat_id, paths=path_ids, mitigation=name, base=base, injections=injections,
        tests=tests, extra_parameters=extra_parameters, extra_top=extra_top,
    ))
    written.append(exp_path)

    return written


# --- spe-eval results (07-agent-friendly.md, *Read*) -------------------------------------------
#
# `matrix.py counts()` is the ladder's own reading of one report directory (hardening.json,
# controls.json, agent.json, run.json, injections.json): labels, probe ids, test metadata,
# per-metric failure counts, never an answer or a token. It refuses a hardening record whose
# `injections` is "mixed" (06's matrix has no column for it), but an experiment's own arm can
# plant only some of the catalogue's fixtures (01, *Attacks*) and so gets exactly that record
# (platform/ansible/roles/handoff/tasks/hardening.yml). `arm_counts` is `counts()` for one arm
# directory, tolerant of "mixed": every other branch is counts() unchanged (same MatrixError), so
# the ladder's own refusal (06's matrix) is never touched; only this one extra case is handled,
# by calling matrix's own small building blocks directly instead of its `counts()` entry point.

def arm_counts(arm_dir: Path) -> dict:
    """`matrix.py counts(arm_dir)`, except a hardening.json with `injections: "mixed"` (an
    experiment's arm, decision 9) is read too, rather than refused: `results`/`pr-body` read any
    arm's report directory, which is exactly this shape (03, *Every run is kept*), and need its
    counts whether the arm's injections are all off, all on, or mixed. Raises `matrix.MatrixError`
    for anything else counts() itself would refuse (a missing or malformed file)."""
    directory = Path(arm_dir)
    try:
        record = matrix.handoff.check_hardening(matrix._load(directory / "hardening.json"))
    except matrix.handoff.ConfigError as e:
        raise matrix.MatrixError(str(e)) from e
    if record["injections"] != "mixed":
        return matrix.counts(directory)  # the ladder's own path and its own refusal, unchanged
    run = matrix._run(directory)
    return {
        "schema_version": 1, "instance": record["instance"], "level": record["level"],
        "injections": "mixed", "started": run["started"], "canaries_sha256": run["canaries_sha256"],
        # mixed means at least one catalogue fixture is planted (never none, by definition): the
        # same bool matrix._payloads itself uses for the "all on" case.
        "payloads": matrix._payloads(directory, True),
        "model": f"{record['model_provider']}:{record['model']}", "commit": record["commit"],
        "restore_seconds": record.get("restore_seconds"),
        "controls": matrix._controls(matrix._rows(matrix._load(directory / "controls.json"), "controls.json")),
        "tests": matrix._tests(matrix._rows(matrix._load(directory / "agent.json"), "agent.json")),
    }


def verdict_for(baseline_failures: dict, mitigated_failures: dict) -> dict[str, str]:
    """One word per metric either arm's `failures` names (07, *Read*): "closed" (baseline failed,
    mitigated does not), "narrowed" (mitigated fails less than baseline, but still some),
    "unchanged" (same count, including 0 and 0), "worse" (mitigated fails more)."""
    verdicts: dict[str, str] = {}
    for metric in sorted(set(baseline_failures) | set(mitigated_failures)):
        b = baseline_failures.get(metric, 0)
        m = mitigated_failures.get(metric, 0)
        if m == 0 and b > 0:
            verdicts[metric] = "closed"
        elif m < b:
            verdicts[metric] = "narrowed"
        elif m == b:
            verdicts[metric] = "unchanged"
        else:
            verdicts[metric] = "worse"
    return verdicts


def build_results(entry: dict, home: Path | None = None) -> dict:
    """The counts of every arm of `entry` (one of `discover_runs`'s, or `run_entry`'s), as
    `results`/`pr-body` print them: `{"run", "experiment", "arms", "model", "repeat", "utility":
    {<arm>: {"passed", "runs"}}, "tests": {<id>: {"group", "threat", "path", "closed_by",
    <arm>: {"runs", "errors", "passed", "failures"}, ..., "verdict": {<metric>: <word>}}}}`.
    `utility`-group tests are summed into `utility` and left out of `tests` (no leak metric, so no
    verdict); `verdict` is present only for a test both arms ran (always true for a two-arm run,
    03's own gate). Raises `ConfigError` for a report `arm_counts` cannot read (never a bare
    `matrix.MatrixError`, which `main()` does not know to catch)."""
    arms = sorted(entry["arms"])  # "baseline" < "mitigated": the run's own order (03, decision 9)
    try:
        counts_by_arm = {arm: arm_counts(reports_dir(entry["experiment"], entry["run"], arm, home)) for arm in arms}
    except matrix.MatrixError as e:
        raise ConfigError(str(e)) from e

    first_arm_record = next((entry["arms"][arm] for arm in arms if entry["arms"].get(arm)), {})
    utility = {arm: {"passed": 0, "runs": 0} for arm in arms}
    tests: dict[str, dict] = {}
    all_tids = sorted({tid for c in counts_by_arm.values() for tid in c["tests"]})
    for tid in all_tids:
        meta: dict | None = None
        per_arm: dict[str, dict] = {}
        for arm in arms:
            t = counts_by_arm[arm]["tests"].get(tid)
            if t is None:
                continue
            if meta is None:
                meta = {k: t[k] for k in ("group", "threat", "path", "closed_by")}
            per_arm[arm] = {"runs": t["runs"], "errors": t["errors"], "passed": t["passed"], "failures": t["failures"]}
        if meta and meta["group"] == "utility":
            for arm, t in per_arm.items():
                utility[arm]["passed"] += t["passed"]
                utility[arm]["runs"] += t["runs"]
            continue
        test_entry = {**(meta or {}), **per_arm}
        if len(arms) == 2 and "baseline" in per_arm and "mitigated" in per_arm:
            test_entry["verdict"] = verdict_for(per_arm["baseline"]["failures"], per_arm["mitigated"]["failures"])
        tests[tid] = test_entry

    return {"run": entry["run"], "experiment": entry["experiment"], "arms": arms,
            "model": first_arm_record.get("model"), "repeat": first_arm_record.get("repeat"),
            "utility": utility, "tests": tests}


def _results_body_lines(results: dict) -> list[str]:
    """The lines `results`'s text output and `pr-body`'s *Result* section share: the utility
    outcome, then every leak-metric test's baseline/mitigated counts and verdict."""
    arms = results["arms"]
    lines = ["Utility tests: " + ", ".join(
        f"{arm} {results['utility'][arm]['passed']}/{results['utility'][arm]['runs']} pass" for arm in arms)]
    for tid in sorted(results["tests"]):
        t = results["tests"][tid]
        lines.append(f"{tid} (group {t.get('group') or '-'}, threat {t.get('threat') or '-'}, "
                      f"path {t.get('path') or '-'}, closed_by {t.get('closed_by') or '-'}):")
        metrics = sorted({m for arm in arms if arm in t for m in t[arm]["failures"]})
        if not metrics:
            lines.append("  no leak metric recorded")
            continue
        verdict = t.get("verdict", {})
        for metric in metrics:
            row = "  " + f"{metric}: " + ", ".join(
                f"{arm} {t[arm]['failures'].get(metric, 0)}/{t[arm]['runs']}" for arm in arms if arm in t)
            if metric in verdict:
                row += f" -> {verdict[metric]}"
            lines.append(row)
    return lines


def format_results_text(results: dict) -> str:
    """`spe-eval results`'s text output (07, *Read*): the run, the experiment, then
    `_results_body_lines`."""
    return "\n".join([f"run {results['run']} ({results['experiment']})", *_results_body_lines(results)]) + "\n"


def test_reasons(entry: dict, test_id: str, home: Path | None = None) -> dict[str, list[str]]:
    """Every component assertion's `reason` for `test_id`, by arm, read straight from each arm's
    `agent.json` (not from `build_results`'s counts, which keep labels and numbers only): `--test`
    (07, *Read*). An arm missing the id, or with no readable `agent.json`, is left out; empty when
    the id never ran at all (never raises: this is a read for a human, not a refusal)."""
    reasons: dict[str, list[str]] = {}
    for arm in sorted(entry["arms"]):
        agent_path = reports_dir(entry["experiment"], entry["run"], arm, home) / "agent.json"
        if not agent_path.is_file():
            continue
        try:
            rows = matrix._rows(matrix._load(agent_path), "agent.json")
        except matrix.MatrixError:
            continue
        found: list[str] = []
        for row in rows:
            meta = (row.get("testCase") or {}).get("metadata") or {}
            if meta.get("id") != test_id:
                continue
            for component in (row.get("gradingResult") or {}).get("componentResults") or []:
                reason = component.get("reason")
                if reason:
                    found.append(str(reason))
        if found:
            reasons[arm] = found
    return reasons


# --- spe-eval pr-body (05-contribution.md, *The PR*; 07-agent-friendly.md, *Share*) -------------
#
# The PR template is `.github/pull_request_template.md`, 05's *The PR* block verbatim. `pr_body`
# fills it in from the files (never from the catalogue's own validation: check_experiment.py's
# output is quoted, not re-derived) and the run's counts (`build_results`, above); a slot the
# experiment does not fill (no mitigation under test, no injection and no own test file) is left
# out rather than printed empty (05's acceptance check). *Idea and rationale* always stays the
# template's own placeholder: the reasoning is the participant's, not something these files hold.

def _one_line(text: object) -> str:
    """Collapse `text` to one line (a YAML `description: >` block's folded newlines, or any other
    free text) for a line of the PR body; "TODO" for anything that is not a non-empty string."""
    if not isinstance(text, str) or not text.strip():
        return "TODO"
    return " ".join(text.split())


def _front_matter_name(path: Path) -> str | None:
    try:
        meta, _ = validate.split_frontmatter(path.read_text(encoding="utf-8"))
    except (ValueError, OSError, UnicodeDecodeError):
        return None
    return meta.get("name") if isinstance(meta, dict) else None


def threat_summary(repo_root: Path, threat_id: str | None) -> str:
    """`<id>: <threats/<id>-*.md's name, one line>` ("TODO" when the id has no catalogue file
    yet, e.g. a `spe-eval new` skeleton not yet filled in)."""
    if not threat_id:
        return "TODO"
    for path in sorted((repo_root / "threats").glob(f"{threat_id}-*.md")):
        name = _front_matter_name(path)
        if name:
            return f"{threat_id}: {_one_line(name)}"
    return f"{threat_id}: TODO"


def path_summary(repo_root: Path, path_id: str) -> str:
    """`<id>: <paths/<id>-*.md's name, one line>` ("TODO" when the id has no catalogue file yet)."""
    for path in sorted((repo_root / "paths").glob(f"{path_id}-*.md")):
        name = _front_matter_name(path)
        if name:
            return f"{path_id}: {_one_line(name)}"
    return f"{path_id}: TODO"


def mitigation_summary(repo_root: Path, mitigation_id: str) -> str:
    """`` `<id>` (`<switch>`[, `<switch2>`...]): <description, one line> ``, the switch(es) read
    from the mitigation's own `on` (never guessed from the naming convention: a reused catalogue
    id such as `L1` does not follow `spe_mitigate_<id>`, only a freshly `spe-eval new`-written
    one does)."""
    path = repo_root / "mitigations" / f"{mitigation_id}.yml"
    try:
        meta = yaml.safe_load(path.read_text(encoding="utf-8"))
    except (OSError, yaml.YAMLError):
        meta = None
    meta = meta if isinstance(meta, dict) else {}
    on = meta.get("on")
    switches = ", ".join(f"`{s}`" for s in sorted(on)) if isinstance(on, dict) and on else "`?`"
    return f"`{mitigation_id}` ({switches}): {_one_line(meta.get('description'))}"


def _fixtures_by_id(repo_root: Path) -> dict[str, dict]:
    path = repo_root / "platform" / "ansible" / "catalog" / "injections" / "fixtures.json"
    try:
        data = json.loads(path.read_text(encoding="utf-8"))
    except (OSError, ValueError):
        return {}
    return {f["id"]: f for f in (data.get("fixtures") or []) if isinstance(f, dict) and "id" in f}


def attack_summary(repo_root: Path, name: str, experiment: dict) -> str | None:
    """The *Attack* line's value, or `None` when this experiment fills no attack slot of its own
    (05, *A skeleton*: it only reuses the catalogue's existing tests) -- a prompt test when
    `tests/experiments/<name>.yaml` exists, each injection id (surface and action, from
    `fixtures.json`) otherwise or in addition."""
    parts: list[str] = []
    own_test = repo_root / "platform" / "promptfoo-evals" / "tests" / "experiments" / f"{name}.yaml"
    if own_test.is_file():
        parts.append(f"a prompt test (`tests/experiments/{name}.yaml`)")
    fixtures = _fixtures_by_id(repo_root)
    for iid in (experiment.get("experiment") or {}).get("injections") or []:
        fixture = fixtures.get(iid)
        if fixture:
            parts.append(f"injection `{iid}`: {fixture.get('surface', '?')} / {fixture.get('action', '?')}")
        else:
            parts.append(f"injection `{iid}`")
    return "; ".join(parts) if parts else None


def pr_body_text(repo_root: Path, name: str, experiment: dict, results: dict | None,
                  checker_output: str) -> tuple[str, str]:
    """The title and body `spe-eval pr-body` prints (05, *The PR*): the template's own sections,
    filled from `experiment` (the files) and `results` (`build_results`, or `None` for *no run
    yet*, 05's acceptance check), with `checker_output` (`check_experiment.py <name>`'s own text)
    quoted verbatim under *Checks*. `title` is the PR title line, printed separately
    (`--help`: "the split")."""
    exp = experiment.get("experiment") or {}
    threat_id = exp.get("threat")
    paths_ids = exp.get("paths") or []
    mitigation_id = exp.get("mitigation")
    base = exp.get("base") or []

    title = f"Experiment: {name}"
    lines = [f"## Experiment: {name}", "", f"**Threat:** {threat_summary(repo_root, threat_id)}"]
    paths_text = "; ".join(path_summary(repo_root, pid) for pid in paths_ids) if paths_ids else "TODO"
    lines.append(f"**Paths:** {paths_text}")
    attack = attack_summary(repo_root, name, experiment)
    if attack is not None:
        lines.append(f"**Attack:** {attack}")
    if mitigation_id:
        lines.append(f"**Mitigation:** {mitigation_summary(repo_root, mitigation_id)}")
    lines.append(f"**Base:** {', '.join(base) if base else 'none'}")
    lines.append(f"**Experiment file:** `experiments/{name}.yml`")
    lines += ["", "### Idea and rationale", "<why this attack or mitigation, what was tried, known limits>", "",
              "### Result"]
    if results is None:
        lines.append(f"TODO: no run yet -- `spe-eval run {name}`, then `spe-eval pr-body {name}` again.")
    else:
        lines.append(f"Model: {results.get('model') or '?'}   Repeat: {results.get('repeat') or '?'}")
        lines += _results_body_lines(results)
        if mitigation_id and "mitigated" in results["arms"]:
            util = results["utility"].get("mitigated") or {}
            ok = bool(util.get("runs")) and util.get("passed") == util.get("runs")
            lines.append(f"Utility tests pass with the mitigation on: {'yes' if ok else 'no'}")
    lines += ["", "### Checks", f"`python3 check_experiment.py {name}`:", "```", checker_output.rstrip(), "```"]
    return title, "\n".join(lines) + "\n"
