"""Contract tests for the GitHub Actions workflows.

Purpose: keep CI honest — it must run the real suite on a blank machine, decide
         by exit code, and never hold a check that cannot be run locally.
Spec:    docs/spec_2026-08-18_downloadable_release.md#r-m3
Tests:   this file

Two global rules drive this file:

* **Never put a check only in the workflow.** Every assertion lives in the suite,
  where it can fail *before* a push; the workflow only invokes that suite. A
  check written as inline YAML cannot be run locally.
* **Decide success from the exit code** (P24). `2 failed, 2181 passed` contains
  the word "passed"; any step that greps for it reports green on a red run.

Workflows are inspected as text rather than parsed YAML on purpose: PyYAML is
not a dependency of this project, and adding one so the tests can read CI config
would be a poor trade. Every assertion here is a presence/absence check that
text handles correctly.

R-M4.C (release body from CHANGELOG.md) and R-M4.D (LICENSE and
THIRD_PARTY_NOTICES.md inside every archive) were held back during Phase 4
because their input files did not exist yet — a permanently red suite is worse
than no CI. Phase 5 created them, so they are covered below.
"""

from __future__ import annotations

import ast
import os
import re
import functools
import subprocess
import sys
import textwrap
from collections.abc import Iterable
from pathlib import Path

import pytest

# This whole file asserts on the REPOSITORY — workflows, packaging, licences,
# docs, traceability — not on application behaviour. Marked `meta` so
# `pytest -m "not meta"` gives a fast app-only run. The default `pytest` run
# still includes it: the marker is for speed, never for skipping.
pytestmark = pytest.mark.meta

REPO_ROOT = Path(__file__).resolve().parents[1]
WORKFLOW_DIR = REPO_ROOT / ".github/workflows"
TESTS_WORKFLOW = WORKFLOW_DIR / "tests.yml"

# Tokens that appear in a tool's output on success *and* alongside failures.
PASS_TOKENS = ("passed", "ok", "success", "succeeded")


def _workflows() -> list[Path]:
    return sorted(WORKFLOW_DIR.glob("*.yml")) + sorted(WORKFLOW_DIR.glob("*.yaml"))


def _run_step_lines(text: str) -> list[str]:
    """Every line belonging to a `run:` block in a workflow.

    Coarse but sufficient: a run block is `run:` followed by an indented body,
    and the checks below only ask whether certain shell constructs appear.
    """
    lines = text.splitlines()
    collected: list[str] = []
    in_run = False
    run_indent = 0

    for line in lines:
        stripped = line.strip()
        if not stripped or stripped.startswith("#"):
            continue
        indent = len(line) - len(line.lstrip())

        if in_run:
            if indent > run_indent:
                collected.append(stripped)
                continue
            in_run = False

        if re.match(r"^-?\s*run:\s*\|?>?-?\s*$", stripped):
            in_run, run_indent = True, indent
        elif stripped.startswith("run:"):
            collected.append(stripped[len("run:"):].strip())
        elif re.match(r"^-\s+run:\s*\S", stripped):
            # `- run: <command>` — run as a step's FIRST key, the same YAML
            # style this repo already uses for `- uses: actions/checkout@v7`.
            # It matched neither branch above, so the line was dropped before
            # any check saw it: `- run: pip install pytest` was invisible.
            collected.append(stripped.split("run:", 1)[1].strip())
    return collected


def _code_only(text: str) -> str:
    """Drop `#` comments so a check judges what a file *does*, not what it says.

    These workflows and scripts carry comments naming the very constructs the
    tests prohibit (`$LASTEXITCODE`, `--onefile`) in order to explain *why* they
    are prohibited. Matching on the explanation would pressure the next person
    into deleting the reasoning to get back to green.
    """
    out = []
    for line in text.splitlines():
        if line.strip().startswith("#"):
            continue
        out.append(line.split("#", 1)[0])
    return "\n".join(out)


# --------------------------------------------------------------------------
# R-M3.A — the workflow exists and runs the real suite on a blank machine
# --------------------------------------------------------------------------

def test_rm3a_tests_workflow_exists():
    assert TESTS_WORKFLOW.exists(), (
        "No .github/workflows/tests.yml. A repo with a test suite pushed to "
        "GitHub gets one — the blank machine is what catches what this Mac hides."
    )


def test_rm3a_tests_workflow_runs_on_ubuntu():
    assert "ubuntu-latest" in TESTS_WORKFLOW.read_text(encoding="utf-8")


# pip options that take a VALUE as the following token, on a command line.
#
# Deliberately NOT the licensing module's REQUIREMENT_OPTIONS_THAT_DECLARE_NOTHING.
# That set answers "does this requirements-file line declare a package?" and so
# contains bare boolean flags (--pre, --no-index, --require-hashes,
# --no-build-isolation). Reusing it here to mean "the previous token ate this
# one" made every package after such a flag invisible:
#
#     pip install --pre pyinstaller          -> pyinstaller not seen
#     pip install --no-index pyinstaller     -> pyinstaller not seen
#
# Two different questions. One shared set is what broke it (P5 cuts both ways:
# unify enumerations of the SAME concept, never of two that merely overlap).
PIP_OPTIONS_TAKING_A_VALUE = frozenset({
    "-r", "--requirement",
    "-c", "--constraint",
    "-i", "--index-url",
    "--extra-index-url",
    "-f", "--find-links",
    "--only-binary", "--no-binary",
    "--hash",
    "--trusted-host",
    "--use-feature", "--use-deprecated",
    "--global-option", "--config-settings",
    "-t", "--target",
    "--prefix",
    "--root", "--src",
    "--cache-dir",
    "--proxy",
    "--timeout",
    "--retries",
    "--python-version", "--python", "--platform", "--abi", "--implementation",
    "--cert", "--client-cert",
    "--log",
    "--upgrade-strategy",
    "--progress-bar",
    "--report",
    "--exists-action",
    "-e", "--editable",
})


def _consumes_the_next_token(previous: str) -> bool:
    """Did this argument already take its value, or does it eat the next one?"""
    if "=" in previous:
        # `--index-url=URL` has already consumed its value; the next token is a
        # package. The requirements-file parser strips at "=" for the opposite
        # reason, which is why these cannot share one rule.
        return False
    return previous in PIP_OPTIONS_TAKING_A_VALUE


def test_rm3a_tests_workflow_installs_from_the_real_dependency_file():
    """Installing an ad-hoc package list would defeat the point of the run.

    requirements-dev.txt is accepted because it starts with
    ``-r requirements.txt`` — asserted by
    ``tests/test_release_licensing.py::test_bi2_dev_requirements_pulls_in_the_runtime_set``,
    so the runtime set is still what CI installs.
    """
    text = TESTS_WORKFLOW.read_text(encoding="utf-8")
    # _code_only: reading the raw text meant
    # `# python -m pip install -r requirements-dev.txt` satisfied this while CI
    # installed nothing at all. The pip guard below already did this; this half
    # did not.
    installs = re.findall(r"-r\s+(requirements(?:-dev)?\.txt)", _code_only(text))
    assert installs, (
        "tests.yml must install from requirements.txt or requirements-dev.txt, "
        "so a missing or wrong dependency declaration fails CI instead of "
        "passing on a warm machine."
    )
    # Judge the code, not the comments; and allow pip's own flags before -r,
    # so `pip install -q -r requirements.txt` is not read as a named package.
    # Searched anywhere in the line, and pip[0-9]*: anchoring on an optional
    # "python -m " prefix made the guard blind to `python3 -m pip install X`,
    # `pip3 install X` and `sudo pip install X` — three spellings it used to
    # catch. A silent miss here is exactly what it exists to prevent.
    for line in _run_step_lines(_code_only(text)):
        # `pip [global options] install ...`: requiring `install` as the very
        # next token let `pip --no-cache-dir install X` through untouched.
        match = re.search(r"\bpip[0-9]*\s+(?:-\S+(?:\s+\S+)?\s+)*?install\b(.*)$",
                          line.strip())
        if not match:
            continue
        args = match.group(1).split()
        if args == ["--upgrade", "pip"]:
            continue
        named = [
            a for i, a in enumerate(args)
            if not a.startswith("-")
            and (i == 0 or not _consumes_the_next_token(args[i - 1]))
        ]
        assert not named, (
            f"tests.yml installs {named} by name: {line!r}. Every dependency "
            "must come from a requirements file, or CI stops being the "
            "blank-machine check."
        )


def test_rm3a_tests_workflow_invokes_pytest():
    assert re.search(r"\bpytest\b", TESTS_WORKFLOW.read_text(encoding="utf-8"))


def test_rm3a_matrix_covers_the_python_version_the_readme_claims():
    """README says 3.11+; CI must at least run the claimed minimum."""
    readme = (REPO_ROOT / "README.md").read_text(encoding="utf-8")
    claimed = re.search(r"Python (\d+)\.(\d+)\+", readme)
    assert claimed, "README no longer states a claimed minimum Python version"
    minimum = f"{claimed.group(1)}.{claimed.group(2)}"

    text = TESTS_WORKFLOW.read_text(encoding="utf-8")
    versions = re.findall(r"['\"](\d+\.\d+)['\"]", text)
    assert minimum in versions, (
        f"README claims Python {minimum}+ but tests.yml does not run {minimum}. "
        f"Versions found: {sorted(set(versions))}"
    )


def test_rm3a_tests_workflow_runs_on_push_and_pull_request():
    text = TESTS_WORKFLOW.read_text(encoding="utf-8")
    assert "push:" in text and "pull_request:" in text, (
        "tests.yml should run on both push and pull_request; a suite that only "
        "runs on one is a suite half the changes never meet."
    )


# --------------------------------------------------------------------------
# The `meta` marker — speed, never silent coverage loss
# --------------------------------------------------------------------------

META_TEST_FILES = {
    "tests/test_ci_contract.py",
    # SAG-M2: the docs-sync rule, which asserts on the repo's own
    # documents and on tools/, not on application behaviour.
    "tests/test_docs_sync_rule.py",
    "tests/test_release_licensing.py",
    "tests/test_packaging_filters.py",
    "tests/test_packaging_resources.py",
    "tests/test_release_docs.py",
    "tests/test_repo_hygiene.py",
    "tests/test_traceability_refs.py",
    "tests/test_no_vacuous_tests.py",
    # CIV-M4: the colour-inventory gate asserts on a generated document and on
    # tools/, not on application behaviour.
    "tests/test_color_inventory_sync.py",
}


