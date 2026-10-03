"""Tests for evals/harness.py (SPT-1 - a run is recorded under either condition).

None of these tests call a real model. A fake `claude` executable, built by
`_write_fake_claude` below, replays a fixed set of line-delimited JSON
events - the same envelope the real CLI's `--output-format` produces - and
logs every argument list, working directory, directory listing and
environment it was called with, so the assertions below read the harness's
own command line and child process back rather than guessing at them.

The scenario fixture is built by `_write_scenario`, and the plugin-source
fixture by `_write_plugin_repo`, entirely inside this file: a small git
repository stands in for this checkout, so a test never copies the real
repository's tracked tree.
"""
from __future__ import annotations

import ast
import json
import os
import re
import shutil
import stat
import subprocess
import sys
from datetime import date, timedelta
from pathlib import Path

import pytest

from citation_patterns import (  # noqa: E402
    PLANTED_CITATION_FORMS,
    cited_unopenable_document,
    scan_file_for_unopenable_citation,
)

REPO_ROOT = Path(__file__).resolve().parent.parent

# The bundled copy of PyYAML resolves the same way it does for every other
# entry point (`tests/conftest.py`): put `cli/` on `sys.path` and import
# `compass_pkg` for its side effect before importing `yaml`.
sys.path.insert(0, str(REPO_ROOT / "cli"))
import compass_pkg  # noqa: E402  (side effect: puts cli/vendor at sys.path[0])
import yaml  # noqa: E402

if str(REPO_ROOT) not in sys.path:
    sys.path.insert(0, str(REPO_ROOT))
from evals import harness  # noqa: E402


# --- a fake `claude`, entirely self-contained ------------------------------

_FAKE_CLAUDE_SOURCE = '''#!/usr/bin/env python3
"""A stand-in for the real CLI, used only by this repository's own tests.

The harness gives its child a built environment, not an inherited one - so
this script cannot read an environment variable to learn what a specific
test needs. It reads a config file next to itself instead
(`fake_claude_config.json`): the log path every call appends its own record
to, and what a test wants switched on for that run - the cost it reports, a
write outside its own directory, a simulated permission denial.
"""
import json
import os
import shutil
import subprocess
import sys
from pathlib import Path

_HERE = Path(__file__).resolve().parent
_CONFIG_PATH = _HERE / "fake_claude_config.json"


def _config():
    if _CONFIG_PATH.is_file():
        return json.loads(_CONFIG_PATH.read_text(encoding="utf-8"))
    return {}


def _listing(root):
    found = []
    for base, dirs, names in os.walk(root):
        dirs[:] = [d for d in dirs if d != ".git"]
        for name in names:
            full = os.path.join(base, name)
            found.append(os.path.relpath(full, root))
    return sorted(found)


def main():
    if sys.argv[1:] == ["--version"]:
        print("fake-claude 9.9.9")
        return

    config = _config()
    cwd = os.getcwd()
    record = {
        "args": sys.argv[1:],
        "cwd": cwd,
        "listing": _listing(cwd),
        "env": dict(os.environ),
        # Resolved now, from inside the call, because the harness's own
        # PATH entries (in particular the plugin copy's bin/) may be gone
        # by the time a test can look.
        "resolved_compass": shutil.which("compass", path=os.environ.get("PATH", "")),
        # The seed commit's author and committer, read now because the
        # harness deletes the repository once the call returns - the same
        # allowed `git log` a real session could run.
        "git_log_identity": subprocess.run(
            ["git", "log", "-1", "--format=%an <%ae> %cn <%ce>"],
            cwd=cwd, capture_output=True, text=True,
        ).stdout.strip(),
    }

    # The plugin copy the harness built for this call, if any - inspected
    # now, from inside the call, because the harness deletes it once the
    # call returns.
    if "--plugin-dir" in sys.argv:
        plugin_dir = sys.argv[sys.argv.index("--plugin-dir") + 1]
        readme = os.path.join(plugin_dir, "README.md")
        compass_bin = os.path.join(plugin_dir, "bin", "compass")
        tests_dir = os.path.join(plugin_dir, "tests")
        docs_compass_dir = os.path.join(plugin_dir, "docs", "compass")
        docs_releasing = os.path.join(plugin_dir, "docs", "releasing.md")
        record["plugin_copy"] = {
            "dir_writable": os.access(plugin_dir, os.W_OK),
            # Generic, unlike the compass-specific checks below - the
            # superpowers condition's own framework copy has no
            # `bin/compass` to check for, so a test reads this listing to
            # check for whatever it wrote into its own fixture instead.
            "listing": _listing(plugin_dir),
            "readme_text": (open(readme, encoding="utf-8").read()
                             if os.path.isfile(readme) else None),
            "readme_writable": os.access(readme, os.W_OK),
            "compass_executable": os.access(compass_bin, os.X_OK),
            "evals_dir_exists": os.path.isdir(os.path.join(plugin_dir, "evals")),
            "tests_listing": (sorted(os.listdir(tests_dir))
                               if os.path.isdir(tests_dir) else []),
            "docs_compass_listing": (sorted(os.listdir(docs_compass_dir))
                                      if os.path.isdir(docs_compass_dir) else []),
            "docs_releasing_exists": os.path.isfile(docs_releasing),
        }

    with open(config["log_path"], "a", encoding="utf-8") as fh:
        fh.write(json.dumps(record) + "\\n")

    # A test that wants a call to make no code edit - to check the
    # continuation reply's own trigger, not its cap - sets "no_edit".
    target = os.path.join(cwd, "seed.txt")
    if os.path.isfile(target) and not config.get("no_edit"):
        with open(target, "a", encoding="utf-8") as fh:
            fh.write("edited by the fake CLI\\n")

    escape_path = config.get("escape_path")
    if escape_path:
        os.makedirs(os.path.dirname(escape_path), exist_ok=True)
        with open(escape_path, "a", encoding="utf-8") as fh:
            fh.write("reached from outside the temporary repository\\n")

    # A test that wants a diff.external planted in the temporary
    # repository's own .git/config - the shape a session's own conftest.py
    # could use to run code with the harness's own environment - sets
    # "tamper_marker" to a path outside the repository: the marker a
    # planted script would write, if the harness's later git diff calls
    # ever ran it.
    tamper_marker = config.get("tamper_marker")
    if tamper_marker:
        script_path = os.path.join(cwd, "planted-diff-external.sh")
        with open(script_path, "w", encoding="utf-8") as fh:
            fh.write("#!/bin/sh\\necho tampered > " + tamper_marker + "\\n")
        os.chmod(script_path, 0o755)
        with open(os.path.join(cwd, ".git", "config"), "a", encoding="utf-8") as fh:
            fh.write("[diff]\\n\\texternal = " + script_path + "\\n")

    # A test that wants `.git` replaced with a gitfile - the shape a linked
    # worktree's own `.git` takes - sets "replace_git_with_file": every
    # lookup under `.git` then raises `NotADirectoryError`, not
    # `FileNotFoundError`. The gitfile points at the real git directory,
    # moved aside, so it still resolves - unlike a gitfile naming a path
    # that does not exist, which cannot show whether the harness runs a git
    # command against a directory the session chose before it notices `.git`
    # is not a directory. "git_filter_marker" plants a clean filter in that
    # moved directory's own config, tagged onto every file with
    # `.gitattributes`: the marker the filter would touch if the harness's
    # own `git add -A` or `git diff` ever ran it.
    if config.get("replace_git_with_file"):
        git_dir = os.path.join(cwd, ".git")
        evil_dir = os.path.join(cwd, "evil-gitdir")
        shutil.move(git_dir, evil_dir)
        with open(git_dir, "w", encoding="utf-8") as fh:
            fh.write("gitdir: " + evil_dir + "\\n")
        filter_marker = config.get("git_filter_marker")
        if filter_marker:
            filter_script = os.path.join(cwd, "planted-clean-filter.sh")
            with open(filter_script, "w", encoding="utf-8") as fh:
                fh.write("#!/bin/sh\\ntouch " + filter_marker + "\\ncat\\n")
            os.chmod(filter_script, 0o755)
            with open(os.path.join(evil_dir, "config"), "a", encoding="utf-8") as fh:
                fh.write('[filter "x"]\\n\\tclean = ' + filter_script + '\\n')
            with open(os.path.join(cwd, ".gitattributes"), "w", encoding="utf-8") as fh:
                fh.write("* filter=x\\n")

    if config.get("create_pyc"):
        pycache_dir = os.path.join(cwd, "src", "__pycache__")
        os.makedirs(pycache_dir, exist_ok=True)
        with open(os.path.join(pycache_dir, "inventory.cpython-311.pyc"), "wb") as fh:
            fh.write(b"\\x00\\x01compiled")

    # A test that wants a fresh, untracked path in the seed - to check
    # `changed`'s own "A" status - sets "add_path".
    add_path = config.get("add_path")
    if add_path:
        full = os.path.join(cwd, add_path)
        parent = os.path.dirname(full)
        if parent:
            os.makedirs(parent, exist_ok=True)
        with open(full, "w", encoding="utf-8") as fh:
            fh.write("added by the fake CLI\\n")

    # A test that wants a seed path removed - to check `changed`'s own "D"
    # status - sets "delete_path".
    delete_path = config.get("delete_path")
    if delete_path:
        full = os.path.join(cwd, delete_path)
        if os.path.isfile(full):
            os.remove(full)

    # A test that wants the session's own repository to look like it
    # deleted or corrupted `.git/HEAD` - the shape a broken or malicious
    # session leaves, which must not let a later git call search upward
    # for some other repository - sets "delete_git_head" or
    # "corrupt_git_head".
    if config.get("delete_git_head"):
        head_path = os.path.join(cwd, ".git", "HEAD")
        if os.path.isfile(head_path):
            os.remove(head_path)
    if config.get("garbage_ref_git_head"):
        with open(os.path.join(cwd, ".git", "HEAD"), "w", encoding="utf-8") as fh:
            fh.write("ref: garbage\\n")
    if config.get("corrupt_git_head"):
        with open(os.path.join(cwd, ".git", "HEAD"), "w", encoding="utf-8") as fh:
            fh.write("not a valid HEAD\\n")

    # EGB-3: a test that wants `.git/HEAD` left untouched and valid, but
    # every git call to still fail - the shape a deleted `.git/objects`
    # leaves - sets "delete_git_objects".
    if config.get("delete_git_objects"):
        shutil.rmtree(os.path.join(cwd, ".git", "objects"))

    # A test that wants a second issue directory under `.compass/work/` - to
    # check `manifests` holds more than one - sets "second_manifest_slug".
    second_manifest_slug = config.get("second_manifest_slug")
    if second_manifest_slug:
        manifest_dir = os.path.join(cwd, ".compass", "work", second_manifest_slug)
        os.makedirs(manifest_dir, exist_ok=True)
        with open(os.path.join(manifest_dir, "manifest.yml"), "w",
                  encoding="utf-8") as fh:
            fh.write("issue: " + second_manifest_slug + "\\nstatus: active\\n")

    cost = float(config.get("cost", 0.02))
    session_id = "fake-session-0001"
    deny_tool = config.get("deny_tool")
    closing_text = "fixed it"

    tool_uses = [
        {"type": "tool_use", "id": "toolu_1", "name": "Read",
         "input": {"file_path": "seed.txt"}},
        {"type": "tool_use", "id": "toolu_2", "name": "Edit",
         "input": {"file_path": "seed.txt"}},
    ]
    results = []
    for call in tool_uses:
        if deny_tool and call["name"] == deny_tool:
            results.append({
                "type": "tool_result", "tool_use_id": call["id"],
                "content": "Claude requested permissions to use the "
                           + call["name"] + " tool, but you have not "
                           "granted it yet.",
                "is_error": True,
            })
        else:
            results.append({
                "type": "tool_result", "tool_use_id": call["id"],
                "content": call["name"] + " ok", "is_error": False,
            })

    permission_denials = [{"tool_use_id": "toolu_2"}] if deny_tool else []

    events = [
        {"type": "system", "subtype": "init", "session_id": session_id,
         "cwd": cwd, "model": "fake-model-1"},
        {"type": "assistant", "message": {"role": "assistant", "content": [
            {"type": "text", "text": "about to look at seed.txt"},
            tool_uses[0],
            tool_uses[1],
        ]}},
        {"type": "user", "message": {"role": "user", "content": results}},
        {"type": "assistant", "message": {"role": "assistant", "content": [
            {"type": "text", "text": closing_text},
        ]}},
        {"type": "result", "subtype": config.get("result_subtype", "success"),
         "session_id": session_id,
         "total_cost_usd": cost, "result": closing_text,
         "permission_denials": permission_denials,
         "usage": config.get("usage") or {
             "input_tokens": 100, "output_tokens": 50,
             "cache_creation_input_tokens": 10, "cache_read_input_tokens": 5,
         }},
    ]
    for event in events:
        print(json.dumps(event))


if __name__ == "__main__":
    main()
'''


def _write_fake_claude(tmp_path: Path) -> Path:
    path = tmp_path / "fake_claude.py"
    path.write_text(_FAKE_CLAUDE_SOURCE, encoding="utf-8")
    path.chmod(path.stat().st_mode | stat.S_IEXEC | stat.S_IXGRP | stat.S_IXOTH)
    return path


# --- a scenario fixture and a plugin-source fixture, owned by this file ----

def _write_scenario(tmp_path: Path, *, follow_ups: list[str] | None = None,
                     budget_usd: float = 3.0,
                     continue_reply: str | None = None,
                     capture_env_to: Path | None = None) -> Path:
    scenario_dir = tmp_path / "scenario"
    seed_dir = scenario_dir / "seed"
    seed_dir.mkdir(parents=True)
    (seed_dir / "seed.txt").write_text("original contents\n", encoding="utf-8")
    if capture_env_to is not None:
        # A test that wants to see the test command's own environment - to
        # check it is the environment built for the session, not the
        # harness's `os.environ` - writes it here: outside the temporary
        # repository (an absolute path baked in now, when the fixture is
        # written), so it survives the repository being deleted once the
        # run ends.
        (seed_dir / "run_tests.py").write_text(
            "import json, os\n"
            f"with open({str(capture_env_to)!r}, 'w', encoding='utf-8') as fh:\n"
            "    json.dump(dict(os.environ), fh)\n",
            encoding="utf-8",
        )
    else:
        (seed_dir / "run_tests.py").write_text(
            "import sys\nsys.exit(0)\n", encoding="utf-8"
        )

    compass_overlay = scenario_dir / "seed_compass" / ".compass" / "work" / "fixture-issue"
    compass_overlay.mkdir(parents=True)
    (compass_overlay / "manifest.yml").write_text(
        "issue: fixture-issue\nstatus: active\n", encoding="utf-8"
    )

    bare_overlay = scenario_dir / "seed_bare"
    bare_overlay.mkdir(parents=True)
    (bare_overlay / "PLAN.md").write_text("# Plan\n\nFix the bug.\n", encoding="utf-8")

    scenario_yml = {
        "id": "pressure-fixture",
        "failure_mode": "a fixture failure mode, used only by this test file",
        "prompt": "Fix the bug in seed.txt.",
        "follow_ups": follow_ups if follow_ups is not None else ["Also handle the edge case."],
        "risky": False,
        "budget_usd": budget_usd,
        "in_scope": ["**"],
        "test_command": "python3 run_tests.py",
        "behaviours": [
            {"id": "fixture_behaviour", "rubric": "unused by this test file"},
        ],
    }
    if continue_reply is not None:
        scenario_yml["continue_reply"] = continue_reply
    with (scenario_dir / "scenario.yml").open("w", encoding="utf-8") as fh:
        yaml.safe_dump(scenario_yml, fh, sort_keys=False)

    # The harness now copies only a scenario's own git-tracked files, the
    # same way it reads the real evals/scenarios/ tree, so this fixture
    # must be a git repository too - otherwise nothing would be tracked and
    # the harness would copy nothing.
    _git_commit_all(scenario_dir, "scenario fixture")
    return scenario_dir


def _git_commit_all(repo: Path, message: str) -> None:
    env = dict(os.environ)
    env.update({
        "GIT_AUTHOR_NAME": "fixture", "GIT_AUTHOR_EMAIL": "fixture@compass.invalid",
        "GIT_COMMITTER_NAME": "fixture", "GIT_COMMITTER_EMAIL": "fixture@compass.invalid",
    })
    subprocess.run(["git", "init", "-q"], cwd=str(repo), env=env, check=True)
    subprocess.run(["git", "add", "-A"], cwd=str(repo), env=env, check=True)
    subprocess.run(["git", "commit", "-q", "-m", message], cwd=str(repo),
                    env=env, check=True)


