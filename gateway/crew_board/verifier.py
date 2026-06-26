"""Verifier — checks an in-progress task against its acceptance criteria.

Three signals:
  1. project test cmd ran cleanly
  2. files-of-interest globs match at least one path each
  3. acceptance criteria texts are either explicitly checked OR appear
     in the diff body (heuristic)

Records each as a structured `verify_results` dict so the UI can show
owner-friendly red/green next to each acceptance line.

Never raises. Failed verifications return ok=False with a reason.
"""

from __future__ import annotations

import json
import logging
import re
import shlex
import subprocess
from dataclasses import dataclass, field
from pathlib import Path

from gateway.crew_board.store import CrewBoardStore, Task, Project

log = logging.getLogger("gateway.crew_board.verifier")


@dataclass
class VerifyResult:
    ok: bool
    tests: dict = field(default_factory=dict)
    files: dict = field(default_factory=dict)
    criteria: dict = field(default_factory=dict)
    reason: str = ""
    # True only when at least one RUNNABLE outcome probe existed and passed.
    # A smoke_cmd that ran and exited 0 is the primary mechanism. Tests-green
    # alone is NOT outcome_proven — that gap is what caused the silent
    # false-done problem (dashboard features shipped broken while tests passed).
    outcome_proven: bool = False
    outcome_reason: str = ""


def _augmented_env() -> dict:
    """os.environ with common dev-SDK bin dirs prepended to PATH.

    The gateway runs with a minimal PATH (often launched from a service /
    hidden window), so tools like `flutter`, `dart`, and `npm` may not be
    resolvable even though they are installed — which made `flutter test`
    fail to spawn and (before the gate fix) silently auto-pass. We prepend
    known SDK bins so configured test_cmds actually run. Honors FLUTTER_ROOT
    if set; otherwise probes a small set of standard install locations.
    """
    import os

    env = dict(os.environ)
    candidates: list[Path] = []
    flutter_root = env.get("FLUTTER_ROOT")
    if flutter_root:
        candidates.append(Path(flutter_root) / "bin")
    candidates += [
        Path("C:/src/flutter/bin"),
        Path("C:/flutter/bin"),
        Path.home() / "flutter" / "bin",
    ]
    extra = [str(p) for p in candidates if p.is_dir()]
    if extra:
        env["PATH"] = os.pathsep.join(extra) + os.pathsep + env.get("PATH", "")
    return env


def _run_tests(project: Project, *, timeout: float = 180.0) -> dict:
    """Run the project's test command. Returns a dict capturing
    stdout/stderr tails + return code."""
    if not project.test_cmd:
        return {
            "ran": False,
            "reason": "no test_cmd configured",
            "exit_code": None,
            "stdout_tail": "",
            "stderr_tail": "",
        }
    project_dir = Path(project.path)
    if not project_dir.is_dir():
        return {
            "ran": False,
            "reason": f"project path missing: {project_dir}",
            "exit_code": None,
            "stdout_tail": "",
            "stderr_tail": "",
        }
    env = _augmented_env()
    argv = shlex.split(project.test_cmd)
    # Windows: `flutter`/`npm` are .bat/.cmd shims. subprocess.run without a
    # shell looks for the bare name and ignores PATHEXT, so `["flutter", ...]`
    # raises WinError 2 even though flutter.bat is on PATH. Resolve argv[0] to
    # its real executable (shutil.which respects PATHEXT) against the augmented
    # PATH before spawning.
    if argv:
        import shutil
        resolved = shutil.which(argv[0], path=env.get("PATH"))
        if resolved:
            argv[0] = resolved
    try:
        proc = subprocess.run(
            argv,
            cwd=project_dir,
            capture_output=True, text=True,
            timeout=timeout, check=False,
            env=env,
        )
    except subprocess.TimeoutExpired:
        return {
            "ran": True,
            "exit_code": -1,
            "reason": f"timeout after {timeout}s",
            "stdout_tail": "",
            "stderr_tail": "",
        }
    except (OSError, ValueError) as e:
        return {
            "ran": False,
            "reason": f"could not spawn: {e}",
            "exit_code": None,
            "stdout_tail": "",
            "stderr_tail": "",
        }
    _out = proc.stdout or ""
    return {
        "ran": True,
        "exit_code": proc.returncode,
        "reason": "",
        "stdout_tail": _out[-2000:],
        "stderr_tail": (proc.stderr or "")[-2000:],
        # Parse from a larger window than we keep for display, so baseline-diff
        # verification can compare failing-test identifiers across runs.
        "failed_ids": _parse_failing_tests(_out[-8000:], project.test_cmd or ""),
    }