@functools.lru_cache(maxsize=None)
def _collected_files(marker_expression: str | None) -> set[str]:
    """Files pytest actually collects, optionally under a -m filter.

    Driven through a real collection rather than by reading source for
    `pytestmark`: the marker's effect is what matters, and a source check would
    pass on a file where the assignment is shadowed or conditional.
    """
    argv = [sys.executable, "-m", "pytest", "--collect-only", "-q"]
    if marker_expression:
        argv += ["-m", marker_expression]
    result = subprocess.run(
        argv, cwd=str(REPO_ROOT), capture_output=True, text=True, timeout=600,
    )
    assert result.returncode == 0, f"collection failed:\n{result.stdout}\n{result.stderr}"
    return {
        line.split("::", 1)[0].strip()
        for line in result.stdout.splitlines()
        if "::" in line
    }


def test_meta_marker_covers_exactly_the_repo_assertion_files():
    """A new test in one of these files must inherit the marker.

    Module-level `pytestmark` gives that for free, which is why it is used —
    but nothing said so, and a file added to the set later could easily be
    marked per-function and miss one.
    """
    marked = _collected_files("meta")
    assert marked == META_TEST_FILES, (
        f"files carrying the `meta` marker: {sorted(marked)}\n"
        f"expected: {sorted(META_TEST_FILES)}\n"
        "Add the file to META_TEST_FILES, or give it "
        "`pytestmark = pytest.mark.meta`."
    )


def test_the_default_run_still_includes_the_meta_tests():
    """The marker is for speed. It must never become a silent skip.

    `pytest` with no -m must collect everything; only an explicit
    `-m "not meta"` narrows it. If addopts ever grew a default deselection,
    this is what would catch it.
    """
    everything = _collected_files(None)
    missing = sorted(META_TEST_FILES - everything)
    assert not missing, (
        f"the default pytest run does not collect {missing}. The `meta` marker "
        "is a speed switch for local iteration, not a way to stop running "
        "these — CI runs the default."
    )


def test_not_meta_is_actually_faster_by_deselecting_them():
    """Adversarial: prove the switch does something.

    If the two sets were equal the marker would be decoration, and the
    documented `pytest -m "not meta"` invocation would be a lie.
    """
    app_only = _collected_files("not meta")
    overlap = sorted(app_only & META_TEST_FILES)
    assert not overlap, (
        f"`-m 'not meta'` still collects {overlap}"
    )
    assert app_only, "`-m 'not meta'` collects nothing at all"


# --------------------------------------------------------------------------
# R-M3.B — GUI tests must run, not silently skip
# --------------------------------------------------------------------------

def _gui_test_files() -> list[Path]:
    """Test files that construct a real Tk root."""
    found = []
    for path in sorted((REPO_ROOT / "tests").glob("test_*.py")):
        text = path.read_text(encoding="utf-8")
        if "ctk.CTk()" in text or "tk.Tk()" in text:
            found.append(path)
    return found


def test_rm3b_there_are_gui_tests_to_protect():
    """If this ever hits zero, the guard below is guarding nothing."""
    assert _gui_test_files(), "no test file constructs a Tk root any more"


def test_rm3b_workflow_provides_a_virtual_display():
    """Without xvfb the GUI tests skip themselves and CI is green on nothing."""
    text = TESTS_WORKFLOW.read_text(encoding="utf-8")
    assert "xvfb" in text.lower(), (
        f"{len(_gui_test_files())} test files construct a Tk root and skip when "
        "no display exists. tests.yml must provide one (xvfb), or CI reports "
        "green while never running them."
    )


def test_rm3b_ui_tests_are_not_skipped_headless():
    """On CI, a Tk root must actually be constructible.

    The GUI tests skip on any exception from ``ctk.CTk()``. That is right
    locally, but on CI a silent skip is indistinguishable from a pass. This
    turns it into a loud failure.
    """
    if not os.environ.get("CI"):
        pytest.skip("only meaningful on CI, where a display must be provided")

    import customtkinter as ctk

    root = ctk.CTk()
    try:
        assert root.winfo_exists()
    finally:
        root.destroy()


# --------------------------------------------------------------------------
# R-M3.C — success comes from the exit code, never from scraping output (P24)
# --------------------------------------------------------------------------

def test_rm3c_no_workflow_greps_for_pass_token():
    """`2 failed, 2181 passed` matches a grep for "passed" and reads green."""
    offenders = []
    for wf in _workflows():
        for line in _run_step_lines(wf.read_text(encoding="utf-8")):
            lowered = line.lower()
            if "grep" not in lowered:
                continue
            if any(token in lowered for token in PASS_TOKENS):
                offenders.append(f"{wf.name}: {line}")
    assert not offenders, (
        "workflow steps decide success by grepping for a pass token, which also "
        f"matches on a failing run: {offenders}. Use the exit code."
    )


def test_rm3c_test_step_does_not_swallow_the_exit_code():
    """A trailing `|| true`, `continue-on-error`, or a pipe into another command
    hides a red suite."""
    text = TESTS_WORKFLOW.read_text(encoding="utf-8")
    assert "continue-on-error: true" not in text, (
        "continue-on-error on the test job makes a failing suite report green"
    )
    for line in _run_step_lines(text):
        if "pytest" in line:
            assert "|| true" not in line, f"exit code discarded: {line}"
            assert not re.search(r"pytest[^|]*\|[^|]", line), (
                f"pytest output piped into another command; the pipeline's exit "
                f"code is the last command's, not pytest's: {line}"
            )


# --------------------------------------------------------------------------
# R-M3.D — every test file is actually collected
# --------------------------------------------------------------------------

def test_rm3d_no_test_files_at_the_repo_root():
    strays = sorted(p.name for p in REPO_ROOT.glob("test_*.py"))
    assert not strays, (
        f"test files at the repo root: {strays}. Move them under tests/ so one "
        "run collects everything."
    )


# Directories whose test files pytest never collects, so this file must not
# report them as uncollected.
#
# ``.gmd-optout-probe`` is written and removed inside
# test_the_mapped_window_opt_out_is_off_by_default; ``.claude`` holds the
# desktop app's per-session git worktrees, each a full checkout with its own
# ``tests/`` tree. pytest's default norecursedirs skips dot-directories, so
# neither is ever collected — without these entries a killed run, or any
# worktree session, turns this assertion red against files that are not even
# part of this checkout.
UNCOLLECTED_DIRS = frozenset({
    "venv", ".venv", "dist", "build", ".git", "__pycache__",
    ".gmd-optout-probe", ".claude",
})


def is_outside_collection(path) -> bool:
    """True when pytest will never collect ``path`` because of its directory."""
    return any(part in UNCOLLECTED_DIRS for part in path.parts)


def test_rm3d_worktree_tests_are_not_counted_as_uncollected():
    """A session worktree's tests belong to that checkout, not this one.

    The desktop app puts each session's git worktree under
    ``.claude/worktrees/<name>/``, a full checkout carrying its own
    ``tests/`` tree. pytest skips dot-directories, so those files are never
    collected here and must not be reported as rotting. Before ``.claude``
    was excluded, opening one worktree session turned
    test_rm3d_all_test_files_are_collected red against 115 files that are
    not part of this working tree at all.
    """
    from pathlib import Path as _Path

    assert is_outside_collection(
        _Path(".claude/worktrees/some-session/tests/test_thing.py"))
    assert is_outside_collection(_Path("venv/lib/tests/test_vendored.py"))
    # The repo's own tests are still counted, or the assertion it guards
    # would pass by excluding everything.
    assert not is_outside_collection(_Path("tests/test_ci_contract.py"))
    assert not is_outside_collection(_Path("tests/test_ape_week_actions.py"))


def test_rm3d_all_test_files_are_collected():
    """Ask pytest what it collects and compare against what exists on disk."""
    on_disk = {
        p.relative_to(REPO_ROOT).as_posix()
        for p in REPO_ROOT.rglob("test_*.py")
        if not is_outside_collection(p)
    }
    assert on_disk, "no test files found at all — the glob is wrong"

    result = subprocess.run(
        [sys.executable, "-m", "pytest", "--collect-only", "-q"],
        cwd=str(REPO_ROOT), capture_output=True, text=True, timeout=600,
    )
    assert result.returncode == 0, f"collection failed:\n{result.stdout}\n{result.stderr}"

    collected = {
        line.split("::", 1)[0].strip()
        for line in result.stdout.splitlines()
        if "::" in line
    }
    missing = sorted(on_disk - collected)
    assert not missing, (
        f"test files that exist but are never collected: {missing}. They can "
        "rot silently — nothing runs them."
    )