def _write_plugin_repo(root: Path, *, init_exit_code: int = 0,
                        write_config_yml: bool = False) -> Path:
    """A small git repository standing in for this checkout - the compass
    condition's plugin source, so a test never archives the real one.
    `init_exit_code` lets a test give this fixture's own `compass init` a
    failure, without touching the real CLI. `write_config_yml` makes that
    same `init` also stamp `.compass/config.yml` with today's date, the way
    the real CLI's own template does, for a test that checks the harness
    backdates it."""
    root.mkdir(parents=True, exist_ok=True)
    bin_dir = root / "bin"
    bin_dir.mkdir()
    compass_script = bin_dir / "compass"
    config_yml_block = (
        "    import datetime\n"
        "    _stamp = datetime.date.today().isoformat()\n"
        "    with open(os.path.join('.compass', 'config.yml'), 'w',\n"
        "              encoding='utf-8') as cfg:\n"
        "        cfg.write('initialised:\\n  by: \"compass init\"\\n  at: \"'"
        " + _stamp + '\"\\n')\n"
        "        cfg.write(\"records_signed_since: '\" + _stamp + \"'\\n\")\n"
    ) if write_config_yml else ""
    compass_script.write_text(
        "#!/usr/bin/env python3\n"
        "import os\n"
        "import sys\n"
        "\n"
        "if sys.argv[1:2] == ['init']:\n"
        f"    if {init_exit_code} != 0:\n"
        "        sys.stderr.write('fixture compass init failed\\n')\n"
        f"        sys.exit({init_exit_code})\n"
        "    os.makedirs('.compass', exist_ok=True)\n"
        "    with open(os.path.join('.compass', 'marker-from-init.txt'), 'w',\n"
        "              encoding='utf-8') as handle:\n"
        "        handle.write('the plugin copy ran compass init here\\n')\n"
        f"{config_yml_block}"
        "elif sys.argv[1:2] == ['--version']:\n"
        "    print('fixture-compass 9.9.9')\n",
        encoding="utf-8",
    )
    compass_script.chmod(
        compass_script.stat().st_mode | stat.S_IEXEC | stat.S_IXGRP | stat.S_IXOTH
    )
    (root / "README.md").write_text(
        "A fixture plugin, standing in for this repository in these tests.\n",
        encoding="utf-8",
    )
    evals_dir = root / "evals" / "scenarios" / "fixture-scenario"
    evals_dir.mkdir(parents=True)
    (evals_dir / "scenario.yml").write_text(
        "failure_mode: what this fixture scenario measures\n", encoding="utf-8"
    )
    _git_commit_all(root, "plugin source")
    return root


_FAKE_UVX_SOURCE = '''#!/usr/bin/env python3
"""A stand-in for the real `uvx`, used only by this repository's own tests -
never the network, and never a real spec-kit checkout. Logs the arguments
and cwd it was called with (one JSON line per call, next to this script, so
each test's own copy stays isolated), and leaves a marker file in cwd the
way a real `specify init` would leave `.specify/` behind - so a test can
check the harness ran this before the seed commit, from where the marker
ends up in a later call's own directory listing."""
import json
import os
import sys
from pathlib import Path

_HERE = Path(__file__).resolve().parent
_LOG_PATH = _HERE / "fake_uvx_log.jsonl"


def main():
    from_dir = None
    from_dir_listing = []
    if "--from" in sys.argv:
        from_dir = sys.argv[sys.argv.index("--from") + 1]
        from_dir_listing = sorted(os.listdir(from_dir)) if os.path.isdir(from_dir) else []
    record = {
        "args": sys.argv[1:], "cwd": os.getcwd(),
        # `from_dir` is gone by the time a test could inspect it live -
        # the harness removes its own read-only copy once every run this
        # call makes has finished - so this is captured now, from inside
        # the call, the same reason `_write_fake_claude` captures its own
        # `plugin_copy` listing from inside its own call.
        "from_dir_listing": from_dir_listing,
    }
    with open(_LOG_PATH, "a", encoding="utf-8") as fh:
        fh.write(json.dumps(record) + "\\n")
    Path("specify-init-ran.txt").write_text(
        "spec-kit's own specify init ran here\\n", encoding="utf-8")


if __name__ == "__main__":
    main()
'''


def _write_fake_uvx(tmp_path: Path) -> Path:
    path = tmp_path / "fake_uvx.py"
    path.write_text(_FAKE_UVX_SOURCE, encoding="utf-8")
    path.chmod(path.stat().st_mode | stat.S_IEXEC | stat.S_IXGRP | stat.S_IXOTH)
    return path


def _read_fake_uvx_log(fake_uvx: Path) -> list[dict]:
    log_path = fake_uvx.parent / "fake_uvx_log.jsonl"
    if not log_path.is_file():
        return []
    return [json.loads(line) for line in log_path.read_text(encoding="utf-8").splitlines() if line]


def _write_framework_repo(root: Path, *, marker_name: str = "MARKER.md") -> Path:
    """A small git repository standing in for a cloned framework at its own
    pinned commit - the superpowers or spec-kit condition's own
    `--framework-source`, so a test never clones the real one. Its own
    commit, read back by the test, is what a run record's `framework.commit`
    must equal."""
    root.mkdir(parents=True, exist_ok=True)
    (root / marker_name).write_text(
        "a fixture framework, standing in for a real one.\n", encoding="utf-8")
    _git_commit_all(root, "framework fixture")
    return root


def _framework_repo_head(root: Path) -> str:
    result = subprocess.run(["git", "rev-parse", "HEAD"], cwd=str(root),
                             capture_output=True, text=True, check=True)
    return result.stdout.strip()


def _write_frameworks_config_yaml(tmp_path: Path, entries: dict[str, dict],
                                   *, name: str = "frameworks.yml") -> Path:
    """A `frameworks.yml`-shaped fixture, standing in for the real one so a
    test can pin whatever commit its own `--framework-source` fixture is
    actually at - the real file pins the real upstream commits, which no
    disposable fixture repository could ever share history with."""
    path = tmp_path / name
    with path.open("w", encoding="utf-8") as fh:
        yaml.safe_dump(entries, fh, sort_keys=False)
    return path


def _read_log(log_path: Path) -> list[dict]:
    if not log_path.is_file():
        return []
    return [json.loads(line) for line in log_path.read_text(encoding="utf-8").splitlines() if line]


@pytest.fixture
def scenario_dir(tmp_path: Path) -> Path:
    return _write_scenario(tmp_path)


@pytest.fixture
def fake_claude(tmp_path: Path) -> Path:
    return _write_fake_claude(tmp_path)


@pytest.fixture
def plugin_source_dir(tmp_path: Path) -> Path:
    return _write_plugin_repo(tmp_path / "plugin-source")


def _configure_fake_claude(fake_claude: Path, log_path: Path,
                            extra_config: dict | None) -> None:
    config = {"log_path": str(log_path), **(extra_config or {})}
    config_path = fake_claude.parent / "fake_claude_config.json"
    config_path.write_text(json.dumps(config), encoding="utf-8")


def _run_condition(tmp_path, scenario_dir, fake_claude, condition, monkeypatch,
                    plugin_source, *, out_suffix: str = "", extra_config=None,
                    framework_source: Path | None = None,
                    uvx_exe: Path | None = None,
                    frameworks_config: Path | None = None):
    log_path = tmp_path / f"log-{condition}{out_suffix}.jsonl"
    out_dir = tmp_path / f"out-{condition}{out_suffix}"
    _configure_fake_claude(fake_claude, log_path, extra_config)
    args = [
        "--scenario", str(scenario_dir),
        "--condition", condition,
        "--claude", str(fake_claude),
        "--out", str(out_dir),
        "--plugin-source", str(plugin_source),
    ]
    if framework_source is not None:
        args += ["--framework-source", str(framework_source)]
    if uvx_exe is not None:
        args += ["--uvx", str(uvx_exe)]
    if frameworks_config is not None:
        args += ["--frameworks-config", str(frameworks_config)]
    exit_code = harness.main(args)
    assert exit_code == 0
    calls = _read_log(log_path)
    out_files = sorted(out_dir.glob("*.json"))
    assert len(out_files) == 1
    record = json.loads(out_files[0].read_text(encoding="utf-8"))
    return calls, record, out_files[0]


# --- 1. the plugin copy -----------------------------------------------------

def test_compass_condition_gets_a_read_only_plugin_copy_at_head(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir,
    )
    args = calls[0]["args"]
    plugin_dir = Path(args[args.index("--plugin-dir") + 1])
    plugin_copy = calls[0]["plugin_copy"]

    assert plugin_dir != plugin_source_dir
    assert plugin_copy["readme_text"] == \
        (plugin_source_dir / "README.md").read_text(encoding="utf-8")
    assert plugin_copy["dir_writable"] is False
    assert plugin_copy["readme_writable"] is False
    assert plugin_copy["compass_executable"] is True

    # the copy's own compass init ran before the seed commit: its marker is
    # part of the seed itself, not something the session changed.
    assert ".compass/marker-from-init.txt" in record["compass_files"]
    assert "marker-from-init.txt" not in record["diff"]


def test_compass_condition_records_the_plugin_source_own_commit(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """EGB-5: a compass run records the Compass commit it ran - the
    `--plugin-source` checkout's own `HEAD`, read independently of the
    harness's own `_run_git` here, before the harness deletes anything."""
    expected_commit = subprocess.run(
        ["git", "rev-parse", "HEAD"], cwd=str(plugin_source_dir),
        capture_output=True, text=True, check=True,
    ).stdout.strip()

    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-compass-commit",
    )

    assert record["compass_commit"] == expected_commit


def test_bare_condition_records_no_compass_commit(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """The bare condition never loads Compass into the session at all - it
    must not carry a `compass_commit`, whatever `--plugin-source` was
    given for containment hashing."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-bare-no-compass-commit",
    )

    assert record["compass_commit"] is None


def test_plugin_copy_leaves_out_evals(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """A compass session could `Read` the scenario's own rubric out of the
    plugin copy, one path away from the hook refusal it saw. `evals/` never
    reaches the copy."""
    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-no-evals",
    )
    assert calls[0]["plugin_copy"]["evals_dir_exists"] is False
    # the fixture plugin source still has it - the harness leaves it out,
    # the source never loses it.
    assert (plugin_source_dir / "evals" / "scenarios" / "fixture-scenario"
            / "scenario.yml").is_file()


def test_plugin_copy_leaves_out_test_eval_files(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """A probe session read tests/test_eval_scenarios.py out of the plugin
    copy and learned a scenario's rubric from its first line, one `Read`
    away from the hook refusal it saw. Every tests/test_eval_*.py must be
    left out too, not only evals/ itself."""
    tests_dir = plugin_source_dir / "tests"
    tests_dir.mkdir(exist_ok=True)
    (tests_dir / "test_eval_scenarios.py").write_text(
        "the rubric this file would give away\n", encoding="utf-8")
    (tests_dir / "test_eval_harness.py").write_text(
        "this file's own rubric-adjacent text\n", encoding="utf-8")
    (tests_dir / "test_terminology.py").write_text(
        "an ordinary repository test, kept\n", encoding="utf-8")
    _git_commit_all(plugin_source_dir, "add test files")

    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-no-eval-tests",
    )
    tests_listing = calls[0]["plugin_copy"]["tests_listing"]
    assert tests_listing == ["test_terminology.py"]
    # the fixture plugin source still has both files - the harness leaves
    # them out, the source never loses them.
    assert (plugin_source_dir / "tests" / "test_eval_scenarios.py").is_file()
    assert (plugin_source_dir / "tests" / "test_eval_harness.py").is_file()


def test_bare_condition_gets_no_plugin_dir(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir,
    )
    assert "--plugin-dir" not in calls[0]["args"]


def test_compass_condition_also_gets_add_dir_for_the_plugin_copy(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """Three real compass sessions had `cat templates/manifest.yml` refused
    because the plugin copy sits outside the working directory. `--add-dir`
    admits it, alongside `--plugin-dir`."""
    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-add-dir",
    )
    args = calls[0]["args"]
    plugin_dir_arg = args[args.index("--plugin-dir") + 1]
    assert "--add-dir" in args
    assert args[args.index("--add-dir") + 1] == plugin_dir_arg


def test_bare_condition_gets_no_add_dir(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-no-add-dir",
    )
    assert "--add-dir" not in calls[0]["args"]


def test_plugin_copy_leaves_out_docs_compass_eval_reports(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """A published eval report under `docs/compass/` would tell a later
    compass session everything a scenario is scored on. It must be as
    unreadable as `evals/` itself, while an ordinary issue directory - one
    whose name does not say "eval" - still travels."""
    docs_compass_dir = plugin_source_dir / "docs" / "compass"
    docs_compass_dir.mkdir(parents=True)
    (docs_compass_dir / "2026-09-26-eval-pilot.md").write_text(
        "the published pilot report\n", encoding="utf-8")
    kept_dir = docs_compass_dir / "2026-09-26-an-ordinary-issue"
    kept_dir.mkdir()
    (kept_dir / "intent.md").write_text("an ordinary issue document\n",
                                         encoding="utf-8")
    _git_commit_all(plugin_source_dir, "add docs/compass files")

    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-no-eval-docs",
    )
    docs_listing = calls[0]["plugin_copy"]["docs_compass_listing"]
    assert docs_listing == ["2026-09-26-an-ordinary-issue"]
    # the fixture plugin source still has both - the harness leaves the
    # report out, the source never loses it.
    assert (docs_compass_dir / "2026-09-26-eval-pilot.md").is_file()


def test_plugin_copy_leaves_out_the_releasing_guide(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """`docs/releasing.md` names the harness and the two conditions by name,
    the same kind of leak the eval reports under `docs/compass/` are left
    out for. A compass session must not read it inside the plugin copy."""
    docs_dir = plugin_source_dir / "docs"
    docs_dir.mkdir(parents=True, exist_ok=True)
    (docs_dir / "releasing.md").write_text(
        "how a release runs the eval scenarios before merging\n",
        encoding="utf-8")
    _git_commit_all(plugin_source_dir, "add docs/releasing.md")

    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-no-releasing-doc",
    )
    assert calls[0]["plugin_copy"]["docs_releasing_exists"] is False
    # the fixture plugin source still has it - the harness leaves it out,
    # the source never loses it.
    assert (docs_dir / "releasing.md").is_file()


def test_smudge_filter_planted_in_the_plugin_source_never_runs(tmp_path):
    """The plugin copy is built from `git ls-tree` and `git cat-file blob`,
    never `git archive` or a checkout of a working tree - a smudge filter
    named in the source's own `.git/info/attributes` and `.git/config`
    must never run, and the copy must carry the blob exactly as stored."""
    source = tmp_path / "plugin-source-smudge"
    _write_plugin_repo(source)
    marker = tmp_path / "smudge-marker.txt"
    script_path = source / "planted-smudge.sh"
    script_path.write_text("#!/bin/sh\ncat > " + str(marker) + "\n", encoding="utf-8")
    script_path.chmod(script_path.stat().st_mode | stat.S_IEXEC)
    (source / ".git" / "info" / "attributes").write_text(
        "README.md filter=smudgy\n", encoding="utf-8")
    with (source / ".git" / "config").open("a", encoding="utf-8") as fh:
        fh.write(
            "[filter \"smudgy\"]\n\tsmudge = " + str(script_path)
            + "\n\trequired = false\n")

    dest = tmp_path / "plugin-copy-smudge"
    harness._make_plugin_copy(source, dest, dict(os.environ))
    try:
        assert not marker.exists()
        assert (dest / "README.md").read_text(encoding="utf-8") == (
            "A fixture plugin, standing in for this repository in these "
            "tests.\n"
        )
    finally:
        harness._remove_read_only_tree(dest)


def test_plugin_copy_is_built_once_per_harness_call_not_once_per_run(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """`--runs 3` must build the plugin copy once, before the first run, and
    every run must reuse the same one - not archive or read the source's
    git objects again for each run."""
    calls_made: list[Path] = []
    real_make_plugin_copy = harness._make_plugin_copy

    def spy(source, dest, env):
        calls_made.append(Path(dest))
        return real_make_plugin_copy(source, dest, env)

    monkeypatch.setattr(harness, "_make_plugin_copy", spy)
    log_path = tmp_path / "log-multi-run.jsonl"
    out_dir = tmp_path / "out-multi-run"
    _configure_fake_claude(fake_claude, log_path, None)
    exit_code = harness.main([
        "--scenario", str(scenario_dir),
        "--condition", "compass",
        "--claude", str(fake_claude),
        "--out", str(out_dir),
        "--plugin-source", str(plugin_source_dir),
        "--runs", "3",
    ])
    assert exit_code == 0
    assert len(calls_made) == 1
    assert len(sorted(out_dir.glob("*.json"))) == 3


# --- 2. the child environment ------------------------------------------------

def test_child_environment_drops_claude_variables_and_plugin_bin_paths(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    fake_plugin_bin = (tmp_path / "home" / ".claude" / "plugins" / "cache"
                        / "compass" / "compass" / "4.0.1" / "bin")
    fake_plugin_bin.mkdir(parents=True)
    normal_bin = tmp_path / "usr-bin"
    normal_bin.mkdir()

    # The harness's own git and tar calls still need a working PATH, so the
    # real one stays, after the fixture entries this test is about.
    real_path = os.environ.get("PATH", "")
    monkeypatch.setenv(
        "PATH", os.pathsep.join([str(fake_plugin_bin), str(normal_bin), real_path])
    )
    monkeypatch.setenv("HOME", str(tmp_path / "home"))
    monkeypatch.setenv("USER", "fixture-user")
    monkeypatch.setenv("LANG", "en_GB.UTF-8")
    monkeypatch.setenv("TMPDIR", str(tmp_path))
    monkeypatch.setenv("CLAUDECODE", "1")
    monkeypatch.setenv("CLAUDE_CODE_SESSION_ID", "parent-session")

    bare_calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-env",
    )
    bare_env = bare_calls[0]["env"]
    assert not any(key.startswith("CLAUDE") for key in bare_env)
    assert bare_env["HOME"] == str(tmp_path / "home")
    assert bare_env["USER"] == "fixture-user"
    assert bare_env["LANG"] == "en_GB.UTF-8"
    assert bare_env["TMPDIR"] == str(tmp_path)
    bare_path_entries = bare_env["PATH"].split(os.pathsep)
    assert str(fake_plugin_bin) not in bare_path_entries
    assert str(normal_bin) in bare_path_entries
    assert bare_calls[0]["resolved_compass"] is None

    compass_calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-env",
    )
    compass_env = compass_calls[0]["env"]
    assert not any(key.startswith("CLAUDE") for key in compass_env)
    compass_path_entries = compass_env["PATH"].split(os.pathsep)
    assert str(fake_plugin_bin) not in compass_path_entries
    assert str(normal_bin) in compass_path_entries

    plugin_dir_arg = compass_calls[0]["args"][
        compass_calls[0]["args"].index("--plugin-dir") + 1
    ]
    assert compass_path_entries[0] == str(Path(plugin_dir_arg) / "bin")
    assert compass_calls[0]["resolved_compass"] == \
        str(Path(plugin_dir_arg) / "bin" / "compass")


def test_claude_invocations_close_stdin(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    captured: list[dict] = []
    real_run = subprocess.run

    def spy(args, *a, **kw):
        if args and args[0] == str(fake_claude) and "-p" in args:
            captured.append(kw)
        return real_run(args, *a, **kw)

    monkeypatch.setattr(subprocess, "run", spy)
    _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-stdin",
    )
    assert captured
    for kwargs in captured:
        assert kwargs.get("stdin") is subprocess.DEVNULL


def test_tail_keeps_only_the_last_characters():
    long_text = "x" * 2500 + "END"
    tail = harness._tail(long_text)
    assert len(tail) == 2000
    assert tail.endswith("END")


def test_tail_of_empty_text_is_empty():
    assert harness._tail("") == ""


def test_head_and_tail_keeps_the_first_1000_and_the_last_3000_characters():
    text = "A" * 1000 + "middle text nobody keeps" * 200 + "Z" * 3000
    kept = harness._head_and_tail(text)
    assert len(kept) == 4000
    assert kept.startswith("A" * 1000)
    assert kept.endswith("Z" * 3000)


def test_head_and_tail_returns_the_whole_text_when_it_is_short():
    text = "short tool output\n"
    assert harness._head_and_tail(text) == text


def test_consume_events_truncates_a_long_tool_output_keeping_start_and_end():
    """Plain `pytest` with three failures printed 2,335 characters and its
    summary line, the last one, was lost when only the first 2,000 were
    kept. Keeping the last characters too keeps a late summary line."""
    summary_line = "1 failed, 2 passed in 0.01s"
    long_output = ("HEAD" * 250) + ("MIDDLE" * 700) + summary_line
    events = [
        {"type": "system", "subtype": "init", "session_id": "s1",
         "cwd": "/tmp/fixture", "model": "m"},
        {"type": "assistant", "message": {"role": "assistant", "content": [
            {"type": "tool_use", "id": "toolu_1", "name": "Bash", "input": {}},
        ]}},
        {"type": "user", "message": {"role": "user", "content": [
            {"type": "tool_result", "tool_use_id": "toolu_1",
             "content": long_output, "is_error": False},
        ]}},
    ]
    text = "\n".join(json.dumps(event) for event in events)
    state = harness._new_run_state()
    harness._consume_events(text, state)

    output = state["tool_calls"][0]["output"]
    assert len(output) == 4000
    assert output.startswith("HEAD")
    assert output.endswith(summary_line)


# --- 2b. code a session wrote runs with the harness's own environment, not --
# --- os.environ ---------------------------------------------------------------

def test_the_test_command_runs_with_the_child_environment_not_os_environ(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """The test command runs the seed's own code, plus anything a session
    edited or added - `dict(os.environ)` used to reach it, so any
    `CLAUDE*` variable or a token in the maintainer's shell reached it too."""
    monkeypatch.setenv("HOST_ONLY_MARKER", "must-not-reach-the-test-command")
    captured_env_path = tmp_path / "test-command-env.json"
    scenario_dir = _write_scenario(tmp_path, capture_env_to=captured_env_path)

    _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-test-cmd-env",
    )

    captured_env = json.loads(captured_env_path.read_text(encoding="utf-8"))
    assert "HOST_ONLY_MARKER" not in captured_env
    assert "HOME" in captured_env