def _parse_failing_tests(stdout: str, test_cmd: str) -> list[str]:
    """Best-effort extraction of FAILING test identifiers from runner stdout,
    for baseline-diff verification ("pass iff no NEW failures"). Runner-specific;
    returns [] when nothing recognisable is found (caller then fails strict, so a
    parser miss never falsely passes a red suite)."""
    cmd = (test_cmd or "").lower()
    ids: list[str] = []
    lines = stdout.splitlines()
    if "flutter" in cmd or "dart" in cmd:
        # e.g. "00:02 +186 -3: <file>.dart: <test name> [E]"
        for ln in lines:
            s = ln.strip()
            if s.endswith("[E]") and ".dart:" in s:
                seg = re.sub(r"^\d+:\d+\s+\+\d+\s+-\d+:\s*", "", s)
                ids.append(seg[:-3].strip())
    elif "pytest" in cmd or "python" in cmd:
        for ln in lines:
            if ln.startswith("FAILED "):
                ids.append(ln[7:].split(" ")[0])
            elif ln.startswith("ERROR ") and "::" in ln:
                ids.append(ln[6:].split(" ")[0])
    elif "cargo" in cmd:
        for ln in lines:
            s = ln.strip()
            if s.startswith("test ") and s.endswith("... FAILED"):
                ids.append(s.split()[1])
    elif "go test" in cmd or cmd.strip().startswith("go "):
        for ln in lines:
            s = ln.strip()
            if s.startswith("--- FAIL:"):
                parts = s.split()
                if len(parts) >= 3:
                    ids.append(parts[2])
    elif any(k in cmd for k in ("npm", "node", "jest", "vitest", "yarn", "pnpm")):
        for ln in lines:
            s = ln.strip()
            if s.startswith("not ok ") or s.startswith("✕") or s.startswith("✗") \
                    or s.startswith("FAIL "):
                ids.append(s[:160])
    seen: set[str] = set()
    out: list[str] = []
    for x in ids:
        if x and x not in seen:
            seen.add(x)
            out.append(x)
    return out


def _check_files(task: Task, project: Project) -> dict:
    """For each `files_of_interest` glob, count matching paths under
    the project dir. Glob is interpreted relative to the project."""
    project_dir = Path(project.path)
    out: dict = {"globs": [], "all_present": True}
    if not task.files_of_interest:
        out["all_present"] = True  # nothing required
        return out
    for glob in task.files_of_interest:
        try:
            matches = list(project_dir.glob(glob))
        except (OSError, ValueError):
            matches = []
        out["globs"].append({
            "glob": glob,
            "matches": [str(m.relative_to(project_dir)).replace("\\", "/")
                        for m in matches[:20]],
            "count": len(matches),
        })
        if not matches:
            out["all_present"] = False
    return out


def _check_criteria(task: Task) -> dict:
    """Owner manually ticks each acceptance criterion in the UI; this
    just reports the current state. We don't auto-infer from diff
    content — too noisy. The UI shows the unchecked ones."""
    items = task.acceptance_criteria or []
    checked = sum(1 for c in items if c.get("checked"))
    return {
        "total": len(items),
        "checked": checked,
        "all_checked": (checked == len(items)) if items else True,
        "unchecked": [
            c.get("text", "") for c in items if not c.get("checked")
        ],
    }


def _check_commit(task: Task, project: Project) -> dict:
    """False-done gate: a real 'done' must show actual work — either uncommitted
    changes in the tree (the loop commits after verify) OR a commit that
    references the task. A CLEAN tree with NO task commit means nothing was
    produced (the example-app T-0375 case: marked done, zero diff). Permissive
    when the project isn't a git checkout."""
    pdir = Path(project.path) if getattr(project, "path", None) else None
    if pdir is None or not (pdir / ".git").exists():
        return {"checked": False, "reason": "not a git checkout"}
    def _git(*args: str) -> str:
        try:
            return subprocess.run(
                ["git", "-C", str(pdir), *args],
                capture_output=True, text=True, timeout=30,
            ).stdout.strip()
        except (OSError, subprocess.SubprocessError):
            return ""
    dirty = _git("status", "--porcelain")
    has_commit = bool(_git("log", "--oneline", "-100", "--grep", task.slug))
    if not dirty and not has_commit:
        return {
            "checked": True, "ok": False,
            "reason": (
                f"false-done: working tree is clean AND no commit references "
                f"{task.slug} — no work was produced for this task"
            ),
        }
    return {"checked": True, "ok": True}