def test_rm3d_every_test_file_is_importable_on_its_own(tmp_path):
    """Guards the bug the repo-root conftest.py fixed.

    Two relocated files imported ``getmoredone`` before their own sys.path
    insert ran, so they only worked when an alphabetically earlier file had
    already set the path. Run alone, they errored.

    ONE subprocess, not one per file.

    This used to run `pytest <file> --collect-only` for every test file — 91
    separate interpreter starts, each importing the whole application. It was
    the single heaviest thing in the suite and made a full run noticeably slow
    the machine it ran on.

    The child below imports each module with `sys.modules` reset between files,
    which is what the guarantee actually needs: a file that only works because
    an alphabetically earlier one already inserted `src/` on the path fails
    here, exactly as it did before.

    CIG-M1: the child gets ``GETMOREDONE_DATA_DIR``. It has no conftest, and
    six modules attach the weekly-tactic ``FileHandler`` at import time, so
    without the override this probe created the user's real
    ``weekly_tactic_debug.log`` -- on a fresh CI runner, where none existed,
    the session guard then failed the run. Asserted by the log appearing in
    ``tmp_path``: on a machine where the real file already exists, an
    append-mode open writes nothing, so watching the real file proves nothing.
    """
    probe = r"""
import importlib.util, pathlib, sys

root = pathlib.Path.cwd()
failures = []

# Only the PROJECT's modules are evicted between files. Clearing all of
# sys.modules re-imports C extensions, and objc refuses:
# "RuntimeError: Reload of objc._objc detected, this is not supported".
# Scoping it is also more honest — the bug being guarded is a file importing
# `getmoredone` before its own sys.path insert ran, which is about project
# modules and sys.path, not about third-party state.
PROJECT = ("getmoredone", "src", "tests", "conftest")

for path in sorted(root.glob("tests/test_*.py")):
    for name in [n for n in sys.modules
                 if n.split(".")[0] in PROJECT or n == path.stem]:
        sys.modules.pop(name, None)
    for entry in ("", str(root), str(root / "src")):
        while entry in sys.path:
            sys.path.remove(entry)
    spec = importlib.util.spec_from_file_location(path.stem, path)
    module = importlib.util.module_from_spec(spec)
    try:
        spec.loader.exec_module(module)
    except Exception as exc:
        failures.append("FAIL " + path.name + ": " + type(exc).__name__ + ": " + str(exc))

# Prefixed, because importing the app prints banners (pygame) to stdout and a
# bare line-split would count those as failures.
for line in failures:
    print(line)
"""
    env = dict(os.environ)
    env["GETMOREDONE_DATA_DIR"] = str(tmp_path)
    result = subprocess.run(
        [sys.executable, "-c", probe],
        cwd=str(REPO_ROOT), capture_output=True, text=True, timeout=300, env=env,
    )
    assert result.returncode == 0, (
        f"the import probe itself failed:\n{result.stdout}\n{result.stderr}"
    )
    assert (tmp_path / "weekly_tactic_debug.log").exists(), (
        "the probe's child did not log into the redirected data directory, "
        "so its imports opened the user's real weekly_tactic_debug.log")
    failures = [
        line[len("FAIL "):] for line in result.stdout.splitlines()
        if line.startswith("FAIL ")
    ]
    assert not failures, (
        f"test files that cannot be imported on their own: {failures}"
    )


# --------------------------------------------------------------------------
# R-M3.E — no check lives only in the workflow
# --------------------------------------------------------------------------

def test_rm3e_workflows_contain_no_inline_assertions():
    """A check written as YAML cannot fail before a push."""
    offenders = []
    for wf in _workflows():
        for line in _run_step_lines(wf.read_text(encoding="utf-8")):
            if re.search(r"\bassert\b", line):
                offenders.append(f"{wf.name}: {line}")
            if re.search(r"\bpython3?\s+-c\b", line):
                offenders.append(f"{wf.name}: {line}")
    assert not offenders, (
        "workflow steps contain checks that cannot be run locally: "
        f"{offenders}. Move the assertion into the pytest suite and have the "
        "workflow invoke the suite."
    )


def test_rm3e_run_step_parser_actually_finds_run_blocks():
    """Adversarial: an empty parser would make every check above vacuous."""
    sample = "\n".join([
        "jobs:",
        "  build:",
        "    steps:",
        "      - name: One",
        "        run: echo hello",
        "      - name: Two",
        "        run: |",
        "          grep passed out.txt",
        "          assert something",
        "      - uses: actions/checkout@v4",
    ])
    lines = _run_step_lines(sample)
    assert "echo hello" in lines
    assert "grep passed out.txt" in lines
    assert "assert something" in lines
    assert "uses: actions/checkout@v4" not in lines

    # And it finds real content in the checked-in workflows.
    assert any(_run_step_lines(wf.read_text(encoding="utf-8")) for wf in _workflows())


# --------------------------------------------------------------------------
# R-M4 — release pipeline hardening
# --------------------------------------------------------------------------

RELEASE_WORKFLOW = WORKFLOW_DIR / "build-release.yml"

# Where each OS job's packaged executable lands, per daVIPA.spec.
PACKAGED_EXECUTABLES = {
    "build-macos": "dist/daVIPA.app/Contents/MacOS/daVIPA",
    "build-windows": "daVIPA.exe",
}

# BI1 — the single job that creates the public GitHub Release.
PUBLISH_JOB = "publish"

# The artifact each OS job uploads, and the archive inside it.
BUILD_ARTIFACTS = {
    "build-windows": "daVIPA-win64",
    "build-macos": "daVIPA-mac",
}
RELEASE_ARCHIVES_BY_JOB = {
    "build-windows": "daVIPA-win64.zip",
    "build-macos": "daVIPA-mac.zip",
}
RELEASE_ARCHIVES = tuple(RELEASE_ARCHIVES_BY_JOB.values())


def _job_blocks(text: str) -> dict[str, str]:
    """Split a workflow into {job_name: job_text}."""
    lines = text.splitlines()
    try:
        start = next(i for i, l in enumerate(lines) if l.rstrip() == "jobs:")
    except StopIteration:
        return {}

    jobs: dict[str, list[str]] = {}
    current = None
    for line in lines[start + 1:]:
        if not line.strip() or line.strip().startswith("#"):
            if current:
                jobs[current].append(line)
            continue
        indent = len(line) - len(line.lstrip())
        match = re.match(r"^\s{2}([A-Za-z0-9_-]+):\s*$", line)
        if indent == 2 and match:
            current = match.group(1)
            jobs[current] = []
            continue
        if indent == 0:
            break
        if current:
            jobs[current].append(line)
    return {name: "\n".join(body) for name, body in jobs.items()}


def test_rm4_job_splitter_finds_both_os_jobs():
    """Adversarial: an empty splitter makes every R-M4 check below vacuous."""
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    assert set(PACKAGED_EXECUTABLES).issubset(jobs), (
        f"expected jobs {sorted(PACKAGED_EXECUTABLES)}, found {sorted(jobs)}"
    )
    for name in PACKAGED_EXECUTABLES:
        assert "pyinstaller" in jobs[name].lower(), f"{name} body looks empty"


# R-M4.A — the packaged bundle must prove it starts

def test_rm4a_release_workflow_runs_selftest_on_the_packaged_bundle():
    """Every OS job must run --selftest against the BUILT executable.

    This is the automated guard against F1 recurring. Running
    `python run.py --selftest` instead would test the source tree, which is
    exactly the thing that was never broken.
    """
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job, executable in PACKAGED_EXECUTABLES.items():
        body = jobs[job]
        assert "--selftest" in body, f"{job} never runs --selftest on its build"
        assert executable in body, (
            f"{job} runs --selftest but not against {executable}"
        )


def test_rm4a_selftest_does_not_run_from_source():
    """`python run.py --selftest` in a release job would prove nothing."""
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        assert not re.search(r"python\s+run\.py\s+--selftest", jobs[job]), (
            f"{job} selftests the source tree, not the packaged bundle"
        )


def test_rm4a_selftest_runs_after_the_build():
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        body = jobs[job]
        assert body.lower().index("pyinstaller") < body.index("--selftest"), (
            f"{job} runs --selftest before it builds anything"
        )


def test_rm4a_selftest_runs_before_anything_is_published():
    """A bundle that cannot start must never reach an artifact or a release."""
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        body = jobs[job]
        selftest_at = body.index("--selftest")
        for publish in ("upload-artifact", "action-gh-release"):
            if publish in body:
                assert selftest_at < body.index(publish), (
                    f"{job} publishes via {publish} before the selftest runs"
                )


def test_rm4a_windows_job_waits_for_the_windowed_exe_and_reads_its_exit_code():
    """daVIPA.exe is console=False, so `& app.exe` does not wait for it.

    Observed on run 32191324517: the step threw "Packaged build failed its
    selftest (exit )" — $LASTEXITCODE unset — while the selftest was still
    running, and it then reported 4/4 checks passed. The shell had already
    moved on. Only Start-Process -Wait -PassThru yields a real exit code for a
    windowed-subsystem process.
    """
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))["build-windows"])
    selftest_at = body.index("--selftest")
    # Look at the step containing the selftest, not the whole job.
    step = body[max(0, selftest_at - 800):selftest_at + 800]

    assert "Start-Process" in step and "-Wait" in step, (
        "the Windows selftest must use Start-Process -Wait: a windowed exe "
        "launched with & returns immediately and the job checks nothing"
    )
    assert "PassThru" in step and "ExitCode" in step, (
        "the Windows selftest must read .ExitCode from the waited process"
    )


def test_rm4a_windows_selftest_does_not_rely_on_lastexitcode():
    """$LASTEXITCODE is empty after launching a windowed exe, so `-ne 0` is
    always true and the step fails even on a healthy build."""
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))["build-windows"])
    selftest_at = body.index("--selftest")
    step = body[max(0, selftest_at - 800):selftest_at + 800]
    assert "LASTEXITCODE" not in step, (
        "the Windows selftest step still consults $LASTEXITCODE, which a "
        "windowed exe never sets"
    )


def test_rm4a_local_windows_build_script_waits_too():
    """Same bug class in build_windows.ps1 — fix one, fix the siblings (P5)."""
    script = _code_only((REPO_ROOT / "build_windows.ps1").read_text(encoding="utf-8"))
    if "--selftest" not in script:
        pytest.skip("build_windows.ps1 does not run a selftest")
    assert "Start-Process" in script and "-Wait" in script and "ExitCode" in script, (
        "build_windows.ps1 launches the windowed exe without waiting for it, so "
        "its selftest check is decorative"
    )
    assert "LASTEXITCODE" not in script, (
        "build_windows.ps1 still consults $LASTEXITCODE for a windowed exe"
    )


def test_rm4a_selftest_uses_a_scratch_database():
    """The selftest must not be pointed at whatever default path the runner has."""
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        assert "GETMOREDONE_DB" in jobs[job], (
            f"{job} should give --selftest an explicit scratch DB path"
        )


# R-M4.B — checksums published beside each artifact

def test_rm4b_release_workflow_publishes_checksums():
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        body = jobs[job].lower()
        assert "sha256" in body, f"{job} publishes no SHA-256 checksum"


def test_rm4b_checksum_files_are_uploaded_as_artifacts():
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        body = jobs[job]
        assert ".sha256" in body, (
            f"{job} computes a checksum but never uploads a .sha256 file"
        )


def test_rm4b_checksums_reach_the_github_release():
    """A checksum only in the Actions artifact does not help a downloader.

    Since BI1 there is one release step, in the publish job, so this asserts
    every platform's .sha256 is attached by it — the per-job form of this check
    would now pass while the publish job attached only one platform's.
    """
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    release_at = body.find("action-gh-release")
    assert release_at != -1, "the publish job has no release step"
    attached = body[release_at:]
    for archive in RELEASE_ARCHIVES:
        assert f"{archive}.sha256" in attached, (
            f"{archive}.sha256 is not attached to the GitHub Release"
        )