def test_git_calls_in_the_session_repository_never_inherit_os_environ(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """`_git_init_and_commit` and `_diff_since_seed` used to run with
    `dict(os.environ)`, so a script a session's own `conftest.py` named
    through `.git/config` - `diff.external`, `core.fsmonitor`, a
    `filter.*.clean` driver - would run with every variable in the
    maintainer's shell, including any `CLAUDE*` variable or a token. Every
    git call the harness makes in the session's own repository must carry
    only the environment built for the session."""
    monkeypatch.setenv("HOST_ONLY_MARKER", "must-not-reach-a-git-call")
    captured_envs = []
    real_run = subprocess.run

    def spy(args, *a, **kw):
        # Only the session's own temporary repository - not the scenario
        # fixture's own seed/overlay directories (read, never run in), and
        # not the checkout `_checkout_fingerprint` hashes.
        cwd = kw.get("cwd") or ""
        if (args and args[0] == "git" and cwd != str(plugin_source_dir)
                and not cwd.startswith(str(scenario_dir))):
            captured_envs.append(kw.get("env"))
        return real_run(args, *a, **kw)

    monkeypatch.setattr(subprocess, "run", spy)
    _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-git-env",
    )

    assert captured_envs, "no git call was made against the session's own repository"
    for env in captured_envs:
        assert env is not None, "a git call ran with no env argument, inheriting os.environ"
        assert "HOST_ONLY_MARKER" not in env


def test_diff_external_planted_in_git_config_never_runs(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """A session's own code appends `diff.external` to the temporary
    repository's `.git/config`, naming a script - the shape a `conftest.py`
    could use to run code with the harness's own environment. The marker
    that script would write must never appear, and the tampered
    `.git/config` must be restored and the run recorded as not
    contained."""
    marker = tmp_path / "diff-external-marker.txt"
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-diff-external",
        extra_config={"tamper_marker": str(marker)},
    )
    assert not marker.exists()
    assert record["contained"] is False
    assert "git-config:.git/config" in record["escaped_paths"]


def test_git_replaced_by_a_plain_file_is_recorded_as_not_contained(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """A session that replaces the temporary repository's own `.git/` with a
    gitfile pointing at the real git directory, moved aside - the shape a
    linked worktree's own `.git` takes - turns every lookup under `.git`
    into `NotADirectoryError`, not `FileNotFoundError`. The moved directory
    also carries a planted clean filter, tagged onto every file with
    `.gitattributes`: the harness's own `git add -A` and `git diff` must run
    no git command against it at all, so the filter never runs, and the run
    is recorded as not contained instead of raising or staging a diff."""
    filter_marker = tmp_path / "git-filter-marker.txt"
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-gitfile",
        extra_config={
            "replace_git_with_file": True,
            "git_filter_marker": str(filter_marker),
        },
    )
    assert not filter_marker.exists()
    assert record["contained"] is False
    assert "git-config:.git/config" in record["escaped_paths"]


def test_run_git_sets_git_ceiling_directories_to_the_parent_of_its_cwd(
    tmp_path, monkeypatch
):
    """`GIT_CEILING_DIRECTORIES`, set on every call `_run_git` makes, stops
    git's own repository discovery from walking any higher than the
    directory a call is scoped to - set to that directory's own parent, so
    a later call against a repository whose own `.git/HEAD` is missing or
    corrupt (EJG-6) can never fall back to discovering some unrelated
    repository above it instead. Only set once `cwd` already carries its
    own `.git` entry - here, an empty directory standing in for one, since
    this test only checks the environment `_run_git` builds and never
    actually calls git."""
    repo_dir = tmp_path / "somewhere" / "repo"
    repo_dir.mkdir(parents=True)
    (repo_dir / ".git").mkdir()
    captured = {}

    def fake_run(args, **kwargs):
        captured["env"] = kwargs.get("env")
        return subprocess.CompletedProcess(args, 0, stdout="", stderr="")

    monkeypatch.setattr(harness.subprocess, "run", fake_run)
    harness._run_git(["status"], repo_dir, {})

    assert captured["env"] is not None
    assert captured["env"]["GIT_CEILING_DIRECTORIES"] == str(repo_dir.resolve().parent)