def _check_entrypoint(task: Task, project: Project) -> dict:
    """Boot gate: an APP must be launchable, not merely test-green. Catches the
    'tests pass but the app has no entry point' class (the tetris no-main() bug,
    where 79 tests passed but the app could not start on any platform).
    Flutter: require a top-level main() in lib/main.dart."""
    import re
    pdir = Path(project.path) if getattr(project, "path", None) else None
    if pdir is None:
        return {"checked": False}
    if (pdir / "pubspec.yaml").exists():
        main_dart = pdir / "lib" / "main.dart"
        if not main_dart.exists():
            return {"checked": True, "ok": False,
                    "reason": "Flutter app has no lib/main.dart — it cannot launch"}
        try:
            text = main_dart.read_text(encoding="utf-8", errors="ignore")
        except OSError:
            return {"checked": False}
        if not re.search(r"^\s*(?:void\s+|Future\s*<\s*void\s*>\s+|[\w<>]+\s+)?main\s*\(", text, re.M):
            return {
                "checked": True, "ok": False,
                "reason": (
                    "Flutter app's lib/main.dart has no main() entry point — "
                    "the app cannot launch (tests pass with their own mains)"
                ),
            }
        return {"checked": True, "ok": True}
    return {"checked": False}


def verify(
    store: CrewBoardStore,
    task: Task,
    *,
    project: Project | None = None,
    run_tests: bool = True,
) -> VerifyResult:
    """Run all three signals; persist results into task.verify_results.
    `project` overrides the lookup so a parallel task can be verified
    against its own worktree checkout."""
    if project is None:
        project = store.get_project(task.project_slug)
    if project is None:
        return VerifyResult(
            ok=False, reason=f"unknown project {task.project_slug!r}",
        )
    tests = _run_tests(project) if run_tests else {"ran": False, "reason": "skipped"}
    files = _check_files(task, project)
    criteria = _check_criteria(task)
    # Smoke gate (A1+A7): a task may carry a `smoke_cmd` — a shell
    # command run AFTER pytest in the project dir. Non-zero exit fails
    # the tier. This catches "tests pass but the live binary is broken"
    # bugs like the all-black-fog StarCraftHive screen, where every
    # unit test mocked the state and the cross-module integration was
    # never exercised.
    smoke = _run_smoke(task, project) if run_tests else {"ran": False}
    # #177 gates: a task can't be "done" on green tests alone.
    #   - false-done gate: clean tree AND no commit referencing the task = no
    #     work was produced (example-app T-0375 was marked done with zero diff).
    #   - boot gate: an app must be launchable, not merely test-green (the tetris
    #     no-main() bug: 79 tests passed but the app had no entry point).
    commit = _check_commit(task, project) if run_tests else {"checked": False}
    entry = _check_entrypoint(task, project)
    # Auto-Ok rules (gates the move-to-review):
    #   - tests didn't fail (exit code 0 OR not configured)
    #   - all files-of-interest globs matched
    #   - smoke command (if any) exited 0
    # Note: acceptance criteria are checked by the owner during human
    # review, NOT by the verifier. Otherwise a fully-working agent run
    # would stall forever because nobody had ticked the boxes.
    # A test_cmd that is CONFIGURED but couldn't run (spawn failure or a
    # missing project path) must FAIL the gate — it is a broken environment,
    # not "no tests". Only a genuinely-absent test_cmd ("no test_cmd
    # configured") or an explicitly skipped run is permissive. This closes a
    # false-positive where e.g. `flutter test` failing to spawn auto-passed.
    _tests_reason = tests.get("reason", "") or ""
    _spawn_failed = (not tests.get("ran")) and _tests_reason.startswith(
        ("could not spawn", "project path missing")
    )
    if _spawn_failed:
        tests_ok = False
    elif not tests.get("ran"):
        tests_ok = True  # no test_cmd configured / skipped — permissive (unchanged)
    elif tests.get("exit_code") == 0:
        tests_ok = True  # whole suite green
    else:
        # Non-zero exit. BASELINE-DIFF: pass iff every currently-failing test was
        # ALREADY failing when the chain started (captured by the pre-flight in
        # decompose_goal as crew_meta `preflight:failing:<slug>`). This stops a
        # pre-existing broken/flaky test from freezing a whole chain whose own
        # work is fine. Requires a captured baseline AND parseable failures;
        # otherwise fail strict (covers compile errors / crashes / timeouts where
        # nothing parses → no false pass).
        _baseline_raw = store.get_meta(f"preflight:failing:{project.slug}")
        _failed_ids = tests.get("failed_ids") or []
        if _baseline_raw is not None and _failed_ids:
            try:
                _baseline = set(json.loads(_baseline_raw))
            except (ValueError, TypeError):
                _baseline = set()
            _new = set(_failed_ids) - _baseline
            tests_ok = not _new
            if not tests_ok:
                tests["new_failures"] = sorted(_new)[:20]
        else:
            tests_ok = False
    smoke_ok = (
        not smoke.get("ran")  # no smoke_cmd configured is permissive
        or smoke.get("exit_code") == 0
    )
    commit_ok = (not commit.get("checked")) or commit.get("ok", True)
    entry_ok = (not entry.get("checked")) or entry.get("ok", True)
    ok = (
        tests_ok and files.get("all_present", True) and smoke_ok
        and commit_ok and entry_ok
    )
    reasons: list[str] = []
    if not tests_ok:
        if _spawn_failed:
            reasons.append(f"tests could not run: {_tests_reason}")
        else:
            _nf = tests.get("new_failures")
            if _nf:
                reasons.append(
                    f"tests failed — {len(_nf)} NEW failure(s) vs baseline: "
                    f"{_nf[:5]}"
                )
            else:
                reasons.append(
                    f"tests failed (exit={tests.get('exit_code')})"
                )
    if not files.get("all_present", True):
        missing = [g["glob"] for g in files.get("globs", []) if g["count"] == 0]
        reasons.append(f"files missing: {missing}")
    if not smoke_ok:
        reasons.append(
            f"smoke failed (exit={smoke.get('exit_code')}): "
            f"{smoke.get('stderr_tail', '')[:200]}"
        )
    if not commit_ok:
        reasons.append(commit.get("reason", "no committed work"))
    if not entry_ok:
        reasons.append(entry.get("reason", "app has no entry point"))
    # criteria_unchecked is informational only — it does NOT make ok=False.
    if not criteria.get("all_checked", False):
        reasons.append(
            f"(owner-review) {criteria.get('total', 0) - criteria.get('checked', 0)} "
            f"criteria unchecked"
        )
    # Outcome-proven: was actual behavior ever asserted by a runnable probe?
    # Tests passing alone is NOT sufficient — the pipeline has historically
    # shipped broken features (e.g. all-black dashboard panels) where every
    # test mocked the real system and nothing ran end-to-end. A smoke_cmd
    # that ran and exited 0 is the primary mechanism for proving behavior.
    # outcome_proven gates the auto-approve timeout path in the dispatcher;
    # it does NOT change `ok` (which gates promotion to review as before).
    if smoke.get("ran") and smoke.get("exit_code") == 0:
        outcome_proven = True
        outcome_reason = "smoke_cmd ran and exited 0"
    else:
        outcome_proven = False
        if not getattr(task, "smoke_cmd", None):
            outcome_reason = "no outcome probe configured (no smoke_cmd)"
        elif not smoke.get("ran"):
            outcome_reason = (
                f"smoke_cmd could not run: {smoke.get('reason', 'unknown')}"
            )
        else:
            outcome_reason = (
                f"smoke_cmd exited {smoke.get('exit_code')} (non-zero)"
            )
    result = VerifyResult(
        ok=ok,
        tests=tests,
        files=files,
        criteria=criteria,
        reason="; ".join(reasons),
        outcome_proven=outcome_proven,
        outcome_reason=outcome_reason,
    )
    store.update_verify_results(task.slug, {
        "ok": result.ok,
        "tests": result.tests,
        "files": result.files,
        "criteria": result.criteria,
        "smoke": smoke,
        "commit": commit,
        "entrypoint": entry,
        "reason": result.reason,
        "outcome_proven": result.outcome_proven,
        "outcome_reason": result.outcome_reason,
    })
    return result