# R-M4.C — release body comes from CHANGELOG.md

def test_rm4c_release_body_sourced_from_changelog():
    """Typed-by-hand release notes drift from the repo; generated ones cannot."""
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    assert "body_path" in body, "the publish job publishes a release with no notes"
    assert "extract_release_notes" in body, (
        "the publish job does not generate its notes from CHANGELOG.md"
    )


def test_rm4c_extractor_script_exists_and_is_not_inline_yaml():
    """R-M3.E: the logic must be runnable and testable outside CI."""
    script = REPO_ROOT / "tools/extract_release_notes.py"
    assert script.exists(), (
        "the workflow calls tools/extract_release_notes.py but it does not exist"
    )
    assert (REPO_ROOT / "tests/test_release_notes.py").exists(), (
        "the extractor has no tests, so CI is the only place it is exercised"
    )


def test_rm4c_notes_are_generated_before_the_release_step():
    # _code_only: the job's comment explains the two-release defect by name,
    # and matching the explanation would order the prose, not the steps.
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    assert body.index("extract_release_notes") < body.index("action-gh-release"), (
        "the publish job generates its release notes after publishing the release"
    )


# R-M4.D — LICENSE and notices travel inside the archive

REQUIRED_ARCHIVE_FILES = ("LICENSE", "THIRD_PARTY_NOTICES.md", "licenses")


def test_rm4d_licence_files_reach_every_archive():
    """Two routes, one requirement.

    macOS relies on daVIPA.spec, which bundles the files into
    Contents/Resources. Windows adds a copy at the folder root as well, because
    a user who unzips sees only daVIPA.exe and _internal/ — a licence
    buried in there is not "included" in any useful sense.
    """
    spec = _code_only((REPO_ROOT / "daVIPA.spec").read_text(encoding="utf-8"))
    for required in REQUIRED_ARCHIVE_FILES:
        assert required in spec, (
            f"daVIPA.spec must bundle {required} — it is the only route "
            "that puts it inside the macOS archive (R-M4.D)"
        )

    windows = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))["build-windows"])
    for required in ("LICENSE", "THIRD_PARTY_NOTICES.md"):
        assert required in windows, (
            f"the Windows job should place {required} beside the executable"
        )


def test_rm4d_macos_job_does_not_restage_what_the_spec_already_bundles():
    """Regression: `cp -R licenses dest/licenses` when dest/licenses already
    exists copies *into* it, producing Resources/licenses/licenses/.

    Observed in run 32193099401. The spec is the single source on macOS.
    """
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))["build-macos"])
    assert "cp -R licenses" not in body, (
        "the macOS job copies licenses/ into a directory the spec already "
        "created, which nests it one level deeper"
    )
    assert "Contents/Resources/licenses" not in body, (
        "the macOS job stages into Contents/Resources/licenses, which the spec "
        "already populates"
    )


def test_rm4d_windows_licence_files_are_staged_before_the_archive_is_made():
    """Copying them after the zip step would ship an archive without them."""
    body = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))["build-windows"]
    assert body.index("THIRD_PARTY_NOTICES.md") < body.index("Compress-Archive"), (
        "the Windows job stages the licence files after zipping"
    )


def test_rm4d_required_archive_files_exist_in_the_repo():
    """The workflow copies these by name; a rename would fail the job."""
    missing = [f for f in REQUIRED_ARCHIVE_FILES if not (REPO_ROOT / f).exists()]
    assert not missing, f"the release workflow copies files that do not exist: {missing}"


def test_no_workflow_disables_the_mapped_window_tests():
    """The local focus-stealing opt-out must never become a CI default.

    ``GETMOREDONE_NO_MAPPED_WINDOWS`` makes the tests that read real Tk
    geometry skip, so the suite can run on a machine someone is working on.
    Set in CI it would turn the only coverage of the sash-drag and pin-drag
    contracts into a permanent silent skip.
    """
    from conftest import NO_MAPPED_WINDOWS_ENV

    offenders = [
        wf.name for wf in _workflows()
        if NO_MAPPED_WINDOWS_ENV in wf.read_text(encoding="utf-8")
    ]
    assert not offenders, (
        f"{offenders} set GETMOREDONE_NO_MAPPED_WINDOWS. That variable is a "
        "local convenience for not stealing focus; in CI it silently skips the "
        "geometry tests."
    )


def _mapped_window_test_count() -> int:
    """How many tests actually take the ``mapped_windows`` fixture.

    By AST rather than by a text search: ``mapped_windows`` appears in
    docstrings, in comments and in this file, and a grep count would include
    all of them.

    The request is read by ``display_capabilities.fixture_names``, the same
    function the read-back detector uses, so the two cannot disagree about
    what asking for the fixture looks like.
    """
    from tests.display_capabilities import fixture_names

    total = 0
    for path in sorted((REPO_ROOT / "tests").glob("test_*.py")):
        tree = ast.parse(path.read_text(encoding="utf-8"))
        for node in ast.walk(tree):
            if isinstance(node, (ast.FunctionDef, ast.AsyncFunctionDef)):
                if not node.name.startswith("test_"):
                    continue
                if "mapped_windows" in fixture_names(node):
                    total += 1
    return total


def test_the_fixture_request_is_read_the_same_way_by_both_guards():
    """A test that asks for the fixture by mark is counted, not just cleared.

    Purpose: the read-back detector was widened to accept
             `@pytest.mark.usefixtures("mapped_windows")` and keyword-only
             parameters; this counter still read `node.args.args`, so a new
             on-screen-window test written either way would have passed the
             detector and left the documented count untouched.
    Tests:   this test
    """
    from tests.display_capabilities import fixture_names

    source = textwrap.dedent("""
        @pytest.mark.usefixtures("mapped_windows")
        def test_by_mark():
            pass

        def test_by_keyword(*, mapped_windows):
            pass

        def test_positionally(mapped_windows):
            pass

        def test_not_at_all():
            pass
    """)
    asked = {node.name for node in ast.walk(ast.parse(source))
             if isinstance(node, ast.FunctionDef)
             and "mapped_windows" in fixture_names(node)}

    assert asked == {"test_by_mark", "test_by_keyword", "test_positionally"}, (
        f"the fixture request was read as {sorted(asked)}; a shape this misses "
        "is a real window the documented count does not mention")


def test_the_documented_mapped_window_count_is_the_real_one():
    """CLAUDE.md and conftest state how many tests put a window on screen.

    Purpose: a number in prose that nothing checks drifts, and this one did
             twice -- conftest said "three" and CLAUDE.md "Ten" while nineteen
             tests took the fixture. The count is what tells a reader how much
             the documented local workflow skips, so a stale one understates
             what a green local run did not cover.
    Spec:    CLAUDE.md -- the GETMOREDONE_NO_MAPPED_WINDOWS workflow
    Tests:   this test

    An exact count, not a floor: a floor hides the narrowing it exists to
    catch, and a test that no longer needs a real window should lose the
    fixture rather than quietly keep it.
    """
    actual = _mapped_window_test_count()
    pattern = re.compile(r"\b(\d+) tests (?:build a real|it disables)")

    for relative in ("CLAUDE.md", "conftest.py"):
        text = (REPO_ROOT / relative).read_text(encoding="utf-8")
        stated = pattern.findall(text)
        assert len(stated) == 1, (
            f"{relative} states the mapped-window count {len(stated)} times; "
            "exactly one place per file keeps it fixable"
        )
        assert int(stated[0]) == actual, (
            f"{relative} says {stated[0]} tests put a window on screen; "
            f"{actual} take the mapped_windows fixture"
        )


def test_the_mapped_window_opt_out_is_off_by_default():
    """A default-on escape hatch is the same silent skip by another route.

    Driven as a real subprocess. The string form of this test passed with the
    condition INVERTED — the substring it looked for is still present in
    ``if not os.environ.get(...)`` — which would have skipped the three
    geometry tests on every machine, CI included, leaving a skip count as the
    only signal.

    The nested target is a **probe file this test writes**, not the real
    geometry test. It requests the ``mapped_windows`` fixture and asserts
    nothing else, so the fixture's decision is exercised and no window is ever
    mapped. An earlier version ran the real geometry test, which meant this
    test took keyboard focus twice on every run — and it then had to skip
    itself when the opt-out was set, so under the project's own documented
    local command it did not run at all. A guard that is disabled by the thing
    it guards is not a guard.

    The probe lives under the repo root so root ``conftest.py`` applies to it.
    """
    probe_dir = REPO_ROOT / ".gmd-optout-probe"
    probe = probe_dir / "test_probe.py"

    from conftest import NO_MAPPED_WINDOWS_ENV

    def _run(env_value):
        env = dict(os.environ)
        env.pop(NO_MAPPED_WINDOWS_ENV, None)
        if env_value is not None:
            env[NO_MAPPED_WINDOWS_ENV] = env_value
        # No -rs here on purpose: pytest.ini's addopts must be what produces
        # the skip reason, so deleting that line fails this test.
        return subprocess.run(
            [sys.executable, "-m", "pytest", str(probe), "-q", "--no-header"],
            cwd=str(REPO_ROOT), capture_output=True, text=True, timeout=120, env=env,
        )

    def _describe(result):
        return (
            f"exit={result.returncode}\n"
            f"--- stdout ---\n{result.stdout[-1500:]}\n"
            f"--- stderr ---\n{result.stderr[-1500:]}"
        )

    probe_dir.mkdir(exist_ok=True)
    try:
        probe.write_text(
            "def test_probe(mapped_windows):\n"
            "    # Requests the fixture and builds nothing. The point is the\n"
            "    # fixture's skip decision, not a window.\n"
            "    assert True\n",
            encoding="utf-8",
        )

        # Success is the EXIT CODE, not a token in stdout — this file's own
        # docstring forbids the latter (P24), and this repo's
        # pytest_sessionfinish sets a non-zero status with no FAILURES section.
        unset = _run(None)
        assert unset.returncode == 0 and "1 passed" in unset.stdout, (
            "with GETMOREDONE_NO_MAPPED_WINDOWS unset the fixture must let the "
            f"test RUN.\n{_describe(unset)}"
        )

        on = _run("1")
        assert on.returncode == 0, f"a skipped test must still exit 0.\n{_describe(on)}"
        assert "1 skipped" in on.stdout, (
            f"GETMOREDONE_NO_MAPPED_WINDOWS=1 must skip it.\n{_describe(on)}"
        )
        assert NO_MAPPED_WINDOWS_ENV in on.stdout, (
            "the skip REASON must be printed, so a suppressed run cannot be "
            "mistaken for a passing one. This depends on addopts = -rs in "
            f"pytest.ini.\n{_describe(on)}"
        )

        # Imported, not re-spelled: a second copy here would drift from the
        # one conftest actually uses, which is the duplication this commit's
        # own sibling fix argued against.
        import conftest

        # Upper-case forms included deliberately: every value in conftest's
        # tuple is lowercase, so a loop over it alone never exercises .lower()
        # and removing that call passed. "FALSE"/"OFF"/"No" would then silently
        # turn the opt-out ON.
        # ONE representative off-value, not eight. Each iteration is a nested
        # pytest process, and eight of them made a full suite run noticeably
        # heavy on the machine someone is working on. The parsing itself is
        # covered in-process by test_the_opt_out_values_are_not_duplicated.
        for off_value in ["FALSE"]:
            off = _run(off_value)
            assert off.returncode == 0 and "1 passed" in off.stdout, (
                f"GETMOREDONE_NO_MAPPED_WINDOWS={off_value!r} must mean OFF. A "
                "bare truthiness check makes every one of these turn the "
                f"opt-out ON.\n{_describe(off)}"
            )
    finally:
        # rmtree, not rmdir: the nested pytest run leaves a __pycache__ behind.
        # NOT ignore_errors: a cleanup that silently fails leaves
        # .gmd-optout-probe/test_probe.py on disk, and the next run fails in
        # test_rm3d_all_test_files_are_collected with a message pointing at
        # the wrong problem (P2 — a silent drop whose consequence surfaces
        # somewhere else).
        import shutil

        shutil.rmtree(probe_dir)
        assert not probe_dir.exists(), (
            f"could not remove {probe_dir}; a leftover probe file makes "
            "test_rm3d_all_test_files_are_collected fail on the next run"
        )