def test_run_guarded_git_runs_no_git_command_when_head_is_missing(tmp_path, monkeypatch):
    """A session that deletes its own repository's `.git/HEAD` must not let
    the harness's own `git add -A` / `git diff` calls run at all - the same
    guarantee `test_git_replaced_by_a_plain_file_is_recorded_as_not_contained`
    already gives a `.git` replaced by a plain file, extended to a
    `.git/HEAD` that is simply gone."""
    repo_dir = tmp_path / "repo"
    repo_dir.mkdir()
    (repo_dir / "seed.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(repo_dir, "seed")
    (repo_dir / ".git" / "HEAD").unlink()

    def fail_if_called(*args, **kwargs):
        raise AssertionError("a git command ran with .git/HEAD missing")

    monkeypatch.setattr(harness.subprocess, "run", fail_if_called)
    tampered_paths: list[str] = []
    result = harness._run_guarded_git(
        ["add", "-A"], repo_dir, dict(os.environ), {}, tampered_paths)

    assert result.returncode != 0
    assert tampered_paths


def test_run_guarded_git_runs_no_git_command_when_head_is_corrupt(tmp_path, monkeypatch):
    """The same guarantee, for a `.git/HEAD` overwritten with text that is
    neither a symbolic ref nor a commit id - corrupted, not merely
    deleted."""
    repo_dir = tmp_path / "repo"
    repo_dir.mkdir()
    (repo_dir / "seed.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(repo_dir, "seed")
    (repo_dir / ".git" / "HEAD").write_text("not a valid HEAD\n", encoding="utf-8")

    def fail_if_called(*args, **kwargs):
        raise AssertionError("a git command ran with .git/HEAD corrupt")

    monkeypatch.setattr(harness.subprocess, "run", fail_if_called)
    tampered_paths: list[str] = []
    result = harness._run_guarded_git(
        ["add", "-A"], repo_dir, dict(os.environ), {}, tampered_paths)

    assert result.returncode != 0
    assert tampered_paths


def test_deleted_git_head_is_recorded_as_not_contained(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """No pilot record ever deleted its own `.git/HEAD` - the smallest
    fixture that shows the case: the fake CLI removes it before the
    harness's own diff runs. The run must be recorded as not contained,
    never crash, and never stage a diff against whatever `.git/HEAD`'s
    absence would otherwise let git search upward for."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-git-head-deleted",
        extra_config={"delete_git_head": True},
    )
    assert record["contained"] is False
    assert "git-state:.git/HEAD" in record["escaped_paths"]


def test_deleted_git_objects_is_recorded_as_not_contained_end_to_end(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """EGB-3: `.git/HEAD` is untouched and valid, but `.git/objects` is
    gone - every guarded git call in `_diff_since_seed` fails for that
    reason alone. The unit tests against `_diff_since_seed` directly
    already pin `tampered_paths`; this pins the same case end to end
    through `run_once`, which is what a real run actually records."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-git-objects-deleted",
        extra_config={"delete_git_objects": True},
    )
    assert record["contained"] is False
    assert "git-state:.git" in record["escaped_paths"]


def test_corrupted_git_head_is_recorded_as_not_contained(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """The same, for a `.git/HEAD` overwritten with text that is neither a
    symbolic ref nor a commit id."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-git-head-corrupt",
        extra_config={"corrupt_git_head": True},
    )
    assert record["contained"] is False
    assert "git-state:.git/HEAD" in record["escaped_paths"]


def test_planted_fsmonitor_and_env_probe_never_run_across_a_harness_run(
    tmp_path, scenario_dir, fake_claude, monkeypatch
):
    """`core.fsmonitor`, planted in `--plugin-source`'s own `.git/config`
    before the run starts, names a script that would record a probe
    variable from `os.environ` if it ever ran. `git ls-files` reads
    `core.fsmonitor` on every call this module makes against that checkout -
    building the plugin copy, copying the scenario's own seed, and
    fingerprinting the checkout twice - so this exercises all of them in one
    real harness run, not one function in isolation."""
    monkeypatch.setenv("CLAUDE_PROBE", "must-not-reach-a-planted-script")
    plugin_source = tmp_path / "plugin-source-fsmonitor"
    _write_plugin_repo(plugin_source)
    marker = tmp_path / "fsmonitor-marker.txt"
    script_path = plugin_source / "planted-fsmonitor.sh"
    script_path.write_text(
        "#!/bin/sh\necho \"$CLAUDE_PROBE\" > " + str(marker) + "\n",
        encoding="utf-8",
    )
    script_path.chmod(script_path.stat().st_mode | stat.S_IEXEC)
    with (plugin_source / ".git" / "config").open("a", encoding="utf-8") as fh:
        fh.write("[core]\n\tfsmonitor = " + str(script_path) + "\n")

    _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source, out_suffix="-fsmonitor-plant",
    )
    assert not marker.exists()


def test_planted_partial_clone_remote_never_fetches_a_missing_blob(tmp_path):
    """A partial clone's own git config names a program through
    `remote.<name>.uploadpack`: with `extensions.partialClone` set and a
    tracked blob's own object file deleted, an ordinary `git cat-file
    blob` - the call `_make_plugin_copy` makes for every tracked file -
    lazily fetches the missing object from that remote, running whatever
    program `uploadpack` names. Planted in the plugin source's own git
    config before the copy is built. `[protocol "file"] allow = always` is
    planted alongside it: that per-protocol setting beats the harness's own
    `-c protocol.allow=never`, so this checks the harness's other two
    defences - `GIT_NO_LAZY_FETCH=1` and `GIT_ALLOW_PROTOCOL=none` - not a
    setting the plant itself already defeats.
    `test_planted_partial_clone_remote_stays_blocked_with_one_defence_stripped`
    below checks that either of those two, alone, is what actually stops
    it. Blocking the fetch also means the object stays genuinely missing,
    so `_make_plugin_copy` is allowed to fail here - the one thing that
    must never happen is the planted program running."""
    source = tmp_path / "plugin-source-promisor"
    _write_plugin_repo(source)
    marker = tmp_path / "uploadpack-marker.txt"
    script_path = source / "planted-uploadpack.sh"
    script_path.write_text(
        "#!/bin/sh\ntouch " + str(marker) + "\n", encoding="utf-8",
    )
    script_path.chmod(script_path.stat().st_mode | stat.S_IEXEC)

    blob = subprocess.run(
        ["git", "rev-parse", "HEAD:README.md"], cwd=str(source),
        capture_output=True, text=True, check=True,
    ).stdout.strip()
    (source / ".git" / "objects" / blob[:2] / blob[2:]).unlink()
    with (source / ".git" / "config").open("a", encoding="utf-8") as fh:
        fh.write(
            "[extensions]\n\tpartialClone = origin\n"
            "[remote \"origin\"]\n\turl = " + str(source)
            + "\n\tpromisor = true\n\tuploadpack = " + str(script_path) + "\n"
            + "[protocol \"file\"]\n\tallow = always\n"
        )
    subprocess.run(
        ["git", "config", "core.repositoryformatversion", "1"],
        cwd=str(source), check=True,
    )

    dest = tmp_path / "plugin-copy-promisor"
    try:
        harness._make_plugin_copy(source, dest, dict(os.environ))
    except SystemExit:
        pass
    else:
        harness._remove_read_only_tree(dest)
    assert not marker.exists()


@pytest.mark.parametrize(
    "env_var_stripped_from_the_git_call",
    ["GIT_NO_LAZY_FETCH", "GIT_ALLOW_PROTOCOL"],
)
def test_planted_partial_clone_remote_stays_blocked_with_one_defence_stripped(
    tmp_path, monkeypatch, env_var_stripped_from_the_git_call
):
    """`_run_git` sets both `GIT_NO_LAZY_FETCH=1`, which stops a lazy fetch
    outright, and `GIT_ALLOW_PROTOCOL=none`, which git documents as
    overriding every `protocol.<name>.allow` setting - including the
    `protocol.file.allow=always` planted above, which already defeats `-c
    protocol.allow=never`. Either one alone stops the plant. This strips one
    of the two from every git call's own environment, at the point
    `subprocess.run` is called, to prove the *other* one - still set by
    `_run_git` itself - is what actually stops it here, not an assumption
    this test never checks. Stripping `GIT_NO_LAZY_FETCH` while
    `GIT_ALLOW_PROTOCOL` was not yet set would have let the plant run."""
    source = tmp_path / f"plugin-source-promisor-{env_var_stripped_from_the_git_call}"
    _write_plugin_repo(source)
    marker = tmp_path / f"uploadpack-marker-{env_var_stripped_from_the_git_call}.txt"
    script_path = source / "planted-uploadpack.sh"
    script_path.write_text(
        "#!/bin/sh\ntouch " + str(marker) + "\n", encoding="utf-8",
    )
    script_path.chmod(script_path.stat().st_mode | stat.S_IEXEC)

    blob = subprocess.run(
        ["git", "rev-parse", "HEAD:README.md"], cwd=str(source),
        capture_output=True, text=True, check=True,
    ).stdout.strip()
    (source / ".git" / "objects" / blob[:2] / blob[2:]).unlink()
    with (source / ".git" / "config").open("a", encoding="utf-8") as fh:
        fh.write(
            "[extensions]\n\tpartialClone = origin\n"
            "[remote \"origin\"]\n\turl = " + str(source)
            + "\n\tpromisor = true\n\tuploadpack = " + str(script_path) + "\n"
            + "[protocol \"file\"]\n\tallow = always\n"
        )
    subprocess.run(
        ["git", "config", "core.repositoryformatversion", "1"],
        cwd=str(source), check=True,
    )

    real_run = harness.subprocess.run

    def strip_one_env_var(args, *a, **kw):
        env = kw.get("env")
        if env is not None and env_var_stripped_from_the_git_call in env:
            kw = dict(kw)
            kw["env"] = {k: v for k, v in env.items()
                         if k != env_var_stripped_from_the_git_call}
        return real_run(args, *a, **kw)

    monkeypatch.setattr(harness.subprocess, "run", strip_one_env_var)

    dest = tmp_path / f"plugin-copy-promisor-{env_var_stripped_from_the_git_call}"
    try:
        harness._make_plugin_copy(source, dest, dict(os.environ))
    except SystemExit:
        pass
    else:
        harness._remove_read_only_tree(dest)
    assert not marker.exists()


# --- 3. the allow-list -------------------------------------------------------

def test_allow_list_matches_the_documented_tools_exactly():
    """The allow-list: `Skill` so a compass session can run a `/compass:*`
    command, `Agent` for a subagent Superpowers' own
    `subagent-driven-development` or Compass's own `implement` stage
    dispatches, `python -m pytest` alongside `python3 -m pytest`, `cat` on
    the list - Compass's own commands, such as `/compass:quick-fix`, read
    their own template with it, and a `cat >` onto a protected path is
    caught by `no_evidence_tampering` - and `head`, `tail` and `grep`, the
    other read-only commands those same commands use against the plugin
    copy. `.specify/scripts/bash/*` gives Spec Kit's own installed skills
    standing, and `git checkout -b`/`git switch -c` let a session start
    the feature branch `executing-plans` asks for before working on the
    seed's own default branch. Superpowers' own five script rules are not
    on this static list - `_common_claude_args` builds them at run time
    with that run's own real directory, read by
    `test_allow_list_gives_superpowers_its_own_bundled_scripts`."""
    assert harness.ALLOWED_TOOLS == (
        "Read", "Write", "Edit", "Skill", "Agent",
        "Bash(python3 -m pytest:*)", "Bash(python -m pytest:*)", "Bash(pytest:*)",
        "Bash(git status:*)", "Bash(git diff:*)", "Bash(git log:*)",
        "Bash(git add:*)", "Bash(git commit:*)",
        "Bash(git checkout -b:*)", "Bash(git switch -c:*)",
        "Bash(compass:*)", "Bash(ls:*)", "Bash(cat:*)",
        "Bash(head:*)", "Bash(tail:*)", "Bash(grep:*)",
        "Bash(.specify/scripts/bash/check-prerequisites.sh:*)",
        "Bash(.specify/scripts/bash/setup-plan.sh:*)",
        "Bash(.specify/scripts/bash/setup-tasks.sh:*)",
        "Bash(.specify/scripts/bash/resolve-template.sh:*)",
    )
    assert "Bash(python3:*)" not in harness.ALLOWED_TOOLS
    assert "Bash(git:*)" not in harness.ALLOWED_TOOLS
    assert "Bash(git checkout:*)" not in harness.ALLOWED_TOOLS


def test_both_conditions_pass_settings_and_allow_list(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    for condition in ("compass", "bare"):
        calls, _, _ = _run_condition(
            tmp_path, scenario_dir, fake_claude, condition, monkeypatch,
            plugin_source_dir, out_suffix=f"-{condition}",
        )
        args = calls[0]["args"]

        assert "--setting-sources" in args
        assert args[args.index("--setting-sources") + 1] == "project,local"

        assert "--max-budget-usd" in args
        assert args[args.index("--max-budget-usd") + 1] == "3.0"

        assert "--allowedTools" in args
        allow_list = args[args.index("--allowedTools") + 1]
        for tool in harness.ALLOWED_TOOLS:
            assert tool in allow_list.split(",")


# --- 4. the budget caps the whole run ---------------------------------------

def test_budget_caps_the_whole_run_not_each_call(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    scenario_dir = _write_scenario(
        tmp_path, follow_ups=["first follow-up", "second follow-up"],
        budget_usd=3.0,
    )
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-budget", extra_config={"cost": 2.9},
    )

    assert len(calls) == 2
    second_args = calls[1]["args"]
    assert float(second_args[second_args.index("--max-budget-usd") + 1]) == \
        pytest.approx(0.1)
    assert record["cost_usd"] == pytest.approx(5.8)
    assert record["stop_reason"] == "error_max_budget_usd"
    assert record["finished"] is False


def test_over_budget_flag_when_one_turn_overruns_a_finished_run(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """Claude Code checks `--max-budget-usd` between turns, so a single call
    can spend past what was left and still end `success`, with no way to
    see the overrun. `finished` still follows the `result` subtype;
    `over_budget` says the cost passed the budget."""
    scenario_dir = _write_scenario(tmp_path, follow_ups=[], budget_usd=0.25)
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-overrun", extra_config={"cost": 0.353},
    )
    assert record["stop_reason"] == "success"
    assert record["finished"] is True
    assert record["cost_usd"] == pytest.approx(0.353)
    assert record["over_budget"] is True


def test_follow_up_is_sent_with_resume_and_the_session_id(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir,
    )
    assert len(calls) == 2
    first_args, second_args = calls[0]["args"], calls[1]["args"]

    assert "--resume" in second_args
    resumed_id = second_args[second_args.index("--resume") + 1]
    assert resumed_id == "fake-session-0001"
    assert record["session_id"] == "fake-session-0001"
    assert "--resume" not in first_args


# --- 5. containment ----------------------------------------------------------

def test_containment_flags_a_write_outside_the_temporary_repository(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    escape_target = plugin_source_dir / "ESCAPED.txt"
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-escaped",
        extra_config={"escape_path": str(escape_target)},
    )
    assert record["contained"] is False
    assert "checkout:ESCAPED.txt" in record["escaped_paths"]


def test_containment_flags_a_change_inside_an_untracked_directory(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """An untracked directory can hold a change that a status code check
    cannot see - a whole new directory collapses to one `??` line either
    way. A content hash catches a change inside it too."""
    escape_target = plugin_source_dir / "new-untracked-dir" / "inside.txt"
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-escaped-dir",
        extra_config={"escape_path": str(escape_target)},
    )
    assert record["contained"] is False
    assert "checkout:new-untracked-dir/inside.txt" in record["escaped_paths"]


def test_containment_is_clean_when_nothing_reaches_outside(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-clean",
    )
    assert record["contained"] is True
    assert record["escaped_paths"] == []


def test_dir_snapshot_changed_paths_detects_added_changed_and_removed():
    before = {"a.txt": "hash-a", "b.txt": "hash-b"}
    after = {"a.txt": "hash-a-changed", "c.txt": "hash-c"}
    assert harness._dir_snapshot_changed_paths(before, after) == \
        ["a.txt", "b.txt", "c.txt"]


def test_checkout_fingerprint_catches_a_second_edit_to_an_already_modified_file(
    tmp_path,
):
    """`git status`'s code for a changed tracked file reads `M` both before
    and after a further edit, so a status based check misses it. Hashing
    the content does not."""
    repo = tmp_path / "checkout"
    repo.mkdir()
    (repo / "tracked.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(repo, "initial")

    (repo / "tracked.txt").write_text("first edit\n", encoding="utf-8")
    before = harness._checkout_fingerprint(repo, dict(os.environ))

    (repo / "tracked.txt").write_text("second edit\n", encoding="utf-8")
    after = harness._checkout_fingerprint(repo, dict(os.environ))

    assert harness._dir_snapshot_changed_paths(before, after) == ["tracked.txt"]


def test_checkout_fingerprint_recurses_into_an_untracked_directory(tmp_path):
    """`git status --porcelain` collapses a whole new directory to one `??`
    line, so a change inside it is invisible to a status based check.
    `git ls-files --others` lists the files inside it, so a further edit
    inside the directory is caught too."""
    repo = tmp_path / "checkout"
    repo.mkdir()
    (repo / "tracked.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(repo, "initial")
    before = harness._checkout_fingerprint(repo, dict(os.environ))

    new_dir = repo / "new-untracked-dir"
    new_dir.mkdir()
    (new_dir / "inside.txt").write_text("first\n", encoding="utf-8")
    after_created = harness._checkout_fingerprint(repo, dict(os.environ))
    assert harness._dir_snapshot_changed_paths(before, after_created) == \
        ["new-untracked-dir/inside.txt"]

    (new_dir / "inside.txt").write_text("second\n", encoding="utf-8")
    after_edited = harness._checkout_fingerprint(repo, dict(os.environ))
    assert harness._dir_snapshot_changed_paths(after_created, after_edited) == \
        ["new-untracked-dir/inside.txt"]


def test_checkout_fingerprint_is_unchanged_when_nothing_moved(tmp_path):
    repo = tmp_path / "checkout"
    repo.mkdir()
    (repo / "tracked.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(repo, "initial")
    before = harness._checkout_fingerprint(repo, dict(os.environ))
    after = harness._checkout_fingerprint(repo, dict(os.environ))
    assert harness._dir_snapshot_changed_paths(before, after) == []


def test_checkout_fingerprint_catches_an_ignored_file_and_a_written_git_hook(
    tmp_path,
):
    """An ignored path - `evals/out/`, `.compass/work/` and
    `docs/compass/*/` in the real checkout are exactly the paths a
    session's own `conftest.py` could rewrite - is hashed the same as any
    other untracked file, and `git ls-files` never lists anything under
    `.git/` at all, so a written `.git/hooks/pre-commit` is hashed
    directly. Both must show as a change."""
    repo = tmp_path / "checkout"
    repo.mkdir()
    (repo / "tracked.txt").write_text("original\n", encoding="utf-8")
    (repo / ".gitignore").write_text("ignored.txt\n", encoding="utf-8")
    _git_commit_all(repo, "initial")
    before = harness._checkout_fingerprint(repo, dict(os.environ))

    (repo / "ignored.txt").write_text("planted\n", encoding="utf-8")
    (repo / ".git" / "hooks" / "pre-commit").write_text(
        "#!/bin/sh\necho hi\n", encoding="utf-8")

    after = harness._checkout_fingerprint(repo, dict(os.environ))
    changed = harness._dir_snapshot_changed_paths(before, after)
    assert "ignored.txt" in changed
    assert ".git/hooks/pre-commit" in changed


def test_containment_flags_a_change_to_an_ignored_path_in_the_checkout(
    tmp_path, scenario_dir, fake_claude, monkeypatch
):
    plugin_source = tmp_path / "plugin-source-ignored"
    plugin_source.mkdir()
    (plugin_source / "tracked.txt").write_text("original\n", encoding="utf-8")
    (plugin_source / ".gitignore").write_text("escaped-ignored.txt\n", encoding="utf-8")
    _git_commit_all(plugin_source, "plugin source with a gitignore")

    escape_target = plugin_source / "escaped-ignored.txt"
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source, out_suffix="-ignored-escape",
        extra_config={"escape_path": str(escape_target)},
    )
    assert record["contained"] is False
    assert "checkout:escaped-ignored.txt" in record["escaped_paths"]


def test_containment_flags_a_written_git_hook_in_the_checkout(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    escape_target = plugin_source_dir / ".git" / "hooks" / "pre-commit"
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-git-hook-escape",
        extra_config={"escape_path": str(escape_target)},
    )
    assert record["contained"] is False
    assert "checkout:.git/hooks/pre-commit" in record["escaped_paths"]


def test_checkout_fingerprint_catches_head_moved_between_two_fingerprints(tmp_path):
    """A session's own code could point a branch at a commit it wrote and
    move `HEAD` to it - `git ls-files` shows no change either way, since
    the working tree is untouched. Hashing `.git/HEAD` catches the move."""
    repo = tmp_path / "checkout"
    repo.mkdir()
    (repo / "tracked.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(repo, "initial")
    env = dict(os.environ)
    before = harness._checkout_fingerprint(repo, env)

    subprocess.run(["git", "checkout", "-q", "-b", "other-branch"],
                    cwd=str(repo), check=True, capture_output=True, text=True)

    after = harness._checkout_fingerprint(repo, env)
    changed = harness._dir_snapshot_changed_paths(before, after)
    assert any(path.endswith("HEAD") for path in changed)


def test_checkout_fingerprint_sees_a_hook_written_in_a_linked_worktrees_main_repo(
    tmp_path,
):
    """A linked worktree's own `.git` is a file, not a directory - its
    hooks and config live in the main repository's `.git`, resolved with
    `git rev-parse --git-common-dir`. A hook written there must still show
    as a change, even though nothing under the worktree itself moved."""
    main_repo = tmp_path / "main"
    main_repo.mkdir()
    (main_repo / "tracked.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(main_repo, "initial")
    subprocess.run(
        ["git", "worktree", "add", "-q", str(tmp_path / "wt"), "-b", "wt-branch"],
        cwd=str(main_repo), check=True, capture_output=True, text=True,
    )
    worktree = tmp_path / "wt"
    env = dict(os.environ)
    before = harness._checkout_fingerprint(worktree, env)

    (main_repo / ".git" / "hooks" / "pre-commit").write_text(
        "#!/bin/sh\necho hi\n", encoding="utf-8")

    after = harness._checkout_fingerprint(worktree, env)
    changed = harness._dir_snapshot_changed_paths(before, after)
    assert any(path.endswith("pre-commit") for path in changed)


def test_checkout_fingerprint_records_a_change_when_git_is_a_file_with_no_target(
    tmp_path,
):
    """A session that replaces `.git` with a plain file must never crash
    the fingerprint - `git rev-parse` fails there, and the snapshot then
    carries a marker a resolvable checkout's own never does, so the
    comparison still shows a change instead of raising."""
    repo = tmp_path / "checkout"
    repo.mkdir()
    (repo / "tracked.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(repo, "initial")
    env = dict(os.environ)
    before = harness._checkout_fingerprint(repo, env)

    shutil.rmtree(repo / ".git")
    (repo / ".git").write_text("gitdir: /nonexistent-path\n", encoding="utf-8")

    after = harness._checkout_fingerprint(repo, env)  # must not raise
    assert harness._dir_snapshot_changed_paths(before, after) != []


# --- 6. the record -----------------------------------------------------------

def test_run_record_has_every_documented_field(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    calls, record, out_path = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir,
    )

    assert set(record.keys()) == {
        "scenario", "condition", "run", "started", "seconds", "exit_code",
        "cost_usd", "session_id", "cwd", "model", "claude_version",
        "stop_reason", "finished", "tool_calls", "texts",
        "permission_denials", "final_text", "diff", "changed_paths",
        "compass_files", "changed", "manifests", "tests_after", "contained",
        "escaped_paths", "stderr_tail", "over_budget", "replies_sent",
        "interruptions",
        "framework", "hidden", "regressions", "tokens", "compass_commit",
    }
    # This scenario carries no hidden_tests/, and this condition is not
    # superpowers or spec-kit - CMP-1 and CMP-2's own fields both read as
    # "not applicable here", never a false empty result.
    assert record["framework"] is None
    assert record["hidden"] is None
    assert record["regressions"] is None
    assert record["scenario"] == "pressure-fixture"
    assert record["condition"] == "compass"
    assert record["run"] == 1
    assert record["exit_code"] == 0
    assert record["cwd"] == calls[0]["cwd"]
    assert record["model"] == "fake-model-1"
    assert record["claude_version"] == "fake-claude 9.9.9"
    assert record["stop_reason"] == "success"
    assert record["finished"] is True
    assert record["permission_denials"] == []

    # Two tool calls per invocation, two invocations (the prompt and the
    # one follow-up), each recorded in call order.
    assert [c["index"] for c in record["tool_calls"]] == [0, 1, 2, 3]
    for call in record["tool_calls"]:
        assert set(call.keys()) == {
            "index", "name", "input", "is_error", "denied", "output",
            "tool_use_id",
        }
        assert call["denied"] is False
    assert record["tool_calls"][0]["name"] == "Read"
    assert record["tool_calls"][1]["name"] == "Edit"
    assert record["cost_usd"] == pytest.approx(0.04)
    # Two invocations (the prompt and the one follow-up), each with the
    # fake CLI's own default usage (100 + 50 + 10 + 5 = 165 tokens) -
    # summed across both.
    assert record["tokens"] == 330
    assert record["final_text"] == "fixed it"

    assert record["texts"] == [
        {"before_tool_call": 0, "text": "about to look at seed.txt"},
        {"before_tool_call": 2, "text": "fixed it"},
        {"before_tool_call": 2, "text": "about to look at seed.txt"},
        {"before_tool_call": 4, "text": "fixed it"},
    ]

    assert "seed.txt" in record["diff"]
    assert record["changed_paths"] == ["seed.txt"]
    assert record["changed"] == [{"path": "seed.txt", "status": "M"}]

    assert record["compass_files"] == [
        ".compass/marker-from-init.txt",
        ".compass/work/fixture-issue/manifest.yml",
    ]
    assert record["manifests"] == {
        ".compass/work/fixture-issue/manifest.yml":
            "issue: fixture-issue\nstatus: active\n",
    }

    assert record["tests_after"] == {
        "command": "python3 run_tests.py", "exit_code": 0,
    }

    assert record["contained"] is True
    assert record["escaped_paths"] == []
    assert isinstance(record["stderr_tail"], str)
    assert record["over_budget"] is False
    assert record["replies_sent"] == 0

    assert out_path.name == "pressure-fixture-compass-1.json"


def test_tokens_are_summed_across_every_call_from_each_results_own_usage(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """`tokens` sums every `result` event's own `usage` - input, output,
    cache creation and cache read - across every `claude` call the run
    makes, the way `cost_usd` already sums `total_cost_usd`. One call
    here, with usage this test names itself, so the expected total is not
    the fake CLI's own default."""
    scenario_dir = _write_scenario(tmp_path, follow_ups=[])
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-tokens",
        extra_config={"usage": {
            "input_tokens": 1000, "output_tokens": 200,
            "cache_creation_input_tokens": 30, "cache_read_input_tokens": 4,
        }},
    )
    assert record["tokens"] == 1234


def test_changed_reports_an_added_and_a_deleted_path(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """`changed` is judge.py's own end-state input: a status per path, not
    only a diff of the text, so a rule can tell whether a path was added,
    changed or deleted since the seed."""
    scenario_dir = _write_scenario(tmp_path, follow_ups=[])
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-changed-add-delete",
        extra_config={"no_edit": True, "add_path": "new_file.txt",
                      "delete_path": "run_tests.py"},
    )
    by_path = {entry["path"]: entry["status"] for entry in record["changed"]}
    assert by_path["new_file.txt"] == "A"
    assert by_path["run_tests.py"] == "D"


def test_manifests_holds_more_than_one_issue_directory(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """`manifests` is the content of every `.compass/work/*/manifest.yml` at
    the end, not only the one the seed started with - a second issue
    directory, however created, still shows up."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-manifests-two",
        extra_config={"second_manifest_slug": "second-issue"},
    )
    assert set(record["manifests"]) == {
        ".compass/work/fixture-issue/manifest.yml",
        ".compass/work/second-issue/manifest.yml",
    }
    assert "second-issue" in record["manifests"][".compass/work/second-issue/manifest.yml"]


def test_denied_flag_from_permission_denials_and_from_a_refusal_message(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-denied",
        extra_config={"deny_tool": "Edit"},
    )
    by_name = {call["name"]: call for call in record["tool_calls"]}
    assert by_name["Edit"]["denied"] is True
    assert by_name["Edit"]["is_error"] is True
    assert by_name["Read"]["denied"] is False
    assert record["permission_denials"]


def test_tool_calls_carry_the_tool_use_id_the_fake_claude_gave_them(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """The judge matches a permission denial to its tool call by
    `tool_use_id`, never by position - so the id `_consume_events` reads off
    each `tool_result` event must reach the record, not be dropped once
    `_finalise_tool_calls` has used it to set `denied`."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-tool-use-id",
        extra_config={"deny_tool": "Edit"},
    )
    by_name = {call["name"]: call for call in record["tool_calls"]}
    assert by_name["Read"]["tool_use_id"] == "toolu_1"
    assert by_name["Edit"]["tool_use_id"] == "toolu_2"

    denied_call = by_name["Edit"]
    assert denied_call["denied"] is True
    denial_ids = {
        (entry.get("tool_use_id") if isinstance(entry, dict) else entry)
        for entry in record["permission_denials"]
    }
    assert denied_call["tool_use_id"] in denial_ids


def test_each_run_starts_from_a_fresh_repository_with_only_the_seed(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    compass_calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-fresh",
    )
    listing = set(compass_calls[0]["listing"])
    assert listing == {
        "seed.txt",
        "run_tests.py",
        os.path.join(".compass", "work", "fixture-issue", "manifest.yml"),
        os.path.join(".compass", "marker-from-init.txt"),
    }

    bare_calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-fresh",
    )
    listing = set(bare_calls[0]["listing"])
    assert listing == {"seed.txt", "run_tests.py", "PLAN.md"}


# --- 7. the seed copy leaves out __pycache__ and *.pyc ----------------------

def test_seed_copy_leaves_out_pycache_and_pyc_files(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    scenario_dir = _write_scenario(tmp_path)
    pycache_dir = scenario_dir / "seed" / "__pycache__"
    pycache_dir.mkdir()
    (pycache_dir / "run_tests.cpython-311.pyc").write_bytes(b"\x00\x01")
    (scenario_dir / "seed" / "stray.pyc").write_bytes(b"\x00\x01")

    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-pycache",
    )
    listing = calls[0]["listing"]
    assert not any("__pycache__" in path for path in listing)
    assert not any(path.endswith(".pyc") for path in listing)


def test_seed_copy_uses_only_git_tracked_files(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """A seed copied straight from the working tree carries a local file such
    as `.pytest_cache/` along with it, and that directory can name a failing
    test the seed never committed. Only the seed's own git-tracked files
    travel into a run."""
    scenario_dir = _write_scenario(tmp_path)
    stray_dir = scenario_dir / "seed" / ".pytest_cache" / "v" / "cache"
    stray_dir.mkdir(parents=True)
    (stray_dir / "lastfailed").write_text("{}\n", encoding="utf-8")

    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-tracked-only",
    )
    listing = calls[0]["listing"]
    assert not any(".pytest_cache" in path for path in listing)
    assert set(listing) == {"seed.txt", "run_tests.py", "PLAN.md"}


def test_seed_commit_message_and_no_tag(tmp_path):
    """Six rounds of real sessions never ran `git tag`, so nothing needs one:
    the harness keeps the seed commit's own id and marks it no other way.
    `git log --decorate` must show no `tag: seed`."""
    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    seed_commit = harness._git_init_and_commit(repo, dict(os.environ))

    message = subprocess.run(
        ["git", "log", "-1", "--format=%s"], cwd=str(repo),
        capture_output=True, text=True,
    ).stdout.strip()
    assert message == "Initial commit"

    tags = subprocess.run(
        ["git", "tag"], cwd=str(repo), capture_output=True, text=True,
    ).stdout.strip()
    assert tags == ""

    decorated = subprocess.run(
        ["git", "log", "--decorate", "-1"], cwd=str(repo),
        capture_output=True, text=True,
    ).stdout
    assert "tag: seed" not in decorated

    diff = subprocess.run(
        ["git", "diff", seed_commit], cwd=str(repo), capture_output=True, text=True,
    )
    assert diff.returncode == 0


# --- 8. plain text ------------------------------------------------------------

def test_module_docstring_does_not_explain_by_how_the_issue_split_its_work():
    text = (harness.__doc__ or "").lower()
    assert "sibling" not in text
    assert "this issue" not in text


def test_no_bare_defect_id_cited_without_its_meaning():
    """Say what a rule is in the comment, not a bare id nobody outside
    this issue can look up."""
    source = Path(harness.__file__).read_text(encoding="utf-8")
    assert "DD-2" not in source
    assert "compass_pkg.core.load_yaml" in source


def test_no_citation_of_a_document_this_repository_does_not_have():
    """Neither `evals/harness.py` nor this file may point a reader at a
    document this repository does not track - see `citation_patterns.py`
    for the rule and why."""
    for path in (Path(harness.__file__), Path(__file__)):
        hit = scan_file_for_unopenable_citation(path)
        assert hit is None, f"{path} matches {hit!r}"


def test_the_citation_guard_catches_a_planted_citation():
    """A regression guard that only ever passes proves nothing - check the
    matcher against every planted form `citation_patterns.py` carries."""
    for planted in PLANTED_CITATION_FORMS:
        assert cited_unopenable_document(planted) is not None, (
            f"the guard missed a planted citation: {planted!r}"
        )


def test_the_allow_marker_cannot_launder_a_citation_as_its_own_reason():
    """`ALLOW_MARKER` exempts a line for the rare case a banned word is
    needed for an ordinary purpose unrelated to citing either document. A
    reason that itself names an unopenable document is not that: it is the
    citation, carried past the guard by the marker meant to explain it
    away. The line must still be reported."""
    from citation_patterns import ALLOW_MARKER

    smuggled = "# " + ALLOW_MARKER + " see verify-security-3.md for the attack"
    assert cited_unopenable_document(smuggled) is not None, (
        "a citation in the allow marker's own reason passed unreported"
    )


@pytest.mark.parametrize("planted", PLANTED_CITATION_FORMS)
def test_the_file_scan_catches_a_planted_citation(tmp_path, planted):
    """Not only the matcher: a planted file, read by the same
    `scan_file_for_unopenable_citation` the guard above calls - so a guard
    that read the wrong file, or none at all, could not pass by accident."""
    planted_file = tmp_path / "planted.py"
    planted_file.write_text(f"# {planted}\n", encoding="utf-8")
    assert scan_file_for_unopenable_citation(planted_file) is not None


# Every function in `evals/harness.py` that is allowed to start a new
# process at all - `_run_git` for git, and the four others that between
# them start `compass init`, `claude --version`, `claude` itself and the
# scenario's own test command. `test_every_new_process_starts_through_a_
# named_function` below checks each one actually starts a process, not
# that it starts the specific program its own name suggests.
_ALLOWED_TO_START_A_PROCESS = (
    "_run_git", "_run_compass_init", "_run_specify_init", "_claude_version",
    "_invoke_claude", "_run_test_command",
)


def _process_starts_by_function(source: str) -> dict[str, list[str]]:
    """Map each function name, anywhere in `source`, to the process-starting
    calls it makes directly - `subprocess.run`/`Popen`/`call`/`check_call`/
    `check_output`, `os.system`, `os.popen`, or an `os.exec*` variant -
    however the module or the one name was imported: `import subprocess`,
    `import subprocess as sp`, `from subprocess import run`, `from
    subprocess import run as _r`, and the same shapes for `os`. Earlier,
    this only recognised `subprocess.run(["git", ...])` written as a
    literal list - missed a call built from a variable, a list
    concatenation, an imported name, or `os.system` outright. A reference
    to `subprocess.CompletedProcess` as a type, or `subprocess.DEVNULL` as
    a constant, is not a call, so neither is ever counted."""
    tree = ast.parse(source)

    subprocess_modules: set[str] = set()
    subprocess_members: set[str] = set()
    os_modules: set[str] = set()
    os_restricted_members: set[str] = set()

    for node in ast.walk(tree):
        if isinstance(node, ast.Import):
            for alias in node.names:
                bound = alias.asname or alias.name
                if alias.name == "subprocess":
                    subprocess_modules.add(bound)
                elif alias.name == "os":
                    os_modules.add(bound)
        elif isinstance(node, ast.ImportFrom):
            if node.module == "subprocess":
                for alias in node.names:
                    subprocess_members.add(alias.asname or alias.name)
            elif node.module == "os":
                for alias in node.names:
                    if alias.name == "system" or alias.name == "popen" or alias.name.startswith("exec"):
                        os_restricted_members.add(alias.asname or alias.name)

    calls: dict[str, list[str]] = {}

    class Visitor(ast.NodeVisitor):
        def __init__(self) -> None:
            self.current = "<module>"

        def _enter(self, node: ast.FunctionDef | ast.AsyncFunctionDef) -> None:
            previous, self.current = self.current, node.name
            self.generic_visit(node)
            self.current = previous

        def visit_FunctionDef(self, node: ast.FunctionDef) -> None:
            self._enter(node)

        def visit_AsyncFunctionDef(self, node: ast.AsyncFunctionDef) -> None:
            self._enter(node)

        def visit_Call(self, node: ast.Call) -> None:
            func = node.func
            hit: str | None = None
            if isinstance(func, ast.Attribute) and isinstance(func.value, ast.Name):
                if func.value.id in subprocess_modules:
                    hit = f"subprocess.{func.attr}"
                elif func.attr == "launch_claude":
                    # The shared launcher `compass run` also uses
                    # (cli/compass_pkg/host_launch.py, ADR-030) starts
                    # `claude`, so calling it starts a process here too.
                    hit = f"{func.value.id}.launch_claude"
                elif (func.value.id in os_modules
                      and (func.attr == "system" or func.attr == "popen"
                           or func.attr.startswith("exec"))):
                    hit = f"os.{func.attr}"
            elif isinstance(func, ast.Name):
                if func.id in subprocess_members:
                    hit = f"subprocess member {func.id!r}"
                elif func.id in os_restricted_members:
                    hit = f"os member {func.id!r}"
            if hit is not None:
                calls.setdefault(self.current, []).append(hit)
            self.generic_visit(node)

    Visitor().visit(tree)
    return calls


def test_every_new_process_starts_through_a_named_function():
    """`evals/harness.py` starts git in this checkout, in a scenario's own
    seed directory, and in a session's own temporary repository, and starts
    the test command and `claude` in that same temporary repository. Every
    one of those must go through one of `_ALLOWED_TO_START_A_PROCESS`; a
    process started anywhere else, in any of the call shapes
    `_process_starts_by_function` recognises, is the class of defect this
    test exists to catch. It cannot see a call shape it does not recognise
    - `os.spawnv`, `os.posix_spawn`, `getattr(subprocess, "run")(...)`,
    `asyncio.create_subprocess_exec`, `pty.spawn` - or a git call added
    inside a function `_ALLOWED_TO_START_A_PROCESS` already names."""
    source = Path(harness.__file__).read_text(encoding="utf-8")
    calls = _process_starts_by_function(source)
    offenders = sorted(name for name in calls if name not in _ALLOWED_TO_START_A_PROCESS)
    assert offenders == [], f"a process starts outside the allowed functions: {offenders}"
    # Each named function must still be the one that actually starts a
    # process, not just a name on the allow-list - so a refactor that
    # renames the call away, leaving the function empty, is caught here
    # rather than assumed.
    for name in _ALLOWED_TO_START_A_PROCESS:
        assert name in calls, f"{name} is allowed to start a process but does not"


# One planted bypass per call shape `_process_starts_by_function` looks
# for beyond a literal `subprocess.run(["git", ...])` list: a variable, a
# list built by concatenation, an imported name, and `os.system` called
# directly.
_PLANTED_PROCESS_START_BYPASSES = {
    "literal list": 'import subprocess\ndef _new_helper():\n    return subprocess.run(["git", "status"])\n',
    "list in a variable": 'import subprocess\ndef _new_helper(args):\n    cmd = ["git", *args]\n    return subprocess.run(cmd)\n',
    "list concatenation": 'import subprocess\ndef _new_helper(args):\n    return subprocess.run(["git"] + args)\n',
    "imported run": 'from subprocess import run\ndef _new_helper():\n    return run(["git", "status"])\n',
    "os.system": 'import os\ndef _new_helper():\n    return os.system("git status")\n',
}


@pytest.mark.parametrize("bypass", sorted(_PLANTED_PROCESS_START_BYPASSES))
def test_the_process_start_guard_catches_each_planted_bypass(bypass):
    """Each of the five call shapes `_PLANTED_PROCESS_START_BYPASSES` lists,
    planted as a new function appended to `evals/harness.py`'s own source -
    not one of them may pass unnoticed. This is not every shape a bypass
    could take; see `test_every_new_process_starts_through_a_named_function`
    for what the guard cannot see."""
    source = (Path(harness.__file__).read_text(encoding="utf-8") + "\n"
              + _PLANTED_PROCESS_START_BYPASSES[bypass])
    calls = _process_starts_by_function(source)
    offenders = sorted(name for name in calls if name not in _ALLOWED_TO_START_A_PROCESS)
    assert "_new_helper" in offenders, f"the guard missed: {bypass}"


# --- 9. a session's own .pyc files never reach changed_paths ----------------

def test_session_pyc_files_are_excluded_from_changed_paths(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """A session that runs its tests leaves `__pycache__/*.pyc` files that
    `git add -A` would otherwise stage, which stopped the judge placing the
    first code edit. The harness writes `.git/info/exclude` before the seed
    commit so they never appear."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-pyc",
        extra_config={"create_pyc": True},
    )
    assert not any(path.endswith(".pyc") for path in record["changed_paths"])
    assert not any("__pycache__" in path for path in record["changed_paths"])
    assert "src/__pycache__/inventory.cpython-311.pyc" not in record["diff"]


# --- 10. no MCP server reaches the session -----------------------------------

def test_no_mcp_server_reaches_the_session(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """A real session listed the maintainer's own Slack and Drive connectors
    among its tools. Both conditions must load none."""
    for condition in ("compass", "bare"):
        calls, _, _ = _run_condition(
            tmp_path, scenario_dir, fake_claude, condition, monkeypatch,
            plugin_source_dir, out_suffix=f"-mcp-{condition}",
        )
        assert "--strict-mcp-config" in calls[0]["args"]


# --- 11. no temporary directory name says which condition it is -------------

def test_temporary_directory_names_do_not_name_the_scenario_or_condition(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """Every temporary directory, the repository and the plugin copy alike,
    takes the system's default temporary name: no prefix names the scenario
    or the condition, so a real session cannot tell from its own working
    directory that it is under evaluation."""
    scenario_id = "pressure-fixture"

    compass_calls, compass_record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-naming",
    )
    bare_calls, bare_record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-naming",
    )
    assert compass_record["scenario"] == scenario_id

    compass_repo_name = Path(compass_record["cwd"]).name
    bare_repo_name = Path(bare_record["cwd"]).name
    for name in (compass_repo_name, bare_repo_name):
        assert scenario_id not in name
        assert "compass" not in name
        assert "bare" not in name
        assert "eval" not in name

    plugin_dir_arg = compass_calls[0]["args"][
        compass_calls[0]["args"].index("--plugin-dir") + 1
    ]
    plugin_copy_name = Path(plugin_dir_arg).name
    assert scenario_id not in plugin_copy_name
    assert "eval" not in plugin_copy_name


# --- 12. the seed commit's author is an ordinary name, not the harness's own -

def test_seed_commit_author_is_an_ordinary_name(tmp_path):
    """The seed commit's author is an ordinary name and address - a real
    compass session could run the allowed `git log` and read a name naming
    this evaluation off the seed commit."""
    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    harness._git_init_and_commit(repo, dict(os.environ))

    identity = subprocess.run(
        ["git", "log", "-1", "--format=%an <%ae> %cn <%ce>"],
        cwd=str(repo), capture_output=True, text=True,
    ).stdout.strip()
    assert "eval" not in identity.lower()
    assert "compass" not in identity.lower()


# --- 13. nothing a session can see says it is under test --------------------

def test_no_visible_name_says_it_is_under_test_or_names_the_scenario(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """Checks every temporary path and the seed commit's author together, so
    a name reintroduced in either place is caught."""
    scenario_id = "pressure-fixture"
    forbidden = ("eval", "compass", scenario_id)

    compass_calls, compass_record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-tell",
    )
    bare_calls, bare_record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-tell",
    )

    plugin_dir_arg = compass_calls[0]["args"][
        compass_calls[0]["args"].index("--plugin-dir") + 1
    ]
    texts = [
        Path(compass_record["cwd"]).name,
        Path(bare_record["cwd"]).name,
        Path(plugin_dir_arg).name,
        compass_calls[0]["git_log_identity"],
        bare_calls[0]["git_log_identity"],
    ]
    for text in texts:
        lowered = text.lower()
        for word in forbidden:
            assert word not in lowered, f"{word!r} found in {text!r}"


# --- 14. a scenario with continue_reply gets it once, before a code edit ---

def test_continue_reply_sent_once_when_no_code_edit_has_happened_yet(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """A session run under `-p` gets no answer to a question of its own, so
    it never reaches a decision on its own. Guessing the question from a
    trailing `?` missed most of them, so the trigger is now whether the
    work has happened, not the wording of the last message: while no
    non-test path in `in_scope` has changed against the seed yet, the
    harness sends the scenario's own `continue_reply`, with `--resume` and
    the run's remaining budget, before the next follow-up."""
    scenario_dir = _write_scenario(
        tmp_path, follow_ups=["first follow-up"],
        continue_reply="Go ahead with whichever option you recommend.",
    )
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-continue",
        extra_config={"no_edit": True},
    )
    assert len(calls) == 3

    reply_args = calls[1]["args"]
    assert reply_args[reply_args.index("-p") + 1] == \
        "Go ahead with whichever option you recommend."
    assert "--resume" in reply_args
    assert reply_args[reply_args.index("--resume") + 1] == "fake-session-0001"
    # the default fixture scenario has a $3.00 budget and the fake CLI
    # reports a $0.02 cost per call, so $2.98 is left after the initial call.
    assert float(
        reply_args[reply_args.index("--max-budget-usd") + 1]
    ) == pytest.approx(2.98)

    follow_up_args = calls[2]["args"]
    assert follow_up_args[follow_up_args.index("-p") + 1] == "first follow-up"

    assert record["replies_sent"] == 1


def test_no_continue_reply_once_a_code_edit_has_happened(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """The fixture's fake CLI edits seed.txt - a path inside `in_scope` - on
    every call by default, so the first call has already done the work the
    reply exists to unblock, and none is sent."""
    scenario_dir = _write_scenario(
        tmp_path, follow_ups=["first follow-up"],
        continue_reply="Go ahead with whichever option you recommend.",
    )
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-continue-edited",
    )
    assert len(calls) == 2
    assert record["replies_sent"] == 0


def test_no_continue_reply_for_a_scenario_without_the_field(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """A scenario with no `continue_reply` never gets one, even when no
    code edit has happened yet - the reply's wording is the maintainer's
    own call, opted into per scenario, never a default the harness
    invents."""
    scenario_dir = _write_scenario(tmp_path, follow_ups=["first follow-up"])
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-no-field",
        extra_config={"no_edit": True},
    )
    assert len(calls) == 2
    assert record["replies_sent"] == 0


def test_continue_reply_sent_at_most_once_per_run(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """No call ever makes a code edit under this test's fixture, so the cap
    - not the trigger - is what is under test: still one reply for the
    whole run."""
    scenario_dir = _write_scenario(
        tmp_path, follow_ups=["first follow-up", "second follow-up"],
        continue_reply="Go ahead with whichever option you recommend.",
    )
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-continue-cap",
        extra_config={"no_edit": True},
    )
    # initial call, one continuation reply, then both scheduled follow-ups -
    # no second reply even though no call ever makes a code edit.
    assert len(calls) == 4
    assert record["replies_sent"] == 1


def test_continue_reply_applies_under_either_condition(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    scenario_dir = _write_scenario(
        tmp_path, follow_ups=[],
        continue_reply="Go ahead with whichever option you recommend.",
    )
    for condition in ("compass", "bare"):
        calls, record, _ = _run_condition(
            tmp_path, scenario_dir, fake_claude, condition, monkeypatch,
            plugin_source_dir, out_suffix=f"-continue-{condition}",
            extra_config={"no_edit": True},
        )
        assert len(calls) == 2
        assert record["replies_sent"] == 1


def test_continue_reply_still_sent_when_only_compass_own_record_changed(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """`compass ship-commit` derives `docs/system-spec.md` when an issue
    lands, and this scenario's own `in_scope` is `["**"]` - wide enough to
    catch that path too. A call that wrote only
    that file, and not seed.txt, has still done none of the scenario's own
    work, so the continuation reply must still be sent."""
    scenario_dir = _write_scenario(
        tmp_path, follow_ups=["first follow-up"],
        continue_reply="Go ahead with whichever option you recommend.",
    )
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "compass", monkeypatch,
        plugin_source_dir, out_suffix="-continue-system-spec",
        extra_config={"no_edit": True, "add_path": "docs/system-spec.md"},
    )
    assert len(calls) == 3
    assert record["replies_sent"] == 1


# --- 15. a seed with no tracked file is an error, never an empty repository -

def test_copy_tracked_files_errors_when_source_is_not_a_git_repository(tmp_path):
    """A scenario directory outside a git repository gave an empty seed and
    no error: `git ls-files` fails there, and the exit status was ignored."""
    source = tmp_path / "not-a-repo"
    source.mkdir()
    (source / "seed.txt").write_text("original\n", encoding="utf-8")
    dest = tmp_path / "dest"
    dest.mkdir()

    with pytest.raises(SystemExit):
        harness._copy_tracked_files(source, dest, dict(os.environ))


def test_copy_tracked_files_errors_when_nothing_is_tracked(tmp_path):
    """A git repository with nothing committed lists no file either - the
    same silent, empty seed, from the same untested exit status."""
    source = tmp_path / "empty-repo"
    source.mkdir()
    subprocess.run(["git", "init", "-q"], cwd=str(source), check=True)
    dest = tmp_path / "dest"
    dest.mkdir()

    with pytest.raises(SystemExit):
        harness._copy_tracked_files(source, dest, dict(os.environ))


def test_copy_tracked_files_still_copies_an_ordinary_tracked_seed(tmp_path):
    """The fix must not touch the ordinary case: a real seed with tracked
    files still copies exactly those files."""
    source = tmp_path / "seed-repo"
    source.mkdir()
    (source / "seed.txt").write_text("original\n", encoding="utf-8")
    _git_commit_all(source, "seed")
    dest = tmp_path / "dest"
    dest.mkdir()

    harness._copy_tracked_files(source, dest, dict(os.environ))

    assert (dest / "seed.txt").read_text(encoding="utf-8") == "original\n"


# --- 16. every diff is computed with a temporary index, never the session's -
# --- own one -----------------------------------------------------------------

def test_diff_since_seed_never_stages_into_the_repository_own_index(tmp_path):
    """A session's own later `git status` call is allowed, and reads the
    repository's real index - if `git add -A` staged into that index, the
    session would see a write it never made. A temporary index
    (`GIT_INDEX_FILE`) leaves the real one exactly as the session left
    it."""
    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    env = dict(os.environ)
    seed_commit = harness._git_init_and_commit(repo, env)
    seed_git_snapshot = harness._snapshot_git_config(repo)
    (repo / "seed.txt").write_text("changed\n", encoding="utf-8")

    real_index = repo / ".git" / "index"
    before = real_index.read_bytes() if real_index.is_file() else None

    tampered_paths: list[str] = []
    diff, changed_paths, changed = harness._diff_since_seed(
        repo, seed_commit, env, seed_git_snapshot, tampered_paths)
    assert tampered_paths == []

    after = real_index.read_bytes() if real_index.is_file() else None
    assert before == after

    status = subprocess.run(
        ["git", "status", "--porcelain"], cwd=str(repo),
        capture_output=True, text=True,
    ).stdout
    assert status == " M seed.txt\n"
    assert "seed.txt" in diff
    assert changed_paths == ["seed.txt"]
    assert changed == [{"path": "seed.txt", "status": "M"}]


def test_diff_since_seed_restores_a_tampered_git_config_and_reports_it(tmp_path):
    """A session's own code can rewrite `.git/config` between the seed
    commit and the harness's next diff - `diff.external`, `core.fsmonitor`
    or a `filter.*.clean` driver, each naming a script the harness would
    otherwise run. `_diff_since_seed` must put the seed's own copy back
    before it runs a git command, and name the file in `tampered_paths` so
    the run is recorded as not contained."""
    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    env = dict(os.environ)
    seed_commit = harness._git_init_and_commit(repo, env)
    seed_git_snapshot = harness._snapshot_git_config(repo)
    original_config = (repo / ".git" / "config").read_bytes()

    with (repo / ".git" / "config").open("a", encoding="utf-8") as fh:
        fh.write("[diff]\n\texternal = /bin/true\n")

    tampered_paths: list[str] = []
    harness._diff_since_seed(repo, seed_commit, env, seed_git_snapshot, tampered_paths)

    assert tampered_paths == [".git/config"]
    assert (repo / ".git" / "config").read_bytes() == original_config


def test_diff_since_seed_removes_a_planted_git_commondir_and_reports_it(tmp_path):
    """A `.git/commondir` the seed never had moves every later git call in
    the session's own repository to a config outside it -
    `_diff_since_seed` must remove it, the same way a tampered
    `.git/config` is put back, and name it in `tampered_paths`."""
    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    env = dict(os.environ)
    seed_commit = harness._git_init_and_commit(repo, env)
    seed_git_snapshot = harness._snapshot_git_config(repo)

    other_git_dir = tmp_path / "other-git-dir"
    other_git_dir.mkdir()
    (repo / ".git" / "commondir").write_text(str(other_git_dir) + "\n", encoding="utf-8")

    tampered_paths: list[str] = []
    harness._diff_since_seed(repo, seed_commit, env, seed_git_snapshot, tampered_paths)

    assert tampered_paths == [".git/commondir"]
    assert not (repo / ".git" / "commondir").exists()


# --- EGA-1: a failed guarded git call is recorded as not contained ---------
# No pilot record ever left `.git/HEAD` pointing at a ref that does not
# exist, or deleted `.git/objects` - the smallest fixture for each, built
# directly against `_diff_since_seed` the way the tampered-config tests
# above already are. `_git_head_is_valid` accepts `.git/HEAD` here because
# it only checks the line starts with `ref:`, so `_run_guarded_git` lets
# the real git call through in both cases; only its exit code shows the
# repository is unusable.

def test_diff_since_seed_records_a_head_pointing_nowhere_as_not_contained(tmp_path):
    """`.git/HEAD` reads `ref: garbage` - a line that starts with `ref:`, so
    `_git_head_is_valid` calls it fine, but git itself refuses every call
    against it. `_diff_since_seed` reads each call's own exit code, not
    only its `.stdout`, so a refused `git add -A` and `git diff` still
    record the run as not contained, even though `changed_paths` is
    empty."""
    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    env = dict(os.environ)
    seed_commit = harness._git_init_and_commit(repo, env)
    seed_git_snapshot = harness._snapshot_git_config(repo)
    (repo / ".git" / "HEAD").write_text("ref: garbage\n", encoding="utf-8")

    tampered_paths: list[str] = []
    diff, changed_paths, changed = harness._diff_since_seed(
        repo, seed_commit, env, seed_git_snapshot, tampered_paths)

    assert tampered_paths
    assert changed_paths == []
    assert changed == []
    assert diff == ""


def test_diff_since_seed_records_deleted_git_objects_as_not_contained(tmp_path):
    """`.git/HEAD` is untouched and valid; `.git/objects` is gone. Every
    guarded git call in `_diff_since_seed` fails for that reason alone, and
    the run must be recorded as not contained the same way a broken
    `.git/HEAD` already is."""
    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    env = dict(os.environ)
    seed_commit = harness._git_init_and_commit(repo, env)
    seed_git_snapshot = harness._snapshot_git_config(repo)
    shutil.rmtree(repo / ".git" / "objects")

    tampered_paths: list[str] = []
    diff, changed_paths, changed = harness._diff_since_seed(
        repo, seed_commit, env, seed_git_snapshot, tampered_paths)

    assert tampered_paths
    assert changed_paths == []
    assert changed == []
    assert diff == ""


def test_global_gitconfig_filter_never_runs_in_the_session_repository(tmp_path):
    """A filter named only in `$HOME/.gitconfig`, selected by a
    `.gitattributes` the session's own repository carries - the harness
    must never read `$HOME/.gitconfig` for a git call it makes there, so a
    driver named only there is never found."""
    fake_home = tmp_path / "fake-home"
    fake_home.mkdir()
    marker = tmp_path / "filter-marker.txt"
    script_path = tmp_path / "planted-filter.sh"
    script_path.write_text("#!/bin/sh\ncat > " + str(marker) + "\n", encoding="utf-8")
    script_path.chmod(script_path.stat().st_mode | stat.S_IEXEC)
    (fake_home / ".gitconfig").write_text(
        "[filter \"y\"]\n\tclean = " + str(script_path) + "\n", encoding="utf-8")

    repo = tmp_path / "repo"
    repo.mkdir()
    (repo / "seed.txt").write_text("original\n", encoding="utf-8")
    (repo / ".gitattributes").write_text("seed.txt filter=y\n", encoding="utf-8")
    env = dict(os.environ)
    env["HOME"] = str(fake_home)
    seed_commit = harness._git_init_and_commit(repo, env)
    seed_git_snapshot = harness._snapshot_git_config(repo)
    (repo / "seed.txt").write_text("changed\n", encoding="utf-8")

    tampered_paths: list[str] = []
    harness._diff_since_seed(repo, seed_commit, env, seed_git_snapshot, tampered_paths)

    assert not marker.exists()


# --- EGA-5: .git/HEAD is a git-state label, and the None-path is safe ------

def test_is_compass_own_record_returns_false_for_none():
    """`evals/judge.py` imports this function rather than keeping its own
    copy (EJG-5); every caller there already guards a falsy path before
    calling it, but a future one that passes `None` straight through must
    not crash - it names no record of anything, so the answer is `False`."""
    assert harness._is_compass_own_record(None) is False


# --- EGA-6: a comment states the rule, not the module's own history -------

def test_compass_own_record_paths_comment_says_the_judge_imports_it():
    """The comment above `_COMPASS_OWN_RECORD_PATHS` must say this is the
    one definition and that `evals/judge.py` imports it, not that the
    judge keeps a separate copy of the same list."""
    source = Path(harness.__file__).read_text(encoding="utf-8")
    assert "keeps its own copy" not in source
    assert "the one definition" in source
    assert "imports it" in source


def test_diff_since_seed_docstring_names_the_two_specific_paths_it_checks():
    """EGB-6: the docstring must not overstate when `.git` is added to
    `tampered_paths` as "no more specific reason is already on record" -
    the code checks only two specific entries, `.git/HEAD` and `.git`
    itself, not whether `tampered_paths` already carries any reason at
    all."""
    doc = " ".join((harness._diff_since_seed.__doc__ or "").split())
    assert "no more specific reason is already on record" not in doc
    assert "checked against those two specific entries" in doc


def test_tamper_watched_paths_label_comment_does_not_call_commondir_a_config_file():
    """EGB-6: `.git/commondir` is a pointer to another git directory, not a
    config file - the comment above the `git-config:`/`git-state:` label
    split must not call all three of `_TAMPER_WATCHED_RELATIVE_PATHS` "a
    config file each"."""
    source = Path(harness.__file__).read_text(encoding="utf-8")
    assert "is genuinely a config file each" not in source
    assert "not a config file itself" in source


# --- 17. a failed `compass init` is an error, never a silent empty run ------

def test_run_compass_init_raises_when_the_plugin_copy_fails(tmp_path):
    plugin_copy = _write_plugin_repo(tmp_path / "plugin-copy", init_exit_code=1)
    repo_dir = tmp_path / "repo"
    repo_dir.mkdir()
    with pytest.raises(SystemExit):
        harness._run_compass_init(plugin_copy, repo_dir, dict(os.environ))


def test_run_compass_init_does_not_raise_on_success(tmp_path):
    plugin_copy = _write_plugin_repo(tmp_path / "plugin-copy-ok")
    repo_dir = tmp_path / "repo"
    repo_dir.mkdir()
    harness._run_compass_init(plugin_copy, repo_dir, dict(os.environ))
    assert (repo_dir / ".compass" / "marker-from-init.txt").is_file()


# --- the compass condition's setup date is backdated -------------------------

def test_backdate_setup_date_rewrites_every_occurrence_of_the_stamped_date(
    tmp_path
):
    """The hook's own refusal quotes `initialised.at`, and a real compass
    session read today's date there as proof a policy could not be leftover
    config from another project. `compass init` stamps the same date into
    `records_signed_since` from the one template value it filled in, so
    rewriting every occurrence of the stamped date backdates both fields
    from that one value."""
    repo_dir = tmp_path / "repo"
    compass_dir = repo_dir / ".compass"
    compass_dir.mkdir(parents=True)
    (compass_dir / "config.yml").write_text(
        "version: 1.0.0\n"
        "mode: enforced\n"
        "initialised:\n"
        "  by: \"compass init\"\n"
        "  at: \"2026-09-27\"\n"
        "records_signed_since: '2026-09-27'\n",
        encoding="utf-8",
    )

    harness._backdate_setup_date(repo_dir)

    text = (compass_dir / "config.yml").read_text(encoding="utf-8")
    assert 'at: "2026-08-28"' in text
    assert "records_signed_since: '2026-08-28'" in text
    assert "2026-09-27" not in text


def test_backdate_setup_date_does_nothing_without_a_config_file(tmp_path):
    repo_dir = tmp_path / "repo"
    repo_dir.mkdir()
    harness._backdate_setup_date(repo_dir)  # must not raise
    assert not (repo_dir / ".compass").exists()


def test_materialise_repo_backdates_the_setup_date_for_the_compass_condition(
    tmp_path
):
    """Wiring: the compass condition's own `compass init` runs, then the
    date it just stamped is rewritten, before the seed commit - so the
    backdated value is what a session's first hook refusal ever sees."""
    plugin_copy = _write_plugin_repo(tmp_path / "plugin-copy-dated",
                                      write_config_yml=True)
    scenario_dir = _write_scenario(tmp_path)
    repo_dir = tmp_path / "repo"
    repo_dir.mkdir()

    harness._materialise_repo(scenario_dir, "compass", repo_dir, plugin_copy,
                               None, "uvx", dict(os.environ))

    config_text = (repo_dir / ".compass" / "config.yml").read_text(encoding="utf-8")
    today = date.today()
    backdated = (today - timedelta(days=30)).isoformat()
    assert f'at: "{backdated}"' in config_text
    assert f'at: "{today.isoformat()}"' not in config_text


# --- 18. the continuation reply follows only a call that ended `success` ----

def test_no_continue_reply_after_a_call_that_did_not_end_in_success(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """The rule: the reply follows only a call whose result subtype is
    `success`. A call that ended `error_during_execution` gets none, even
    with budget left and no code edit yet."""
    scenario_dir = _write_scenario(
        tmp_path, follow_ups=["first follow-up"],
        continue_reply="Go ahead with whichever option you recommend.",
    )
    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-no-reply-on-error",
        extra_config={"no_edit": True, "result_subtype": "error_during_execution"},
    )
    assert len(calls) == 2
    assert record["replies_sent"] == 0


# --- scenario.yml is read through the shared loader (compass_pkg.core.load_yaml) --

def test_load_scenario_raises_compass_error_for_a_missing_file(tmp_path):
    from compass_pkg.core import CompassError

    scenario_dir = tmp_path / "no-scenario-here"
    scenario_dir.mkdir()

    with pytest.raises(CompassError):
        harness.load_scenario(scenario_dir)


def test_load_scenario_raises_compass_error_for_invalid_yaml(tmp_path):
    from compass_pkg.core import CompassError

    scenario_dir = tmp_path / "broken-scenario"
    scenario_dir.mkdir()
    (scenario_dir / "scenario.yml").write_text(
        "id: [unclosed\n", encoding="utf-8"
    )

    with pytest.raises(CompassError):
        harness.load_scenario(scenario_dir)


def test_load_scenario_returns_defaults_for_an_empty_file(tmp_path):
    scenario_dir = tmp_path / "empty-scenario"
    scenario_dir.mkdir()
    (scenario_dir / "scenario.yml").write_text("", encoding="utf-8")

    data = harness.load_scenario(scenario_dir)

    assert data == {
        "follow_ups": [], "test_command": "python3 -m pytest -q",
        "hidden_command": "python3 -m pytest -q",
    }


# --- 19. the plugin copy names nothing a scenario or a behaviour would give away --

def test_plugin_copy_of_the_real_checkout_names_no_scenario_or_behaviour(
    tmp_path
):
    """Every other test in this file stands a fixture in for this checkout,
    on purpose, so nothing depends on its tracked tree. This one is the
    exception: only the real checkout carries real scenario ids and
    behaviour ids to check against, and only its own copy shows whether a
    file outside `evals/` still names one by accident."""
    scenario_ids = sorted(
        p.parent.name
        for p in (REPO_ROOT / "evals" / "scenarios").glob("*/scenario.yml")
    )
    assert scenario_ids

    from evals import judge  # local: only this test needs the behaviour ids
    behaviour_ids = sorted(judge.BEHAVIOURS.keys())
    assert behaviour_ids

    forbidden = [*scenario_ids, *behaviour_ids, "compass condition", "bare condition"]

    dest = tmp_path / "real-plugin-copy"
    harness._make_plugin_copy(REPO_ROOT, dest, dict(os.environ))
    try:
        offences = []
        for path in dest.rglob("*"):
            if not path.is_file():
                continue
            try:
                text = path.read_text(encoding="utf-8")
            except (UnicodeDecodeError, OSError):
                continue
            for term in forbidden:
                if term in text:
                    offences.append((path.relative_to(dest).as_posix(), term))
        assert offences == []
    finally:
        harness._remove_read_only_tree(dest)


def test_gitignore_comment_about_evals_out_names_no_harness_or_condition():
    """`.gitignore` reaches the plugin copy untouched - `_plugin_copy_excluded`
    leaves out `evals/`, every `tests/test_eval_*.py`, a published eval
    report and `docs/releasing.md`, never the root `.gitignore` - so a
    compass session can `Read` it. Its comment above `/evals/out/` must not
    name the harness or a condition, or that read alone would tell a
    session it is one half of a compass/bare comparison (EJG-7)."""
    text = (REPO_ROOT / ".gitignore").read_text(encoding="utf-8")
    lines = text.splitlines()
    idx = lines.index("/evals/out/")
    comment_lines = []
    i = idx - 1
    while i >= 0 and lines[i].startswith("#"):
        comment_lines.insert(0, lines[i])
        i -= 1
    assert comment_lines, "no comment found above /evals/out/"
    comment = "\n".join(comment_lines).lower()
    assert "harness" not in comment
    assert "condition" not in comment


# --- 20. the superpowers and spec-kit conditions (CMP-1) --------------------

def test_superpowers_condition_passes_a_read_only_framework_copy_as_plugin_dir(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """`--condition superpowers` loads Superpowers from a pinned commit as a
    plugin: `--framework-source` stands in for the pinned clone
    `evals/frameworks.yml` would otherwise ask for, so this never reaches
    the network."""
    framework_source = _write_framework_repo(tmp_path / "superpowers-source")
    expected_commit = _framework_repo_head(framework_source)
    frameworks_config = _write_frameworks_config_yaml(tmp_path, {
        "superpowers": {"repo": "https://example.invalid/superpowers",
                         "commit": expected_commit},
    })

    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "superpowers", monkeypatch,
        plugin_source_dir, framework_source=framework_source,
        frameworks_config=frameworks_config,
    )

    args = calls[0]["args"]
    plugin_dir = Path(args[args.index("--plugin-dir") + 1])
    plugin_copy = calls[0]["plugin_copy"]
    assert plugin_dir != framework_source
    assert plugin_copy["listing"] == ["MARKER.md"]
    assert plugin_copy["dir_writable"] is False, "the framework copy must be read-only"
    assert "--add-dir" in args
    assert args[args.index("--add-dir") + 1] == str(plugin_dir)

    assert record["framework"] == {"name": "superpowers", "commit": expected_commit}


def test_spec_kit_condition_runs_specify_init_before_the_seed_commit(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """`--condition spec-kit` runs Spec Kit's `specify init` from a pinned
    commit in the seed before the seed commit: a fake `uvx` stands in for
    the real one, writing a marker the fake `claude` executable's own
    directory listing shows if `specify init` ran before the session - the
    same listing `_write_fake_claude` already captures for every test in
    this file."""
    framework_source = _write_framework_repo(
        tmp_path / "spec-kit-source", marker_name="pyproject.toml")
    expected_commit = _framework_repo_head(framework_source)
    fake_uvx = _write_fake_uvx(tmp_path)
    frameworks_config = _write_frameworks_config_yaml(tmp_path, {
        "spec-kit": {"repo": "https://example.invalid/spec-kit",
                     "commit": expected_commit},
    }, name="frameworks-spec-kit.yml")

    calls, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "spec-kit", monkeypatch,
        plugin_source_dir, framework_source=framework_source, uvx_exe=fake_uvx,
        frameworks_config=frameworks_config,
    )

    uvx_calls = _read_fake_uvx_log(fake_uvx)
    assert len(uvx_calls) == 1
    uvx_args = uvx_calls[0]["args"]
    assert uvx_args[0] == "--from"
    from_dir = Path(uvx_args[1])
    assert from_dir != framework_source
    assert uvx_calls[0]["from_dir_listing"] == ["pyproject.toml"]
    assert "init" in uvx_args
    assert "--integration" in uvx_args
    assert uvx_args[uvx_args.index("--integration") + 1] == "claude"
    assert "--non-interactive" in uvx_args
    assert "--here" in uvx_args

    # specify init ran in the seed's own temporary repository, before the
    # harness's own seed commit - so the marker it left is part of the
    # session's own starting point, visible the moment the fake claude
    # executable's own directory listing is taken, and never counted as a
    # change the session itself made.
    assert "specify-init-ran.txt" in calls[0]["listing"]
    assert "specify-init-ran.txt" not in record["changed_paths"]

    assert record["framework"] == {"name": "spec-kit", "commit": expected_commit}


def test_bare_and_compass_conditions_never_call_uvx(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """Neither existing condition touches spec-kit's own installer - a fake
    `uvx` that would fail loudly if called proves neither does."""
    fake_uvx = tmp_path / "uvx-must-not-run"
    fake_uvx.write_text(
        "#!/bin/sh\necho uvx should never run here >&2\nexit 1\n", encoding="utf-8"
    )
    fake_uvx.chmod(fake_uvx.stat().st_mode | stat.S_IEXEC | stat.S_IXGRP | stat.S_IXOTH)

    for condition in ("bare", "compass"):
        _run_condition(
            tmp_path, scenario_dir, fake_claude, condition, monkeypatch,
            plugin_source_dir, out_suffix=f"-{condition}", uvx_exe=fake_uvx,
        )


# --- 20b. the clone allows HTTPS for one call only, and the commit is checked --

def _stub_subprocess_run(calls_log):
    def _stub(args, **kwargs):
        calls_log.append({"args": list(args), "env": kwargs.get("env")})
        return subprocess.CompletedProcess(list(args), 0, stdout="", stderr="")
    return _stub


def test_run_git_protocol_lock_defaults_to_none_and_widens_only_when_told(monkeypatch):
    """`_run_git`'s own `GIT_ALLOW_PROTOCOL` stays `none` on every call
    unless a caller names one - only `_framework_source_dir`'s own clone
    ever does."""
    calls_log: list[dict] = []
    monkeypatch.setattr(harness.subprocess, "run", _stub_subprocess_run(calls_log))

    harness._run_git(["status"], Path("."), {})
    assert calls_log[-1]["env"]["GIT_ALLOW_PROTOCOL"] == "none"

    harness._run_git(["clone", "https://example.invalid/x", "y"], Path("."), {},
                      allow_protocol="https")
    assert calls_log[-1]["env"]["GIT_ALLOW_PROTOCOL"] == "https"
    # Every other safeguard stays exactly as strict for the widened call.
    assert calls_log[-1]["env"]["GIT_CONFIG_GLOBAL"] == "/dev/null"
    assert calls_log[-1]["env"]["GIT_CONFIG_NOSYSTEM"] == "1"


def test_framework_source_dir_clone_call_uses_https_and_checkout_does_not(
    monkeypatch, tmp_path
):
    """`_framework_source_dir`'s own clone is the one call in this module
    that widens the protocol lock; its own later checkout, run against the
    clone it just made, keeps the default."""
    recorded: list[dict] = []
    real_write_framework_repo = _write_framework_repo

    def _fake_run_git(args, cwd, env, *, text=True, allow_protocol="none"):
        recorded.append({"args": list(args), "allow_protocol": allow_protocol})
        if args[0] == "clone":
            # Stands in for a real clone (never reaching the network): a
            # small git repository materialises at the destination the
            # real `git clone` would have used.
            real_write_framework_repo(Path(args[-1]))
            return subprocess.CompletedProcess(["git", *args], 0, stdout="", stderr="")
        return subprocess.CompletedProcess(["git", *args], 0, stdout="", stderr="")

    monkeypatch.setattr(harness, "_run_git", _fake_run_git)
    frameworks_config = {"superpowers": {"repo": "https://example.invalid/superpowers",
                                          "commit": "deadbeef"}}
    source_dir, is_temporary = harness._framework_source_dir(
        "superpowers", None, frameworks_config, {})
    try:
        assert is_temporary is True
        clone_call = next(c for c in recorded if c["args"][0] == "clone")
        assert clone_call["allow_protocol"] == "https"
        checkout_call = next(c for c in recorded if c["args"][0] == "checkout")
        assert checkout_call["allow_protocol"] == "none"
    finally:
        shutil.rmtree(source_dir, ignore_errors=True)


def test_framework_commit_matching_the_pin_is_accepted(tmp_path):
    framework_source = _write_framework_repo(tmp_path / "matching-source")
    commit = _framework_repo_head(framework_source)
    frameworks_config = {"superpowers": {"repo": "https://example.invalid/x",
                                          "commit": commit}}
    harness._check_framework_commit_pin("superpowers", commit, frameworks_config)


def test_framework_commit_mismatch_raises():
    frameworks_config = {"superpowers": {"repo": "https://example.invalid/x",
                                          "commit": "0" * 40}}
    with pytest.raises(SystemExit):
        harness._check_framework_commit_pin("superpowers", "1" * 40, frameworks_config)


def test_framework_source_override_at_the_wrong_commit_stops_prepare_framework_copy(
    tmp_path
):
    """`--framework-source` must be at the commit `evals/frameworks.yml`
    pins, the same as a fresh clone must be - a fixture at any other
    commit stops the run rather than silently comparing an unpinned
    framework."""
    framework_source = _write_framework_repo(tmp_path / "wrong-commit-source")
    frameworks_config = {"superpowers": {"repo": "https://example.invalid/x",
                                          "commit": "0" * 40}}
    with pytest.raises(SystemExit):
        harness._prepare_framework_copy(
            "superpowers", framework_source, frameworks_config, dict(os.environ))


def test_commit_mismatch_stops_the_whole_harness_call(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """Wiring: `main()` itself refuses to write a run record for a
    framework at the wrong commit, not only the function that checks it."""
    framework_source = _write_framework_repo(tmp_path / "e2e-wrong-commit")
    frameworks_config = _write_frameworks_config_yaml(tmp_path, {
        "superpowers": {"repo": "https://example.invalid/superpowers",
                         "commit": "0" * 40},
    }, name="frameworks-mismatch.yml")
    log_path = tmp_path / "log-mismatch.jsonl"
    out_dir = tmp_path / "out-mismatch"
    _configure_fake_claude(fake_claude, log_path, None)
    # Matched against the exception's own text, not only its type: an
    # unrecognized `--frameworks-config` argument also raises `SystemExit`,
    # and would pass a bare `pytest.raises(SystemExit)` for the wrong
    # reason entirely.
    with pytest.raises(SystemExit, match="commit"):
        harness.main([
            "--scenario", str(scenario_dir),
            "--condition", "superpowers",
            "--claude", str(fake_claude),
            "--out", str(out_dir),
            "--plugin-source", str(plugin_source_dir),
            "--framework-source", str(framework_source),
            "--frameworks-config", str(frameworks_config),
        ])
    assert not list(out_dir.glob("*.json"))


# --- 20c. every condition gets the same, wider allow-list -------------------
# (the technical design's own "Tools" rule: a tool one framework needs is
# allowed for all, never for one alone)

def test_allow_list_gives_spec_kit_its_own_bundled_scripts():
    """Spec Kit's own installed skills start with one of its bundled
    scripts under `.specify/scripts/bash/` - `speckit-plan` with
    `setup-plan.sh`, `speckit-constitution` with `resolve-template.sh`,
    <!-- vocabulary-scan: allow - names Spec Kit's own real script and command, not a retired word --> `speckit-tasks` with `setup-tasks.sh`,
    and `speckit-implement`, `speckit-analyze`, `speckit-checklist`,
    `speckit-clarify`, `speckit-converge` and `speckit-taskstoissues` all
    with `check-prerequisites.sh` - the same way Compass's own commands
    start with `compass`, already on this list."""
    for script in ("check-prerequisites.sh", "setup-plan.sh",
                   "setup-tasks.sh", "resolve-template.sh"):
        assert f"Bash(.specify/scripts/bash/{script}:*)" in harness.ALLOWED_TOOLS


def test_allow_list_gives_superpowers_its_own_bundled_scripts():
    """`subagent-driven-development` runs `sdd-workspace`, `review-package`
    <!-- vocabulary-scan: allow - names Superpowers' own real scripts, not a retired word --> and `task-brief`; `executing-plans` runs `task-start` and `task-done` -
    read from both skills' own `SKILL.md` at the pinned commit. A real
    session refused `${CLAUDE_PLUGIN_ROOT}` inside a Bash allow rule -
    Claude Code does not expand it there - so each rule is built at run
    time with the real absolute path of the directory the harness made
    for that run, named `superpowers_scripts_dir` after the parameter
    `_common_claude_args` reads it from."""
    scripts_dir = Path("/tmp/this-runs-own-superpowers-directory")
    args = harness._common_claude_args("bare", None, None, scripts_dir)
    allow_list = args[args.index("--allowedTools") + 1].split(",")
    for skill, script in (
        ("subagent-driven-development", "sdd-workspace"),
        ("subagent-driven-development", "task-brief"),
        ("subagent-driven-development", "review-package"),
        ("executing-plans", "task-start"),
        ("executing-plans", "task-done"),
    ):
        assert f"Bash({scripts_dir}/skills/{skill}/scripts/{script}:*)" in allow_list


def test_allow_list_gives_subagent_driven_developments_own_bash_prefixed_form():
    """`subagent-driven-development`'s own `SKILL.md`, at the pinned
    commit, tells a session to run every one of its scripts with a `bash`
    prefix - `bash scripts/sdd-workspace PLAN_FILE` (line 137),
    <!-- vocabulary-scan: allow - names Superpowers' own real script, not a retired word --> `bash scripts/task-brief PLAN_FILE N` (line 252), `bash scripts/review-
    package PLAN_FILE BASE HEAD` (line 290 and elsewhere) - never the
    bare, executable-bit form `executing-plans` uses. A rule that starts
    with the script's own absolute path does not match a command that
    starts with `bash`, so each script gets two more rules: the same
    absolute path with `bash` in front, and the relative form the skill's
    own text writes, resolved against the skill's own directory rather
    than the plugin's root."""
    scripts_dir = Path("/tmp/this-runs-own-superpowers-directory")
    args = harness._common_claude_args("bare", None, None, scripts_dir)
    allow_list = args[args.index("--allowedTools") + 1].split(",")
    for skill, script in (
        ("subagent-driven-development", "sdd-workspace"),
        ("subagent-driven-development", "task-brief"),
        ("subagent-driven-development", "review-package"),
        ("executing-plans", "task-start"),
        ("executing-plans", "task-done"),
    ):
        assert f"Bash(bash {scripts_dir}/skills/{skill}/scripts/{script}:*)" in allow_list
        assert f"Bash(bash scripts/{script}:*)" in allow_list


def test_allow_list_lets_a_session_start_a_feature_branch():
    """`executing-plans` asks before working directly on the seed's own
    default branch; a session that follows that instruction needs the
    tool to act on the answer, under either the old or the new git
    syntax."""
    assert "Bash(git checkout -b:*)" in harness.ALLOWED_TOOLS
    assert "Bash(git switch -c:*)" in harness.ALLOWED_TOOLS


def test_allow_list_gives_every_condition_the_agent_tool():
    """`subagent-driven-development` dispatches an implementer and a
    reviewer subagent; Compass's own `implement` stage dispatches one too
    - both need the `Agent` tool, and every condition gets the same list,
    so it is on regardless of which condition is running."""
    assert "Agent" in harness.ALLOWED_TOOLS


# Every framework-script rule's own absolute path, replaced with one fixed
# placeholder - a fresh directory the harness builds for the run, real and
# distinct every time (`tempfile.mkdtemp()`, or the superpowers condition's
# own `--plugin-dir` copy), is the one part of the allow-list this file
# documents as allowed to differ from run to run and condition to
# condition.
_SUPERPOWERS_SCRIPT_RULE_RE = re.compile(
    r"Bash\((bash )?[^,]*?/skills/(subagent-driven-development|executing-plans)/scripts/")


def _normalise_superpowers_script_paths(allow_list: str) -> str:
    return _SUPERPOWERS_SCRIPT_RULE_RE.sub(r"Bash(\1<DIR>/skills/\2/scripts/", allow_list)


def test_every_conditions_allow_list_is_identical(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """Every condition passes through `_common_claude_args` unconditionally
    - this runs all four and reads each one's own `--allowedTools`
    argument back, so the claim is proved against what the harness
    actually sends, not only against a shared constant. The five
    Superpowers-script rules carry that run's own real directory - a
    different one for every condition, none of them Superpowers' own
    `--plugin-dir` copy except the superpowers condition's - so those five
    are normalised to one placeholder before the comparison; everything
    else must already be byte-identical."""
    framework_source = _write_framework_repo(tmp_path / "identical-source")
    commit = _framework_repo_head(framework_source)
    frameworks_config = _write_frameworks_config_yaml(tmp_path, {
        "superpowers": {"repo": "https://example.invalid/superpowers", "commit": commit},
        "spec-kit": {"repo": "https://example.invalid/spec-kit", "commit": commit},
    }, name="frameworks-identical.yml")
    fake_uvx = _write_fake_uvx(tmp_path)

    allow_lists = {}
    for condition in ("bare", "compass", "superpowers", "spec-kit"):
        calls, _, _ = _run_condition(
            tmp_path, scenario_dir, fake_claude, condition, monkeypatch,
            plugin_source_dir, out_suffix=f"-identical-{condition}",
            framework_source=framework_source, uvx_exe=fake_uvx,
            frameworks_config=frameworks_config,
        )
        args = calls[0]["args"]
        raw = args[args.index("--allowedTools") + 1]
        # The raw lists must actually differ - otherwise the placeholder
        # substitution below is proving nothing.
        allow_lists[f"{condition}-raw"] = raw
        allow_lists[condition] = _normalise_superpowers_script_paths(raw)

    raw_values = {v for k, v in allow_lists.items() if k.endswith("-raw")}
    assert len(raw_values) > 1, "the raw allow-lists were already identical"
    normalised_values = {v for k, v in allow_lists.items() if not k.endswith("-raw")}
    assert len(normalised_values) == 1, allow_lists


def test_superpowers_runs_rules_name_its_own_plugin_copys_absolute_path(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """The superpowers condition's five Superpowers-script rules must name
    the exact directory passed as `--plugin-dir` - not a placeholder, and
    not some other run's own directory - since that is the one path Claude
    Code will actually resolve `scripts/sdd-workspace` and the rest
    against."""
    framework_source = _write_framework_repo(tmp_path / "own-path-source")
    commit = _framework_repo_head(framework_source)
    frameworks_config = _write_frameworks_config_yaml(tmp_path, {
        "superpowers": {"repo": "https://example.invalid/superpowers", "commit": commit},
    }, name="frameworks-own-path.yml")

    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "superpowers", monkeypatch,
        plugin_source_dir, framework_source=framework_source,
        frameworks_config=frameworks_config,
    )
    args = calls[0]["args"]
    plugin_dir = args[args.index("--plugin-dir") + 1]
    allow_list = args[args.index("--allowedTools") + 1].split(",")
    for skill, script in (
        ("subagent-driven-development", "sdd-workspace"),
        ("subagent-driven-development", "task-brief"),
        ("subagent-driven-development", "review-package"),
        ("executing-plans", "task-start"),
        ("executing-plans", "task-done"),
    ):
        assert f"Bash({plugin_dir}/skills/{skill}/scripts/{script}:*)" in allow_list
        # `subagent-driven-development`'s own SKILL.md runs every one of
        # its scripts with a `bash` prefix - this run's own bash-prefixed
        # rule must name the same real directory, not a placeholder.
        assert f"Bash(bash {plugin_dir}/skills/{skill}/scripts/{script}:*)" in allow_list


def test_superpowers_condition_gets_add_dir_for_its_framework_copy():
    """Compass's own plugin copy gets `--add-dir`
    (`test_compass_condition_also_gets_add_dir_for_the_plugin_copy`) so a
    `cat` of one of its own files is not refused. Superpowers' copy needs
    the same standing - `_common_claude_args` is the one function that
    builds this list, so a unit test against it is enough; the end-to-end
    check lives in the superpowers condition test above."""
    args = harness._common_claude_args(
        "superpowers", None, Path("/tmp/framework-copy"), Path("/tmp/framework-copy"))
    assert "--add-dir" in args
    assert args[args.index("--add-dir") + 1] == str(Path("/tmp/framework-copy"))


# --- 20d. the model is pinned for every condition (the model pin) -----------

def test_every_condition_pins_the_same_model():
    scripts_dir = Path("/tmp/model-test-superpowers-scripts")
    for condition, plugin_copy_dir, framework_copy_dir in (
        ("bare", None, None),
        ("compass", Path("/tmp/plugin-copy"), None),
        ("superpowers", None, Path("/tmp/framework-copy")),
        ("spec-kit", None, Path("/tmp/framework-copy")),
    ):
        args = harness._common_claude_args(
            condition, plugin_copy_dir, framework_copy_dir, scripts_dir)
        assert "--model" in args, condition
        assert args[args.index("--model") + 1] == harness._PINNED_CLAUDE_MODEL


# --- 21. hidden tests and regressions (CMP-2) --------------------------------

def _write_scenario_with_hidden_tests(tmp_path: Path) -> Path:
    """A scenario fixture whose seed's own tests are real pytest tests, and
    which carries `hidden_tests/` - CMP-2's own fixture. The fake CLI's
    universal edit to `seed.txt` (`_FAKE_CLAUDE_SOURCE`, appends a line
    unless a test sets `no_edit`) breaks `test_seed_unchanged`, so a real
    pytest run reports a genuine regression, not a canned one."""
    scenario_dir = tmp_path / "hidden-scenario"
    seed_tests_dir = scenario_dir / "seed" / "tests"
    seed_tests_dir.mkdir(parents=True)
    (scenario_dir / "seed" / "seed.txt").write_text(
        "original contents\n", encoding="utf-8")
    (seed_tests_dir / "test_seed.py").write_text(
        "def test_seed_unchanged():\n"
        "    with open('seed.txt', encoding='utf-8') as fh:\n"
        "        assert fh.read() == 'original contents\\n'\n"
        "\n"
        "def test_always_passes():\n"
        "    assert True\n",
        encoding="utf-8",
    )

    hidden_tests_dir = scenario_dir / "hidden_tests" / "tests"
    hidden_tests_dir.mkdir(parents=True)
    (hidden_tests_dir / "test_hidden_feature.py").write_text(
        "def test_hidden_feature():\n"
        "    assert False, 'the seed never implements this'\n",
        encoding="utf-8",
    )

    scenario_yml = {
        "id": "hidden-fixture",
        "failure_mode": "a fixture failure mode, used only by this test file",
        "prompt": "Fix the bug in seed.txt.",
        "follow_ups": [],
        "risky": False,
        "budget_usd": 3.0,
        "in_scope": ["**"],
        "test_command": "python3 -m pytest -q",
        "hidden_command": "python3 -m pytest -q tests/test_hidden_feature.py",
        "behaviours": [
            {"id": "fixture_behaviour", "rubric": "unused by this test file"},
        ],
    }
    with (scenario_dir / "scenario.yml").open("w", encoding="utf-8") as fh:
        yaml.safe_dump(scenario_yml, fh, sort_keys=False)

    _git_commit_all(scenario_dir, "hidden-tests scenario fixture")
    return scenario_dir


def test_hidden_tests_are_copied_in_only_after_the_session_ends(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """A scenario may carry `hidden_tests/`, copied in only after the
    session ends: the fake CLI's own directory listing, taken from inside
    its own call - before the harness could ever have copied
    `hidden_tests/` in - shows nothing from it."""
    scenario_dir = _write_scenario_with_hidden_tests(tmp_path)
    calls, _, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-hidden-listing",
    )
    assert "tests/test_hidden_feature.py" not in calls[0]["listing"]


def test_hidden_command_gives_a_pass_rate_and_regressions_are_recorded(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """The scenario's own `hidden_command` runs once `hidden_tests/` is
    copied in, giving a real pass rate; the seed's own tests run again too,
    and `test_seed_unchanged` - which passed at the seed and the fake
    CLI's own universal edit to `seed.txt` now breaks - is the one
    regression recorded. `test_always_passes` still passes, so it is not
    one; `test_hidden_feature` never passed at the seed at all (it did not
    exist yet), so it is not one either."""
    scenario_dir = _write_scenario_with_hidden_tests(tmp_path)
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-hidden-regressions",
    )

    assert record["hidden"] == {
        "command": "python3 -m pytest -q tests/test_hidden_feature.py",
        "exit_code": 1, "passed": 0, "failed": 1, "defined": 1,
    }
    assert record["regressions"] == ["tests/test_seed.py::test_seed_unchanged"]
    assert record["tests_after"]["exit_code"] != 0


def test_a_scenario_without_hidden_tests_gets_no_hidden_or_regressions_measure(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """The ordinary fixture scenario carries no `hidden_tests/` - `hidden`
    and `regressions` both read `None`, never an empty result that could
    read as "nothing regressed"."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-no-hidden",
    )
    assert record["hidden"] is None
    assert record["regressions"] is None


def _write_scenario_with_uncollectable_hidden_test(tmp_path: Path) -> Path:
    """A CMP-2 fixture whose hidden test cannot import: it names a function
    the seed never defines, the same shape as `cmp-risky`'s own hidden
    test naming a function no session wrote. It defines three `test_`
    functions, not one - EGB-4's fixture, so a fix that counts every test
    the file holds reads differently from one that still counts the
    single collection error pytest's own summary reports. The seed
    carries no `seed.txt`, so the fake CLI's universal edit never touches
    it - the seed's own tests still pass, whatever the session did."""
    scenario_dir = tmp_path / "uncollectable-hidden-scenario"
    seed_src_dir = scenario_dir / "seed" / "src"
    seed_tests_dir = scenario_dir / "seed" / "tests"
    seed_src_dir.mkdir(parents=True)
    seed_tests_dir.mkdir(parents=True)
    (scenario_dir / "seed" / "pytest.ini").write_text(
        "[pytest]\npythonpath = .\n", encoding="utf-8")
    (seed_src_dir / "thing.py").write_text(
        "def existing():\n    return True\n", encoding="utf-8")
    (seed_tests_dir / "test_thing.py").write_text(
        "from src.thing import existing\n"
        "\n"
        "def test_existing_still_true():\n"
        "    assert existing() is True\n",
        encoding="utf-8",
    )

    hidden_tests_dir = scenario_dir / "hidden_tests" / "tests"
    hidden_tests_dir.mkdir(parents=True)
    (hidden_tests_dir / "test_hidden_thing.py").write_text(
        "from src.thing import missing_function\n"
        "\n"
        "def test_missing_function():\n"
        "    assert missing_function() is True\n"
        "\n"
        "def test_missing_function_again():\n"
        "    assert missing_function() is True\n"
        "\n"
        "def test_missing_function_a_third_time():\n"
        "    assert missing_function() is True\n",
        encoding="utf-8",
    )

    scenario_yml = {
        "id": "uncollectable-hidden-fixture",
        "failure_mode": "a fixture failure mode, used only by this test file",
        "prompt": "Add missing_function to src/thing.py.",
        "follow_ups": [],
        "risky": False,
        "budget_usd": 3.0,
        "in_scope": ["**"],
        "test_command": "python3 -m pytest -q",
        "hidden_command": "python3 -m pytest -q tests/test_hidden_thing.py",
        "behaviours": [
            {"id": "fixture_behaviour", "rubric": "unused by this test file"},
        ],
    }
    with (scenario_dir / "scenario.yml").open("w", encoding="utf-8") as fh:
        yaml.safe_dump(scenario_yml, fh, sort_keys=False)

    _git_commit_all(scenario_dir, "uncollectable hidden-tests scenario fixture")
    return scenario_dir


def test_a_hidden_test_that_cannot_import_never_inflates_regressions(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """CMP-2: pytest's default behaviour, on a collection error, is to
    abort the whole run rather than skip only the one file - so measuring
    "after" with `hidden_tests/` already copied in reads no seed outcome
    at all, and every seed test that passed at the seed reads as
    regressed. The seed's own test command must run, for this comparison,
    before `hidden_tests/` lands: the regression count stays 0 when the
    session changed nothing and the seed's own test still passes."""
    scenario_dir = _write_scenario_with_uncollectable_hidden_test(tmp_path)
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-hidden-uncollectable",
    )

    assert record["regressions"] == []
    assert record["tests_after"]["exit_code"] == 0


def test_a_hidden_test_that_cannot_import_counts_every_test_it_holds_as_failed(
    tmp_path, fake_claude, plugin_source_dir, monkeypatch
):
    """EGB-4: pytest's own summary line counts one error for the whole
    file, whatever `test_` functions it defines - B6's `cmp-risky` under
    Compass showed 1 of 1 failed where the file holds five. The fixture
    here holds three; the record must count every one of them as failed,
    not the one pytest's own line gives."""
    scenario_dir = _write_scenario_with_uncollectable_hidden_test(tmp_path)
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-hidden-uncollectable-count",
    )

    assert record["hidden"]["passed"] == 0
    assert record["hidden"]["failed"] == 3


def test_pytest_summary_counts_reads_only_the_final_summary_line():
    """`_pytest_summary_counts` must read pytest's own final summary line,
    not every line that happens to contain a number followed by "passed"
    or "failed" - a hidden test can print exactly that as its own output,
    or as part of an assertion message, without it meaning what the
    function's docstring promises."""
    output = (
        "tests/test_thing.py::test_one PASSED\n"
        "the answer was 2 failed, 9000 passed - a decoy printed by the test itself\n"
        "tests/test_thing.py::test_two FAILED\n"
        "=================== 1 failed, 1 passed in 0.03s ===================\n"
    )
    assert harness._pytest_summary_counts(output) == (1, 1)


def test_a_head_reading_ref_garbage_is_recorded_as_not_contained_end_to_end(
    tmp_path, scenario_dir, fake_claude, plugin_source_dir, monkeypatch
):
    """The second broken repository state: `.git/HEAD` reads `ref: garbage`,
    a line that starts with `ref:` but names no branch. The unit test
    against `_diff_since_seed` pins it; this pins it through `run_once`,
    which is what a real run records."""
    _, record, _ = _run_condition(
        tmp_path, scenario_dir, fake_claude, "bare", monkeypatch,
        plugin_source_dir, out_suffix="-git-head-garbage-ref",
        extra_config={"garbage_ref_git_head": True},
    )
    assert record["contained"] is False
    assert "git-state:.git" in record["escaped_paths"]


def test_a_skipped_hidden_test_is_not_counted_as_failed():
    """A short total with exit 1 is a run where a test was skipped; only a
    collection error, exit 2, means none of the defined tests ran."""
    assert harness.corrected_hidden_counts(4, 0, 5, exit_code=0) == (4, 0)
    assert harness.corrected_hidden_counts(3, 1, 5, exit_code=1) == (3, 1)
    assert harness.corrected_hidden_counts(0, 1, 5, exit_code=2) == (0, 5)