def _run_smoke(task: Task, project: Project, *, timeout: float = 120.0) -> dict:
    """Run the task's `smoke_cmd` (if any) in the project dir. Non-zero
    exit means the integration is broken even though unit tests pass."""
    cmd = getattr(task, "smoke_cmd", None)
    if not cmd:
        return {"ran": False, "reason": "no smoke_cmd"}
    project_dir = Path(project.path)
    if not project_dir.is_dir():
        return {"ran": False, "reason": f"project path missing: {project_dir}"}
    try:
        proc = subprocess.run(
            shlex.split(cmd, posix=False),
            cwd=project_dir, capture_output=True, text=True,
            timeout=timeout, check=False,
        )
    except subprocess.TimeoutExpired:
        return {
            "ran": True, "exit_code": -1,
            "reason": f"smoke timeout after {timeout}s",
            "stdout_tail": "", "stderr_tail": "",
        }
    except (OSError, ValueError) as e:
        return {
            "ran": True, "exit_code": -2,
            "reason": f"could not spawn smoke: {e}",
            "stdout_tail": "", "stderr_tail": "",
        }
    return {
        "ran": True,
        "exit_code": proc.returncode,
        "reason": "",
        "stdout_tail": (proc.stdout or "")[-2000:],
        "stderr_tail": (proc.stderr or "")[-2000:],
    }