def test_the_opt_out_values_are_not_duplicated_across_modules():
    """One enumeration, imported — not two that drift.

    The guard test used to re-spell both the variable name and the whole falsy
    tuple, in the same commit that argued against exactly that duplication.
    """
    import ast

    import conftest

    assert conftest.NO_MAPPED_WINDOWS_ENV == "GETMOREDONE_NO_MAPPED_WINDOWS"
    for off_value in ("", "0", "false", "no", "off", "n"):
        assert off_value in conftest.NO_MAPPED_WINDOWS_OFF_VALUES, (
            f"{off_value!r} is no longer treated as 'off', so setting the "
            "variable to it would silently turn the opt-out ON"
        )

    # And no module may keep a SECOND copy. Asserting the six strings are still
    # in conftest's tuple is not a duplication check — a drifted copy elsewhere
    # left that green, which is what the name promises and did not deliver.
    tree = ast.parse(Path(__file__).read_text(encoding="utf-8"))
    duplicates = []
    for node in ast.walk(tree):
        if isinstance(node, ast.Assign):
            literal = ast.dump(node.value)
            if '"GETMOREDONE_NO_MAPPED_WINDOWS"' in literal.replace("'", '"'):
                duplicates.append(f"line {node.lineno}: the env var name")
            if literal.count("Constant") >= 4 and all(
                f"'{v}'" in literal or f'"{v}"' in literal for v in ("0", "false", "off")
            ):
                duplicates.append(f"line {node.lineno}: the off-values tuple")
    assert not duplicates, (
        f"a second copy of conftest's opt-out constants lives here: "
        f"{duplicates}. Import NO_MAPPED_WINDOWS_ENV / "
        "NO_MAPPED_WINDOWS_OFF_VALUES instead — two copies drift and only one "
        "of them is the one the fixture reads."
    )


# --------------------------------------------------------------------------
# BI1 (D1) — one release call, gated on every build succeeding
# --------------------------------------------------------------------------
#
# A GitHub Release is public and permanent the moment it is created, and a
# later job failing does not un-publish it. Two release calls therefore had a
# failure mode with no rollback: the first job to finish created the Release,
# the second failed, and the download page kept serving one platform's assets
# under a version number claiming both.
#
# None of this can be tested by running it. These assertions over the YAML are
# the only check that exists before a real tagged run.

def test_bi1_exactly_one_job_publishes_the_release():
    """The whole of BI1. Two calls is the defect; one is the fix."""
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    publishers = sorted(
        name for name, body in jobs.items()
        if "action-gh-release" in _code_only(body)
    )
    assert publishers == [PUBLISH_JOB], (
        f"expected only {PUBLISH_JOB!r} to call action-gh-release, found "
        f"{publishers}. Two publishing jobs can leave a public Release "
        "carrying one platform's assets when the other build fails."
    )


def test_bi1_publish_job_waits_for_every_build_job():
    """`needs:` is what makes a half-succeeded run publish nothing.

    Derived from the job list rather than a written-out pair, so a third OS
    job added later fails this until it is added to `needs:` too.
    """
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    body = _code_only(jobs[PUBLISH_JOB])
    match = re.search(r"needs:\s*\[([^\]]*)\]", body)
    assert match, f"the {PUBLISH_JOB} job declares no needs: [...]"
    declared = {n.strip() for n in match.group(1).split(",") if n.strip()}

    build_jobs = set(PACKAGED_EXECUTABLES)
    missing = sorted(build_jobs - declared)
    assert not missing, (
        f"the {PUBLISH_JOB} job does not wait for {missing}. Without it that "
        "build can fail while the Release is published anyway."
    )


def test_bi1_publish_job_downloads_every_build_artifact():
    """A release call that names a file no step produced publishes nothing.

    ``fail_on_unmatched_files: true`` turns that into a failed job rather than
    an empty Release, but only after the tag exists. This catches it here.
    """
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    assert "download-artifact" in body, (
        "the publish job never downloads the builds it is publishing"
    )
    for job, artifact in BUILD_ARTIFACTS.items():
        assert re.search(rf"^\s*name:\s*{re.escape(artifact)}\s*$", body, re.MULTILINE), (
            f"the publish job does not download exactly {artifact}, uploaded "
            f"by {job}"
        )


def test_bi1_uploaded_artifact_names_match_what_publish_downloads():
    """Producer/consumer contract (P19).

    The upload name and the download name are one contract across two jobs.
    A rename on either side yields "artifact not found" at release time — after
    both builds have run, on a tag that already exists.
    """
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job, artifact in BUILD_ARTIFACTS.items():
        # Line-anchored: `name: daVIPA-win64` is a SUBSTRING of
        # `name: daVIPA-win64-x86`, so a suffix rename on one side only
        # stayed green — and on a real tag that is download-artifact failing
        # after both builds have run. Third instance of this class in this
        # batch; see LEARNINGS.md.
        assert re.search(rf"^\s*name:\s*{re.escape(artifact)}\s*$",
                         _code_only(jobs[job]), re.MULTILINE), (
            f"{job} does not upload an artifact named exactly {artifact}, "
            "which the publish job downloads by that name"
        )


def test_bi1_every_built_archive_is_attached_to_the_release():
    """Both platforms, one Release. The point of the change."""
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    release_at = body.find("action-gh-release")
    attached = body[release_at:]
    for archive in RELEASE_ARCHIVES:
        # Anchored on the archive ENDING the line: a bare `archive in attached`
        # is satisfied by the ".sha256" entry alone.
        assert re.search(rf"{re.escape(archive)}\s*$", attached, re.MULTILINE), (
            f"{archive} is not attached to the Release (its .sha256 alone does "
            "not count). A run that publishes one platform, or only checksums, "
            "is the failure BI1 exists to prevent."
        )


def test_bi1_no_os_job_publishes_a_release():
    """State it from the other side too.

    ``test_bi1_exactly_one_job_publishes_the_release`` is the general rule;
    this names the specific regression, so a diff that reintroduces a release
    step inside build-windows gets a message that says so.
    """
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        assert "action-gh-release" not in _code_only(jobs[job]), (
            f"{job} publishes a GitHub Release. Publishing belongs in the "
            f"{PUBLISH_JOB} job, which runs only after every build succeeded."
        )


def _job_level_if(job_body: str) -> str | None:
    r"""The job's own ``if:`` value, including block-scalar continuation lines.

    Job-level keys sit at a known indent (4 spaces inside ``jobs: <name>:``),
    so the value is that line's remainder plus every following line indented
    deeper, up to the next job-level key.

    Neither looser form works. Anchoring on ``^\s*if:.*refs/tags/v`` misses a
    block scalar (``if: >`` with the expression beneath). Searching the whole
    body instead accepts the string appearing on a *step's* ``if:`` — so
    deleting the job gate entirely and putting it on the checksum step passed,
    leaving the publish step ungated and a workflow_dispatch with a blank
    release_tag cutting a Release named after the branch.
    """
    lines = job_body.splitlines()
    for i, line in enumerate(lines):
        match = re.match(r"^(\s{4})if:(.*)$", line)
        if not match:
            continue
        indent, value = len(match.group(1)), [match.group(2).strip()]
        for following in lines[i + 1:]:
            if not following.strip():
                continue
            if len(following) - len(following.lstrip()) <= indent:
                break
            value.append(following.strip())
        return " ".join(v for v in value if v)
    return None


def test_bi1_publish_job_is_gated_on_a_tag():
    """Without the gate, every push to a branch would cut a Release."""
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    condition = _job_level_if(body)
    assert condition, f"the {PUBLISH_JOB} job has no job-level if: condition"
    assert "refs/tags/v" in condition, (
        f"the {PUBLISH_JOB} job's own if: does not gate on a tag: {condition!r}. "
        "A gate on one of its steps does not stop the release step running."
    )


def test_bi1_job_level_if_parser_finds_block_scalars():
    """Adversarial: a parser that returns None makes the two tests above pass
    vacuously, and one that stops at the first line misses the case it exists
    for."""
    inline = "    if: startsWith(github.ref, 'refs/tags/v')\n    runs-on: ubuntu-latest\n"
    assert _job_level_if(inline) == "if: startsWith(github.ref, 'refs/tags/v')".split("if:")[1].strip()

    block = (
        "    if: >\n"
        "      always() &&\n"
        "      startsWith(github.ref, 'refs/tags/v')\n"
        "    runs-on: ubuntu-latest\n"
    )
    captured = _job_level_if(block)
    assert "always()" in captured, f"block scalar not captured: {captured!r}"
    assert "refs/tags/v" in captured

    # A step-level if: is not the job's — in BOTH step spellings.
    #
    # The dash form alone did not separate a correct parser from a relaxed one:
    # `^\\s+if:` cannot match a dash line either, so `^(\\s{4})if:` -> `^(\\s+)if:`
    # passed. The 8-space form under `- name:` is what distinguishes them, and
    # it is the form a real workflow uses.
    dash_form = (
        "    runs-on: ubuntu-latest\n"
        "    steps:\n"
        "      - if: startsWith(github.ref, 'refs/tags/v')\n"
    )
    assert _job_level_if(dash_form) is None

    named_step_form = (
        "    runs-on: ubuntu-latest\n"
        "    steps:\n"
        "      - name: Publish\n"
        "        if: startsWith(github.ref, 'refs/tags/v')\n"
    )
    assert _job_level_if(named_step_form) is None, (
        "a step's if: was read as the job's. Deleting the job gate and putting "
        "the tag condition on a step would then look correctly gated, while "
        "every push cut a public Release."
    )


def test_bi1_selftest_still_gates_publication_through_needs():
    """The guarantee moved from step order to job order — check it still holds.

    Each OS job asserts its selftest runs before its upload
    (``test_rm4a_selftest_runs_before_anything_is_published``). With the release
    step now in another job, `needs:` is the only thing carrying that guarantee
    forward to publication, so both halves have to be true at once.
    """
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        body = jobs[job]
        assert body.index("--selftest") < body.index("upload-artifact"), (
            f"{job} uploads its artifact before proving the bundle starts"
        )
    needs = re.search(r"needs:\s*\[([^\]]*)\]", _code_only(jobs[PUBLISH_JOB]))
    assert needs and set(PACKAGED_EXECUTABLES) <= {
        n.strip() for n in needs.group(1).split(",") if n.strip()
    }, "publication no longer depends on the jobs that run the selftest"


def test_bi1_download_path_matches_the_release_file_prefix():
    """Tie the two halves together, or both can be individually "correct".

    ``test_bi1_publish_job_downloads_every_build_artifact`` checks artifact
    NAMES; ``test_bi1_every_built_archive_is_attached_to_the_release`` checks
    archive BASENAMES. Change ``path: release-assets`` to anything else — or
    delete it, so download-artifact defaults to the workspace root — and both
    still pass while the release step matches nothing.
    ``fail_on_unmatched_files: true`` makes that a red job rather than an empty
    Release, so the outcome is a burned tag, not a bad Release. Still a hole in
    "these tests are the only check before a real v* tag".
    """
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])

    # Counted, not set-collapsed: two identical `path:` values collapse to one,
    # so deleting the path from ONE of the two download steps left len == 1 and
    # passed while that artifact landed in the workspace root instead.
    # Only the download steps' path: inputs. actions/checkout takes a `path:`
    # too, so counting every path: in the job would mis-report the moment one
    # is added to the checkout.
    download_steps = len(re.findall(r"uses:\s*actions/download-artifact@", body))
    declared = [
        m.group(1)
        for block in re.split(r"(?=^\s*-\s)", body, flags=re.MULTILINE)
        if "download-artifact@" in block
        for m in [re.search(r"^\s*path:\s*(\S+)\s*$", block, re.MULTILINE)]
        if m
    ]
    assert len(declared) == download_steps, (
        f"{download_steps} download steps but {len(declared)} path: entries — "
        "a download with no path: lands in the workspace root, where the "
        "release step's files: prefix will not match it"
    )
    unique = {p.strip("\"'") for p in declared}
    assert len(unique) == 1, (
        f"the downloads land in different directories {sorted(unique)}; the "
        "release step can only carry one prefix"
    )
    download_dir = unique.pop()

    release_at = body.find("action-gh-release")
    attached = body[release_at:]
    for archive in RELEASE_ARCHIVES:
        for suffix in ("", ".sha256"):
            expected = f"{download_dir}/{archive}{suffix}"
            # Line-anchored, not a substring. "…/daVIPA-mac.zip" IS a
            # substring of "…/daVIPA-mac.zip.sha256", so the substring
            # form passed a files: block containing ONLY the two checksums —
            # which satisfies fail_on_unmatched_files: true and publishes a
            # public, permanent Release with correct notes and no downloadable
            # archives. Verified by mutation.
            assert re.search(rf"^\s*{re.escape(expected)}\s*$", attached, re.MULTILINE), (
                f"the release step does not attach {expected!r} on a line of "
                f"its own. The downloads land in {download_dir!r}, so every "
                "files: entry must start with it."
            )


def test_bi1_downloaded_archives_are_checksum_verified_before_publishing():
    """The guarantee that used to be free inside one job (P6).

    The zip and its .sha256 were once produced and attached from the same
    directory in the same job. They now round-trip through the artifact store
    and are attached by a third job, so a corrupted round-trip would publish an
    asset that does not match the checksum file beside it, green.
    """
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    assert "sha256sum -c" in body, (
        "the publish job attaches checksums it never verified against the "
        "archives it downloaded"
    )
    assert body.index("sha256sum -c") < body.index("action-gh-release"), (
        "the checksum verification runs after the Release is published"
    )
    for archive in RELEASE_ARCHIVES:
        assert f"sha256sum -c {archive}.sha256" in body, (
            f"{archive} is published without its checksum being verified"
        )


def test_bi1_checksum_files_are_written_in_the_format_the_verifier_reads():
    """Producer/consumer contract across three jobs and two platforms (P19).

    The publish job runs GNU ``sha256sum -c`` on files written by PowerShell on
    Windows and ``shasum`` on macOS. Drop ``-NoNewline`` from the Windows step
    and PowerShell emits CRLF; ``sha256sum`` then parses the filename as
    ``daVIPA-win64.zip\r`` and the publish job fails — on a real tag,
    after both builds have run. Nothing asserted the format, only that the
    verification was called.
    """
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))

    windows = _code_only(jobs["build-windows"])
    assert "-NoNewline" in windows, (
        "the Windows checksum step must write without a trailing newline; "
        "PowerShell otherwise emits CRLF, which GNU sha256sum -c cannot parse"
    )
    assert "-Encoding ascii" in windows, (
        "the Windows checksum step must write ASCII; a UTF-16 or BOM-prefixed "
        "file is unreadable to sha256sum -c"
    )
    win_archive = RELEASE_ARCHIVES_BY_JOB["build-windows"]
    assert f'"$hash  {win_archive}"' in windows, (
        f'the Windows checksum step must write `"$hash  {win_archive}"` — the '
        "two-space separator and the BARE filename. A path here makes "
        "sha256sum -c look for it relative to release-assets/ and fail the job."
    )

    macos = _code_only(jobs["build-macos"])
    mac_archive = RELEASE_ARCHIVES_BY_JOB["build-macos"]
    assert f"shasum -a 256 {mac_archive} >" in macos, (
        f"the macOS checksum step must be `shasum -a 256 {mac_archive} >` — a "
        "bare filename, not a path. `shasum -a 256 dist/daVIPA-mac.zip` "
        "writes the path into the .sha256, and the publish job's sha256sum -c "
        "then looks for release-assets/dist/... and fails on a real tag."
    )

    # Both formats exist to be read by one consumer; assert that end too.
    publish = _code_only(jobs[PUBLISH_JOB])
    for archive in RELEASE_ARCHIVES:
        assert f"sha256sum -c {archive}.sha256" in publish, (
            f"nothing consumes {archive}.sha256, so its format is unconstrained"
        )


def test_bi1_publish_job_does_not_run_on_a_failed_build():
    """`needs:` only implies success while no status function overrides it.

    Adding `always() && ...` to the job's `if:` would restore the exact defect
    BI1 removed — both builds could fail and the Release would still be cut —
    and every other BI1 test would stay green.
    """
    body = _code_only(_job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))[PUBLISH_JOB])
    # The whole job body, not just the remainder of the `if:` line. A block
    # scalar (`if: >` with `always() && ...` on the following line) put the
    # override outside a single-line capture and left this green.
    condition = _job_level_if(body)
    assert condition, "the publish job has no job-level if: condition"
    for override in ("always(", "failure(", "cancelled("):
        assert override not in condition, (
            f"the publish job's if: uses {override}), which overrides the "
            "implicit success requirement of needs: and lets a failed build "
            "publish a Release"
        )


def test_bi1_release_notes_are_generated_once():
    """Two copies of the notes agreed only because nothing made them differ."""
    text = _code_only(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    calls = text.count("extract_release_notes.py")
    assert calls == 1, (
        f"extract_release_notes.py is called {calls} times; one Release needs "
        "one set of notes"
    )


# --------------------------------------------------------------------------
# Action versions — pinned, and consistent across every workflow
# --------------------------------------------------------------------------

# `uses:` forms that are legitimately not a versioned marketplace action.
LOCAL_USES_PREFIXES = ("./", "../", "docker://")

_USES_LINE = re.compile(r"\buses:\s*(\S+)")
_VERSIONED_ACTION = re.compile(r"^['\"]?([\w.-]+/[\w.-]+)@([^'\"\s]+)['\"]?$")


def _uses_lines() -> list[tuple[str, str]]:
    """Every `uses:` value in every workflow, as (workflow name, raw value)."""
    found = []
    for wf in _workflows():
        for line in _code_only(wf.read_text(encoding="utf-8")).splitlines():
            match = _USES_LINE.search(line)
            if match:
                found.append((wf.name, match.group(1)))
    return found


def _action_uses() -> dict[str, set[str]]:
    """{action name: {versions used}} across every workflow."""
    found: dict[str, set[str]] = {}
    for _wf, raw in _uses_lines():
        match = _VERSIONED_ACTION.match(raw)
        if match:
            found.setdefault(match.group(1), set()).add(match.group(2))
    return found


def test_every_uses_line_is_recognised_by_the_action_parser():
    """An unparsed `uses:` line is invisible to every check below it.

    The parser used to require an unquoted `owner/repo@ver`, so
    `uses: 'actions/checkout@v4'` — ordinary YAML, and what a reformatter may
    well emit — matched nothing and was silently exempt from the version,
    pinning and drift checks. Unrecognised input must be loud one level up too,
    not only inside the checks it feeds.
    """
    unrecognised = [
        f"{wf}: {raw}" for wf, raw in _uses_lines()
        if not _VERSIONED_ACTION.match(raw)
        and not raw.strip("'\"").startswith(LOCAL_USES_PREFIXES)
    ]
    assert not unrecognised, (
        f"`uses:` lines the action checks cannot see: {unrecognised}. Either "
        "pin them as owner/repo@version, or extend LOCAL_USES_PREFIXES."
    )


def test_action_parser_handles_quoted_and_local_uses_forms():
    """Adversarial: prove the parser change actually covers the missed forms."""
    assert _VERSIONED_ACTION.match("actions/checkout@v7").group(1) == "actions/checkout"
    assert _VERSIONED_ACTION.match("'actions/checkout@v7'").group(1) == "actions/checkout"
    assert _VERSIONED_ACTION.match('"actions/checkout@v7"').group(2) == "v7"
    assert _VERSIONED_ACTION.match("./.github/actions/local") is None
    assert _VERSIONED_ACTION.match("docker://alpine:3.19") is None


def test_actions_are_used_at_one_version_across_all_workflows():
    """Three workflows drifting apart is how one gets left on a dead runtime.

    The Node 20 deprecation landed on all three at once; bumping only the one
    being edited would have left the others behind.
    """
    drifted = {a: sorted(v) for a, v in _action_uses().items() if len(v) > 1}
    assert not drifted, (
        f"the same action is pinned to different versions in different "
        f"workflows: {drifted}"
    )


def test_actions_are_pinned_to_a_version_not_a_branch():
    """`@main` silently changes under you; a major tag does not."""
    floating = {
        f"{action}@{version}"
        for action, versions in _action_uses().items()
        for version in versions
        if version in {"main", "master", "latest", "HEAD"}
    }
    assert not floating, f"actions pinned to a moving ref: {sorted(floating)}"


# Every action used anywhere in .github/workflows must appear here, with the
# last major that ran on the deprecated Node 20 runtime. An action missing from
# this table fails its own test rather than being skipped.
#
# Values are ints, deliberately. An earlier draft allowed None for "no Node 20
# lineage", which put the silent skip back one step out as a documented
# one-word opt-out — and typing None is the path of least resistance when CI
# goes red on a newly added action. Use 0 instead: the comparison still runs
# and simply never fires.
KNOWN_ACTION_MAJORS: dict[str, int] = {
    "actions/checkout": 4,
    "actions/setup-python": 5,
    "actions/upload-artifact": 4,
    "actions/download-artifact": 4,
    "actions/cache": 3,
    "softprops/action-gh-release": 2,
}

# A commit-SHA pin is good practice, but it hides the major from this check.
# Record what each pinned SHA corresponds to so the check still applies.
SHA_PINNED_MAJORS: dict[str, int] = {}


def _parsed_major(version: str) -> int | None:
    match = re.fullmatch(r"v?(\d+)(?:\.\d+)*", version)
    return int(match.group(1)) if match else None


def test_every_action_used_is_declared_in_the_version_table():
    """An unlisted action must be a red test, not a silent skip."""
    unknown = sorted(set(_action_uses()) - set(KNOWN_ACTION_MAJORS))
    assert not unknown, (
        f"workflows use actions absent from KNOWN_ACTION_MAJORS: {unknown}. "
        "Add each one with the last major that ran on Node 20, or 0 if it has "
        "no Node 20 lineage — never None, which would skip the check."
    )


def test_action_version_table_holds_only_integers():
    """A None here would silently exempt that action from the check below."""
    bad = {a: v for a, v in KNOWN_ACTION_MAJORS.items() if not isinstance(v, int)}
    assert not bad, (
        f"KNOWN_ACTION_MAJORS entries that are not ints: {bad}. Use 0 for "
        "'no Node 20 lineage' so the comparison still runs."
    )


def test_every_action_version_is_checkable():
    r"""A version this test cannot parse must fail, not fall through.

    `re.match(r"v(\d+)", ...)` returned None for a SHA pin, and a None match
    hit no assertion at all — so SHA-pinning every action, the standard next
    hardening step, would have disabled this guard entirely.
    """
    unparseable = sorted(
        f"{action}@{version}"
        for action, versions in _action_uses().items()
        for version in versions
        if _parsed_major(version) is None
        and f"{action}@{version}" not in SHA_PINNED_MAJORS
    )
    assert not unparseable, (
        f"action versions this check cannot interpret: {unparseable}. If these "
        "are commit-SHA pins, add 'action@sha': <major> to SHA_PINNED_MAJORS so "
        "the Node 20 check still applies to them."
    )


def _stale_actions(uses: dict[str, set[str]]) -> list[str]:
    """Actions in `uses` sitting on a deprecated Node 20 major.

    Extracted from the test so the adversarial test below can drive it with
    synthetic input. Asserting on a helper's return value proves nothing about
    the guard; this is the guard.
    """
    stale = []
    for action, versions in uses.items():
        limit = KNOWN_ACTION_MAJORS.get(action)
        for version in versions:
            major = _parsed_major(version)
            if major is None:
                major = SHA_PINNED_MAJORS.get(f"{action}@{version}")
            # "unknown action" and "unparseable version" each have their own
            # test above; here they are simply not judgeable.
            if limit is None or major is None:
                continue
            if major <= limit:
                stale.append(f"{action}@{version}")
    return sorted(stale)


def test_no_workflow_uses_a_node20_action_version():
    """GitHub force-runs Node 20 actions on Node 24 with a deprecation warning
    today, and will stop running them.

    Verified against the actions' own latest releases on 2026-08-18:
    checkout v7.0.1, setup-python v7.0.0, upload-artifact v7.0.1,
    action-gh-release v3.0.2.
    """
    stale = _stale_actions(_action_uses())
    assert not stale, (
        f"actions on a deprecated Node 20 runtime: {stale}. "
        "Bump them across every workflow, not just the one being edited."
    )


def test_node20_guard_actually_rejects_the_cases_it_used_to_skip():
    """Drive the guard itself with the four cases that previously passed green.

    An earlier version of this test only asserted `_parsed_major` return values
    and dict membership. It never called the guard, so it stayed green with the
    silent-skip branch still in the loop, and green when `<=` was mutated to
    `<`. It now exercises `_stale_actions` directly.
    """
    # A recognised action on a Node 20 major is flagged.
    assert _stale_actions({"actions/cache": {"v3"}}) == ["actions/cache@v3"]
    assert _stale_actions({"actions/download-artifact": {"v4"}}) == [
        "actions/download-artifact@v4"]
    # Bare major, no leading v.
    assert _stale_actions({"actions/checkout": {"4"}}) == ["actions/checkout@4"]
    # A current major is not flagged.
    assert _stale_actions({"actions/checkout": {"v7"}}) == []
    # Boundary: the guard must flag the last Node 20 major itself, not just below it.
    assert _stale_actions({"actions/checkout": {"v4"}}) == ["actions/checkout@v4"]
    # A SHA pin is not judgeable here; test_every_action_version_is_checkable
    # is what makes it red.
    sha = "11bd71901bbe5b1630ceea73d27597364c9af683"
    assert _stale_actions({"actions/checkout": {sha}}) == []
    assert _parsed_major(sha) is None


def test_node20_guard_is_sensitive_to_the_comparison_operator():
    """Mutation check: `<=` must not be silently weakenable to `<`.

    With the real workflows both operators yield [], so the previous test could
    not tell them apart. This case distinguishes them.
    """
    at_the_limit = {"actions/setup-python": {"v5"}}   # 5 == last Node 20 major
    assert _stale_actions(at_the_limit) == ["actions/setup-python@v5"], (
        "the guard stopped flagging the last Node 20 major itself"
    )


# --------------------------------------------------------------------------
# R-M4.A/B — the publish steps must fail rather than publish nothing
# --------------------------------------------------------------------------

def test_upload_artifact_fails_when_no_files_match():
    """`if-no-files-found` defaults to 'warn': a glob matching nothing would
    log a warning and leave the job green with no artifact attached."""
    text = _code_only(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    uploads = text.count("actions/upload-artifact@")
    assert uploads == 2, f"expected 2 upload steps, found {uploads}"
    assert text.count("if-no-files-found: error") == uploads, (
        "every upload-artifact step must set if-no-files-found: error, or a "
        "build can report success having uploaded nothing"
    )


def test_release_upload_fails_when_no_files_match():
    """`fail_on_unmatched_files` defaults to false, which would publish a
    public, permanent Release with correct notes and zero assets."""
    text = _code_only(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    releases = text.count("softprops/action-gh-release@")
    assert releases == 1, (
        f"expected exactly 1 release step, found {releases} — see "
        "test_bi1_exactly_one_job_publishes_the_release"
    )
    assert text.count("fail_on_unmatched_files: true") == releases, (
        "every action-gh-release step must set fail_on_unmatched_files: true"
    )


def test_publish_hardening_is_present_in_both_os_jobs():
    """Per-job, not just per-file: a count can be satisfied by two in one job."""
    jobs = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))
    for job in PACKAGED_EXECUTABLES:
        body = _code_only(jobs[job])
        assert "if-no-files-found: error" in body, f"{job} upload is not hardened"
    assert "fail_on_unmatched_files: true" in _code_only(jobs[PUBLISH_JOB]), (
        "the publish job's release step is not hardened"
    )


# --------------------------------------------------------------------------
# macOS code signing — optional, but it must fail loudly when it is on
# --------------------------------------------------------------------------

SIGNING_GATE = "steps.signing.outputs.available == 'true'"
SIGNING_SECRETS = (
    "APPLE_CERTIFICATE_P12_BASE64",
    "APPLE_CERTIFICATE_PASSWORD",
    "APPLE_SIGNING_IDENTITY",
    "APPLE_NOTARY_KEY_BASE64",
    "APPLE_NOTARY_KEY_ID",
    "APPLE_NOTARY_ISSUER_ID",
)


def _macos_steps() -> list[dict]:
    """The macOS job's steps, as (name, if, body) dicts parsed from the YAML text.

    Hand-parsed for the same reason as everything else in this file: PyYAML is
    not a project dependency.
    """
    body = _job_blocks(RELEASE_WORKFLOW.read_text(encoding="utf-8"))["build-macos"]
    steps, current = [], None
    for line in body.splitlines():
        stripped = line.strip()
        if stripped.startswith("- name:") or stripped.startswith("- uses:"):
            current = {"name": stripped.split(":", 1)[1].strip(),
                       "if": "", "body": [], "raw": []}
            steps.append(current)
        elif current is not None:
            if stripped.startswith("if:"):
                current["if"] = stripped.split(":", 1)[1].strip()
            current["raw"].append(stripped)
            # `body` excludes comments: several of these steps explain in a
            # comment the very construct the tests prohibit ("rather than
            # --deep"), and matching the explanation instead of the code would
            # pressure the next person into deleting the reasoning.
            if not stripped.startswith("#"):
                current["body"].append(stripped)
    for step in steps:
        step["body"] = "\n".join(step["body"])
        step["raw"] = "\n".join(step["raw"])
    return steps


def test_signing_step_parser_finds_the_macos_steps():
    """Adversarial: an empty parser makes every signing assertion vacuous."""
    steps = _macos_steps()
    names = [s["name"] for s in steps]
    assert len(steps) >= 10, f"parsed only {len(steps)} steps: {names}"
    assert any("Build (PyInstaller)" in n for n in names), names


def test_signing_is_optional_and_defaults_to_skipped():
    """With no credentials the job must behave exactly as it did before.

    Every signing step carries the same gate, so absent secrets produce an
    unsigned build and a green job rather than a failure.
    """
    gated = [s for s in _macos_steps() if SIGNING_GATE in s["if"]]
    assert len(gated) >= 4, (
        f"expected the signing steps to be gated on credentials, found "
        f"{len(gated)}: {[s['name'] for s in gated]}"
    )


def test_every_signing_step_is_gated():
    """An ungated signing step would fail every build that has no certificate."""
    ungated = [
        s["name"] for s in _macos_steps()
        if any(k in s["name"].lower() for k in ("sign", "notaris", "notariz", "keychain"))
        and SIGNING_GATE not in s["if"]
        and "credentials configured" not in s["name"].lower()
    ]
    assert not ungated, (
        f"signing steps that run unconditionally: {ungated}. Without secrets "
        "these fail, breaking builds for anyone without a certificate."
    )


def test_signing_gate_does_not_interpolate_secrets_into_the_script():
    """A secret pasted into a shell body can break on quotes or leak in traces.

    It must arrive through `env:` instead.
    """
    offenders = []
    for step in _macos_steps():
        for line in step["body"].splitlines():
            if "secrets." not in line:
                continue
            # The only acceptable shape is an env mapping: NAME: ${{ secrets.X }}
            if not re.match(r"^[A-Z][A-Z0-9_]*:\s*\$\{\{\s*secrets\.", line):
                offenders.append(f"{step['name']}: {line}")
    assert not offenders, (
        "secrets interpolated somewhere other than an env: mapping — a value "
        f"containing quotes or newlines would break or leak: {offenders}"
    )

    gate = next(s for s in _macos_steps() if "credentials configured" in s["name"].lower())
    assert "env:" in gate["body"], (
        "the credential check should read secrets via env, not inline them"
    )
    assert 'echo "available=' in gate["body"], "the gate must publish a step output"


def test_signing_runs_before_the_archive_is_made():
    """Signing after zipping would ship the unsigned bundle."""
    names = [s["name"] for s in _macos_steps()]
    sign_at = next(i for i, n in enumerate(names) if "Sign the app" in n)
    zip_at = next(i for i, n in enumerate(names) if "Zip macOS app" in n)
    assert sign_at < zip_at, f"signing happens after zipping: {names}"


def test_selftest_runs_after_signing_so_it_exercises_the_shipped_bundle():
    """Signing rewrites the binary; the selftest should see the final artifact."""
    names = [s["name"] for s in _macos_steps()]
    staple_at = next(i for i, n in enumerate(names) if "Notaris" in n or "Notariz" in n)
    selftest_at = next(i for i, n in enumerate(names) if "packaged bundle starts" in n)
    assert staple_at < selftest_at, (
        "the selftest runs before notarisation, so it does not exercise the "
        "bundle that actually ships"
    )


def test_signing_is_verified_against_the_artifact():
    """P6: trusting codesign's exit code is not the same as asking Gatekeeper.

    `spctl --assess` is what Gatekeeper itself runs, and `stapler validate`
    proves the ticket is embedded rather than merely issued.
    """
    body = " ".join(s["body"] for s in _macos_steps())
    assert "spctl --assess" in body, "nothing runs spctl to confirm Gatekeeper accepts it"
    assert "stapler validate" in body, "nothing confirms the notarisation ticket stapled"


def test_signing_keychain_is_always_cleaned_up():
    """A failure mid-signing must not leave a certificate on the runner."""
    cleanup = [s for s in _macos_steps() if "keychain" in s["name"].lower()
               and "clean" in s["name"].lower()]
    assert cleanup, "no keychain cleanup step"
    assert "always()" in cleanup[0]["if"], (
        f"keychain cleanup is not unconditional: {cleanup[0]['if']}"
    )


def test_signing_does_not_use_codesign_deep_for_the_bundle():
    """Apple documents --deep as unsuitable for real bundles; a PyInstaller app
    needs its nested .so/.dylib files signed individually."""
    sign_step = next(s for s in _macos_steps() if "Sign the app" in s["name"])
    assert "--deep" not in sign_step["body"], (
        "signing uses --deep, which Apple advises against for distribution; "
        "sign nested binaries inside-out instead"
    )


def test_signing_entitlements_exist_and_are_minimal():
    """Hardened runtime forces a few entitlements; it must not grant more."""
    plist = REPO_ROOT / "packaging/entitlements.plist"
    assert plist.exists(), "the workflow references packaging/entitlements.plist"
    text = plist.read_text(encoding="utf-8")

    for required in ("com.apple.security.cs.allow-jit",
                     "com.apple.security.cs.allow-unsigned-executable-memory",
                     "com.apple.security.cs.disable-library-validation"):
        assert required in text, f"CPython needs {required} under hardened runtime"

    for forbidden in ("com.apple.security.device.camera",
                      "com.apple.security.device.microphone",
                      "com.apple.security.personal-information.location",
                      "com.apple.security.personal-information.addressbook",
                      "com.apple.security.cs.disable-executable-page-protection"):
        assert forbidden not in text, (
            f"{forbidden} is granted but nothing in the app needs it"
        )


def test_signing_setup_is_documented():
    """Six secrets nobody can guess; the doc is the only way in."""
    doc = REPO_ROOT / "docs/CODE_SIGNING.md"
    assert doc.exists(), "no docs/CODE_SIGNING.md"
    text = doc.read_text(encoding="utf-8")
    missing = [s for s in SIGNING_SECRETS if s not in text]
    assert not missing, f"docs/CODE_SIGNING.md does not name these secrets: {missing}"


def test_documented_secrets_match_the_ones_the_workflow_reads():
    """Doc-vs-artifact drift: a documented secret the workflow ignores, or a
    secret the workflow needs and the doc never mentions, both waste an hour."""
    workflow = RELEASE_WORKFLOW.read_text(encoding="utf-8")
    used = set(re.findall(r"secrets\.([A-Z0-9_]+)", workflow))
    documented = set(
        re.findall(r"\b(APPLE_[A-Z0-9_]+)\b",
                   (REPO_ROOT / "docs/CODE_SIGNING.md").read_text(encoding="utf-8"))
    )
    assert used, "the workflow reads no secrets at all"
    assert used <= documented, (
        f"the workflow reads secrets the doc never explains: {sorted(used - documented)}"
    )


def test_the_opt_out_parsing_handles_whitespace_and_case(monkeypatch):
    """In-process, so it costs no subprocess.

    Narrowing the subprocess loop to one off-value removed the only case
    exercising `.strip()` — `" 0 "` — and the comment justifying that claimed
    the parsing was covered by the membership test above. It is not: that test
    never calls the function. Mutation-verified — removing `.strip()` left both
    tests green.
    """
    import conftest

    for value in (" 0 ", "FALSE", "OFF", "No", "  false  ", "n"):
        monkeypatch.setenv(conftest.NO_MAPPED_WINDOWS_ENV, value)
        assert conftest.mapped_windows_suppressed() is False, (
            f"{value!r} turned the opt-out ON; it means off"
        )

    for value in ("1", "yes", "true", " 1 "):
        monkeypatch.setenv(conftest.NO_MAPPED_WINDOWS_ENV, value)
        assert conftest.mapped_windows_suppressed() is True, (
            f"{value!r} did not turn the opt-out on"
        )

    monkeypatch.delenv(conftest.NO_MAPPED_WINDOWS_ENV, raising=False)
    assert conftest.mapped_windows_suppressed() is False


# The document-set machinery that used to live here is deleted: LIVE_DOCS,
# _live_documents(), the derived DOCS_DIR_LIVE_DOCS and the three guards that
# read them (GSF-M1.1, MAW-M2.1, LDS-M1.1). They existed to scan this repo's
# records for citations of files that are not there. Removed on the user's
# instruction, 2026-11-09: records are filed, not tested. The CI contract
# above — the workflow's own python versions, its secrets, the mapped-window
# count — is kept, because it is about CI and not about prose.


def test_bsfm7_every_apt_call_retries_inside_a_time_limit():
    """BSF-M7 (CI-A1) — a mirror outage is retried, not a red build.

    Spec: docs/unused-docs/implementation_plan_2026-11-13_backlog_small_fixes.md

    Source text, because the alternative is running apt against a broken
    mirror. Anchored per line and counted exactly: the two apt calls each
    carry ``Acquire::Retries``, they sit in a retry loop, and the step has a
    time limit so the loop cannot hang the job.
    """
    lines = TESTS_WORKFLOW.read_text(encoding="utf-8").splitlines()
    apt_lines = [line for line in lines
                 if re.match(r"\s*sudo apt-get\b", line)]
    assert len(apt_lines) == 2, apt_lines
    assert all("-o Acquire::Retries=" in line for line in apt_lines), apt_lines

    step = next(i for i, line in enumerate(lines)
                if line.strip().startswith("- name: Install system packages"))
    end = next(i for i in range(step + 1, len(lines))
               if lines[i].strip().startswith("- name:"))
    body = [line.strip() for line in lines[step:end]]
    assert body.count("timeout-minutes: 15") == 1, body
    assert body.count("for attempt in 1 2 3; do") == 1, body
