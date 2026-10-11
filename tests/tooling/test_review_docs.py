"""Documentation review must use the candidate tree and fail closed."""

from __future__ import annotations

import json
import os
import subprocess
import sys
import time
from concurrent.futures import Future
from pathlib import Path
from tempfile import TemporaryDirectory
from threading import Barrier, Event
from types import SimpleNamespace
from typing import TYPE_CHECKING, Any

import pytest
from scripts import review_docs
from tests.e2e.codex_harness import _terminate_tree

if TYPE_CHECKING:
    from collections.abc import Iterator

    from pytest import MonkeyPatch


def _git(repo: Path, *args: str) -> str:
    return subprocess.check_output(["git", "-C", str(repo), *args], text=True).strip()


@pytest.fixture
def repository() -> Iterator[tuple[Path, str, str]]:
    with TemporaryDirectory(prefix="tradingdev-review-test-") as temporary:
        root = Path(temporary)
        _git(root, "init", "-q")
        (root / "src").mkdir()
        (root / "README.md").write_text("# App\nOld behavior.\n", encoding="utf-8")
        (root / "src/app.py").write_text("VALUE = 'old'\n", encoding="utf-8")
        _git(root, "add", ".")
        base = _git(root, "write-tree")
        (root / "src/app.py").write_text("VALUE = 'staged'\n", encoding="utf-8")
        _git(root, "add", "src/app.py")
        tree = _git(root, "write-tree")
        yield root, base, tree


@pytest.fixture
def fake_codex(monkeypatch: MonkeyPatch) -> Iterator[Path]:
    with TemporaryDirectory(prefix="tradingdev-fake-reviewer-") as temporary:
        root = Path(temporary)
        binary = root / "codex"
        record = root / "record.json"
        binary.write_text(
            f"#!{sys.executable}\n"
            "import json, os, pathlib, signal, sys, time\n"
            "prompt = sys.stdin.read()\n"
            "mode = os.environ.get('REVIEW_FAKE_MODE', 'pass')\n"
            "evidence = json.loads(prompt.rsplit('\\n\\n', 1)[-1])\n"
            "batch = evidence.get('batch', {'index': 1})['index']\n"
            "modes = json.loads(os.environ.get('REVIEW_FAKE_BATCH_MODES', '{}'))\n"
            "mode = modes.get(str(batch), mode)\n"
            "record = {'root': str(pathlib.Path.cwd()), 'pid': os.getpid(), "
            "'prompt': prompt, 'args': sys.argv[1:], 'started': time.monotonic()}\n"
            "record_path = pathlib.Path(os.environ['REVIEW_FAKE_RECORD'])\n"
            "record_dir = record_path.with_suffix('.records')\n"
            "record_dir.mkdir(exist_ok=True)\n"
            "own_record = record_dir / f'{os.getpid()}.json'\n"
            "def record_state():\n"
            "    pending = own_record.with_suffix('.tmp')\n"
            "    pending.write_text(json.dumps(record))\n"
            "    pending.replace(own_record)\n"
            "    record_path.write_text(json.dumps(record))\n"
            "record_state()\n"
            "ready_count = int(os.environ.get('REVIEW_FAKE_READY_COUNT', '0'))\n"
            "while len(list(record_dir.glob('*.json'))) < ready_count:\n"
            "    time.sleep(0.01)\n"
            "if mode in {'timeout', 'wait'}:\n"
            "    if mode == 'timeout': signal.signal(signal.SIGTERM, signal.SIG_IGN)\n"
            "    while True: time.sleep(0.05)\n"
            "if mode == 'exit':\n"
            "    print('authentication failed', file=sys.stderr)\n"
            "    sys.exit(9)\n"
            "verdict = {'passed': True, 'findings': []}\n"
            "if mode == 'outdated':\n"
            "    verdict = {'passed': False, 'findings': [{'file': 'README.md', "
            "'explanation': f'Update old behavior to staged behavior. "
            "Batch {batch}.'}]}\n"
            "if mode == 'inconsistent': verdict['passed'] = False\n"
            "result = 'broken json' if mode == 'malformed' else json.dumps(verdict)\n"
            "output = pathlib.Path(sys.argv["
            "sys.argv.index('--output-last-message') + 1])\n"
            "if mode != 'missing': output.write_text(result)\n"
            "if mode == 'failed_event': print(json.dumps({'type': 'turn.failed'}))\n"
            "elif mode == 'tool':\n"
            "    print(json.dumps({'type': 'item.completed', "
            "'item': {'type': 'command_execution'}}))\n"
            "else: print(json.dumps({'type': 'turn.completed'}))\n"
            "record['ended'] = time.monotonic()\n"
            "record_state()\n",
            encoding="utf-8",
        )
        binary.chmod(0o700)
        monkeypatch.setenv("TRADINGDEV_CODEX_BIN", str(binary))
        monkeypatch.setenv("REVIEW_FAKE_RECORD", str(record))
        monkeypatch.delenv("REVIEW_FAKE_MODE", raising=False)
        monkeypatch.delenv("REVIEW_FAKE_BATCH_MODES", raising=False)
        monkeypatch.delenv("REVIEW_FAKE_READY_COUNT", raising=False)
        yield record


def test_review_uses_immutable_candidate_and_removes_temporary_files(
    repository: tuple[Path, str, str], fake_codex: Path
) -> None:
    repo, base, tree = repository
    (repo / "src/app.py").write_text("VALUE = 'UNSTAGED_SECRET'\n", encoding="utf-8")
    (repo / "README.md").write_text("UNSTAGED_DOC\n", encoding="utf-8")
    review_docs.review(base, tree, repo=repo)
    record = json.loads(fake_codex.read_text(encoding="utf-8"))
    assert "staged" in record["prompt"]
    assert "Old behavior" in record["prompt"]
    assert "UNSTAGED" not in record["prompt"]
    assert "ignore-user-config" in " ".join(record["args"])
    assert "features.shell_tool=false" in record["args"]
    assert "features.shell_snapshot=false" in record["args"]
    assert 'web_search="disabled"' in record["args"]
    assert "--ephemeral" in record["args"]
    assert "read-only" in record["args"]
    assert not Path(record["root"]).exists()


def test_evidence_includes_deleted_files_and_all_existing_docs(
    repository: tuple[Path, str, str],
) -> None:
    repo, base, _ = repository
    (repo / "docs/strategies").mkdir(parents=True)
    (repo / "docs/strategies/example.md").write_text("# Strategy\n", encoding="utf-8")
    (repo / "src/app.py").unlink()
    _git(repo, "add", ".")
    tree = _git(repo, "write-tree")
    evidence = json.loads(review_docs.build_evidence(repo, base, tree))
    assert "deleted file" in evidence["diff"]
    assert "src/app.py" in evidence["changed_paths"]
    assert "src/app.py" not in evidence["candidate_files"]
    assert "docs/strategies/example.md" in evidence["candidate_files"]


@pytest.mark.parametrize(
    "tooling_path",
    [
        "scripts/hooks/pre-commit",
        ".githooks/pre-commit",
        ".Codex/hooks/finalize-python",
        ".vscode/settings.json",
    ],
)
def test_evidence_includes_tooling_but_excludes_runtime_state(
    repository: tuple[Path, str, str],
    tooling_path: str,
) -> None:
    repo, base, _ = repository
    tooling_file = repo / tooling_path
    tooling_file.parent.mkdir(parents=True)
    tooling_file.write_text("tooling content\n", encoding="utf-8")
    (repo / "workspace").mkdir()
    (repo / "workspace/strategy.py").write_text("RUNTIME_SECRET\n", encoding="utf-8")
    _git(repo, "add", ".")
    tree = _git(repo, "write-tree")
    evidence = review_docs.build_evidence(repo, base, tree)
    assert tooling_path in json.loads(evidence)["candidate_files"]
    assert "RUNTIME_SECRET" not in evidence


def test_evidence_includes_deleted_codex_hook(
    repository: tuple[Path, str, str],
) -> None:
    repo, _, _ = repository
    hook = repo / ".Codex/hooks/finalize-python"
    hook.parent.mkdir(parents=True)
    hook.write_text("legacy hook\n", encoding="utf-8")
    _git(repo, "add", ".")
    base = _git(repo, "write-tree")
    hook.unlink()
    _git(repo, "add", ".")
    tree = _git(repo, "write-tree")
    evidence = json.loads(review_docs.build_evidence(repo, base, tree))
    assert "deleted file" in evidence["diff"]
    assert "legacy hook" in evidence["diff"]
    assert ".Codex/hooks/finalize-python" not in evidence["candidate_files"]


@pytest.mark.parametrize(
    ("mode", "message"),
    [
        ("outdated", "README.md: Update old behavior"),
        ("malformed", "could not complete"),
        ("inconsistent", "inconsistent documentation verdict"),
        ("missing", "could not complete"),
        ("exit", "exited 9: authentication failed"),
        ("failed_event", "failed review"),
        ("tool", "attempted a tool call"),
    ],
)
def test_failed_review_always_removes_temporary_files(
    repository: tuple[Path, str, str],
    fake_codex: Path,
    monkeypatch: MonkeyPatch,
    mode: str,
    message: str,
) -> None:
    repo, base, tree = repository
    monkeypatch.setenv("REVIEW_FAKE_MODE", mode)
    with pytest.raises(review_docs.ReviewError, match=message):
        review_docs.review(base, tree, repo=repo)
    record = json.loads(fake_codex.read_text(encoding="utf-8"))
    assert not Path(record["root"]).exists()
    with pytest.raises(ProcessLookupError):
        os.kill(record["pid"], 0)


def test_timeout_terminates_process_and_cleans_files(
    repository: tuple[Path, str, str], fake_codex: Path, monkeypatch: MonkeyPatch
) -> None:
    repo, base, tree = repository
    monkeypatch.setenv("REVIEW_FAKE_MODE", "timeout")
    with pytest.raises(review_docs.ReviewError, match="timed out"):
        review_docs.review(base, tree, repo=repo, timeout_seconds=0.5)
    record = json.loads(fake_codex.read_text(encoding="utf-8"))
    assert not Path(record["root"]).exists()
    with pytest.raises(ProcessLookupError):
        os.kill(record["pid"], 0)


def test_excessive_evidence_fails_before_model_call(
    repository: tuple[Path, str, str], fake_codex: Path
) -> None:
    repo, base, tree = repository
    with pytest.raises(review_docs.ReviewError, match="no evidence was truncated"):
        review_docs.review(base, tree, repo=repo, max_evidence_bytes=10)
    assert not fake_codex.exists()


def test_explicit_budget_reviews_complete_evidence_larger_than_default(
    repository: tuple[Path, str, str], fake_codex: Path
) -> None:
    repo, base, _ = repository
    content = "# unchanged evidence must reach the reviewer\n" * 8_000
    (repo / "src/app.py").write_text(content, encoding="utf-8")
    _git(repo, "add", "src/app.py")
    tree = _git(repo, "write-tree")
    evidence = review_docs.build_evidence(repo, base, tree, max_bytes=1_000_000)
    size = len(evidence.encode("utf-8"))
    assert size > review_docs.MAX_EVIDENCE_BYTES
    with pytest.raises(review_docs.ReviewError, match="no evidence was truncated"):
        review_docs.review(base, tree, repo=repo)
    assert not fake_codex.exists()
    with pytest.raises(review_docs.ReviewError, match="no evidence was truncated"):
        review_docs.review(base, tree, repo=repo, max_evidence_bytes=size - 1)
    assert not fake_codex.exists()

    review_docs.review(base, tree, repo=repo, max_evidence_bytes=size)
    record = json.loads(fake_codex.read_text(encoding="utf-8"))
    assert record["prompt"].endswith(evidence)
    assert not Path(record["root"]).exists()


def test_unavailable_codex_is_an_actionable_failure(
    repository: tuple[Path, str, str], monkeypatch: MonkeyPatch
) -> None:
    repo, base, tree = repository
    monkeypatch.setenv("TRADINGDEV_CODEX_BIN", "/missing/documentation-review-codex")
    with pytest.raises(
        review_docs.ReviewError, match="TRADINGDEV_CODEX_BIN is not executable"
    ):
        review_docs.review(base, tree, repo=repo)


def test_script_is_executable_from_another_working_directory(
    repository: tuple[Path, str, str], fake_codex: Path
) -> None:
    repo, base, tree = repository
    result = subprocess.run(
        [
            sys.executable,
            str(Path(review_docs.__file__).resolve()),
            "--base",
            base,
            "--tree",
            tree,
        ],
        cwd=repo,
        capture_output=True,
        text=True,
        check=False,
    )
    assert result.returncode == 0, result.stderr
    assert "Documentation review passed" in result.stdout
    assert fake_codex.exists()


def _prompt_evidence(prompt: str) -> dict[str, Any]:
    value = json.loads(prompt.rsplit("\n\n", 1)[-1])
    assert isinstance(value, dict)
    return value


def _records(path: Path) -> list[dict[str, Any]]:
    return [
        json.loads(record.read_text(encoding="utf-8"))
        for record in path.with_suffix(".records").glob("*.json")
    ]


def _assert_reviewer_cleanup(records: list[dict[str, Any]]) -> None:
    assert records
    for record in records:
        assert not Path(record["root"]).exists()
        with pytest.raises(ProcessLookupError):
            os.kill(record["pid"], 0)


def _synthetic_evidence(file_count: int = 6) -> str:
    files = {
        "README.md": "# Shared docs\nAll behavior must be reviewed.\n",
        **{
            f"src/file_{index}.py": f"{index:04d}" * 5_000
            for index in range(file_count)
        },
    }
    return json.dumps(
        {
            "base_tree": "a" * 40,
            "candidate_tree": "b" * 40,
            "changed_paths": sorted(files),
            "excluded_from_content": [],
            "selection": "All source files and complete documentation.",
            "diff": "Every implementation change is represented in the shared diff.\n",
            "candidate_files": files,
        },
        ensure_ascii=False,
    )


def _use_small_batches(monkeypatch: MonkeyPatch, *, file_count: int = 6) -> str:
    evidence = _synthetic_evidence(file_count)
    monkeypatch.setattr(review_docs, "MAX_PROMPT_CHARS", 30_000)
    monkeypatch.setattr(review_docs, "build_evidence", lambda *_, **__: evidence)
    assert len(review_docs.build_review_prompts(evidence)) == file_count
    return evidence


def test_prompt_hard_limit_is_independent_of_explicit_evidence_budget() -> None:
    assert 0 < review_docs.MAX_PROMPT_CHARS < 1_048_576
    assert review_docs.MAX_PARALLEL_REVIEWS == 8
    assert review_docs.MAX_EVIDENCE_BYTES == 600_000


def test_large_evidence_batches_include_complete_shared_context_and_all_files(
    repository: tuple[Path, str, str], fake_codex: Path
) -> None:
    repo, base, _ = repository
    (repo / "tests").mkdir()
    (repo / "docs").mkdir()
    (repo / "docs/contract.md").write_text("# Complete contract\n", encoding="utf-8")
    (repo / "src/behavior.md").write_text("# Inline behavior docs\n", encoding="utf-8")
    (repo / "src/app.py").write_text("# source evidence\n" * 16_000, encoding="utf-8")
    (repo / "tests/test_app.py").write_text(
        "# complete regression test evidence\n" * 8_000, encoding="utf-8"
    )
    _git(repo, "add", ".")
    tree = _git(repo, "write-tree")
    raw = review_docs.build_evidence(repo, base, tree, max_bytes=2_000_000)
    evidence = json.loads(raw)
    assert len(raw) > review_docs.MAX_PROMPT_CHARS
    review_docs.review(base, tree, repo=repo, max_evidence_bytes=2_000_000)

    records = _records(fake_codex)
    assert len(records) > 1
    batches = [_prompt_evidence(record["prompt"]) for record in records]
    assert {batch["batch"]["index"] for batch in batches} == set(
        range(1, len(batches) + 1)
    )
    common_docs = {
        path: content
        for path, content in evidence["candidate_files"].items()
        if path.endswith(".md")
    }
    assigned: list[str] = []
    for record, batch in zip(records, batches, strict=True):
        assert len(record["prompt"]) <= review_docs.MAX_PROMPT_CHARS
        assert batch["batch"]["count"] == len(batches)
        assert batch["candidate_file_inventory"] == sorted(evidence["candidate_files"])
        for key, value in evidence.items():
            if key != "candidate_files":
                assert batch[key] == value
        paths = batch["batch"]["assigned_paths"]
        assert paths == sorted(paths)
        assigned.extend(paths)
        assert batch["candidate_files"] == common_docs | {
            path: evidence["candidate_files"][path] for path in paths
        }
    assert sorted(assigned) == sorted(
        set(evidence["candidate_files"]) - common_docs.keys()
    )
    _assert_reviewer_cleanup(records)


def test_prompt_limit_counts_unicode_characters_but_evidence_budget_counts_bytes(
    repository: tuple[Path, str, str], monkeypatch: MonkeyPatch
) -> None:
    repo, base, _ = repository
    (repo / "src/app.py").write_text("# 繁體中文測試資料\n" * 1_000, encoding="utf-8")
    _git(repo, "add", ".")
    tree = _git(repo, "write-tree")
    evidence = review_docs.build_evidence(repo, base, tree)
    byte_count = len(evidence.encode("utf-8"))
    prompt = review_docs.build_review_prompts(evidence)[0]
    assert len(prompt.encode("utf-8")) > len(prompt)
    monkeypatch.setattr(review_docs, "MAX_PROMPT_CHARS", len(prompt))
    assert review_docs.build_review_prompts(evidence) == [prompt]
    assert (
        review_docs.build_evidence(repo, base, tree, max_bytes=byte_count) == evidence
    )
    with pytest.raises(review_docs.ReviewError, match="no evidence was truncated"):
        review_docs.build_evidence(repo, base, tree, max_bytes=byte_count - 1)
    monkeypatch.setattr(review_docs, "MAX_PROMPT_CHARS", len(prompt) - 1)
    with pytest.raises(review_docs.ReviewError, match="character"):
        review_docs.build_review_prompts(evidence)


@pytest.mark.parametrize("overflow", ["shared-docs", "shared-diff", "last-file"])
def test_unsplittable_evidence_fails_before_any_batch_invokes_model(
    repository: tuple[Path, str, str],
    fake_codex: Path,
    monkeypatch: MonkeyPatch,
    overflow: str,
) -> None:
    repo, base, tree = repository
    evidence = json.loads(_use_small_batches(monkeypatch))
    if overflow == "shared-docs":
        evidence["candidate_files"]["README.md"] = "x" * 30_000
    elif overflow == "shared-diff":
        evidence["diff"] = "x" * 30_000
    else:
        evidence["candidate_files"]["src/file_5.py"] = "x" * 30_000
    monkeypatch.setattr(
        review_docs, "build_evidence", lambda *_, **__: json.dumps(evidence)
    )
    with pytest.raises(review_docs.ReviewError, match="character"):
        review_docs.review(base, tree, repo=repo, max_evidence_bytes=2_000_000)
    assert not fake_codex.exists()
    assert not _records(fake_codex)


def test_parallel_batches_are_bounded_and_every_successful_process_is_cleaned(
    repository: tuple[Path, str, str], fake_codex: Path, monkeypatch: MonkeyPatch
) -> None:
    repo, base, tree = repository
    workers = review_docs.MAX_PARALLEL_REVIEWS
    batch_count = workers + 2
    _use_small_batches(monkeypatch, file_count=batch_count)
    monkeypatch.setenv("REVIEW_FAKE_READY_COUNT", str(workers))
    review_docs.review(base, tree, repo=repo, timeout_seconds=10)
    records = _records(fake_codex)
    assert len(records) == batch_count
    events = sorted(
        event
        for record in records
        for event in [(record["started"], 1), (record["ended"], -1)]
    )
    active = maximum = 0
    for _, change in events:
        active += change
        maximum = max(maximum, active)
    assert maximum == workers
    _assert_reviewer_cleanup(records)


def test_findings_from_separate_batches_are_all_reported(
    repository: tuple[Path, str, str], fake_codex: Path, monkeypatch: MonkeyPatch
) -> None:
    repo, base, tree = repository
    _use_small_batches(monkeypatch)
    monkeypatch.setenv(
        "REVIEW_FAKE_BATCH_MODES", json.dumps({"1": "outdated", "5": "outdated"})
    )
    with pytest.raises(review_docs.ReviewError) as error:
        review_docs.review(base, tree, repo=repo)
    assert "Batch 1." in str(error.value)
    assert "Batch 5." in str(error.value)
    records = _records(fake_codex)
    assert len(records) == 6
    _assert_reviewer_cleanup(records)


@pytest.mark.parametrize(
    ("mode", "message"),
    [
        ("malformed", "could not complete"),
        ("inconsistent", "inconsistent documentation verdict"),
        ("missing", "could not complete"),
        ("exit", "exited 9: authentication failed"),
        ("failed_event", "failed review"),
        ("tool", "attempted a tool call"),
    ],
)
def test_one_invalid_batch_cannot_be_hidden_by_other_passing_batches(
    repository: tuple[Path, str, str],
    fake_codex: Path,
    monkeypatch: MonkeyPatch,
    mode: str,
    message: str,
) -> None:
    repo, base, tree = repository
    _use_small_batches(monkeypatch)
    monkeypatch.setenv("REVIEW_FAKE_BATCH_MODES", json.dumps({"3": mode}))
    with pytest.raises(review_docs.ReviewError, match=message):
        review_docs.review(base, tree, repo=repo)
    records = _records(fake_codex)
    assert len(records) == 6
    _assert_reviewer_cleanup(records)


def test_queued_and_running_batches_share_one_absolute_deadline(
    repository: tuple[Path, str, str], monkeypatch: MonkeyPatch
) -> None:
    repo, base, tree = repository
    workers = review_docs.MAX_PARALLEL_REVIEWS
    batch_count = workers * 2
    _use_small_batches(monkeypatch, file_count=batch_count)
    clock = SimpleNamespace(now=100.0)
    monkeypatch.setattr(
        review_docs, "time", SimpleNamespace(monotonic=lambda: clock.now)
    )
    calls: list[tuple[int, float, float, Path]] = []

    def advance_clock() -> None:
        clock.now += 90.5

    ready = Barrier(workers, action=advance_clock)

    def controlled_run(
        root: Path,
        prompt: str,
        timeout_seconds: float,
        *,
        deadline: float,
        cancelled: Event,
    ) -> None:
        assert timeout_seconds == 180
        assert not cancelled.is_set()
        index = _prompt_evidence(prompt)["batch"]["index"]
        calls.append((index, deadline, clock.now, root))
        # Advance only once all current worker slots are occupied. The second
        # wave starts after elapsed time and must retain the original deadline.
        ready.wait(timeout=10)
        if clock.now >= deadline:
            raise review_docs.ReviewError("Codex documentation review timed out.")
        (root / "verdict.json").write_text(
            json.dumps({"passed": True, "findings": []}), encoding="utf-8"
        )

    monkeypatch.setattr(review_docs, "_run", controlled_run)
    with pytest.raises(review_docs.ReviewError, match="timed out"):
        review_docs.review(base, tree, repo=repo, timeout_seconds=180)
    assert len(calls) == batch_count
    assert {deadline for _, deadline, _, _ in calls} == {280.0}
    assert [started for _, _, started, _ in sorted(calls)] == (
        [100.0] * workers + [190.5] * workers
    )
    assert all(not root.exists() for _, _, _, root in calls)


@pytest.mark.parametrize("cleanup_failure", [False, True])
def test_interrupt_cancels_running_batches_and_cleans_all_reviewer_processes(
    repository: tuple[Path, str, str],
    fake_codex: Path,
    monkeypatch: MonkeyPatch,
    cleanup_failure: bool,
) -> None:
    repo, base, tree = repository
    workers = review_docs.MAX_PARALLEL_REVIEWS
    batch_count = workers * 2
    _use_small_batches(monkeypatch, file_count=batch_count)
    monkeypatch.setenv("REVIEW_FAKE_MODE", "wait")
    interruption = KeyboardInterrupt("review interrupted")

    if cleanup_failure:

        def fail_after_cleanup(*args: Any, **kwargs: Any) -> None:
            leader = args[0]
            assert leader is not None
            _terminate_tree(*args, **kwargs)
            raise RuntimeError(
                f"cleanup verification failed for leader PID {leader.pid}"
            )

        monkeypatch.setattr(review_docs, "_terminate_tree", fail_after_cleanup)

    def interrupt_result(self: Future[Any], timeout: float | None = None) -> Any:
        # Trigger the interrupt only after all slots hold real waiting
        # subprocesses. No guessed scheduling delay is needed.
        deadline = time.monotonic() + 10
        while len(list(fake_codex.with_suffix(".records").glob("*.json"))) < workers:
            if time.monotonic() >= deadline:
                raise AssertionError("Reviewers did not reach the ready barrier")
            time.sleep(0.01)
        raise interruption

    monkeypatch.setattr(Future, "result", interrupt_result)
    with pytest.raises(KeyboardInterrupt) as error:
        review_docs.review(base, tree, repo=repo, timeout_seconds=30)
    assert error.value is interruption
    records = _records(fake_codex)
    assert len(records) == workers
    assert all("ended" not in record for record in records)
    _assert_reviewer_cleanup(records)
    notes = getattr(error.value, "__notes__", [])
    if cleanup_failure:
        assert len(notes) == workers
        for record in records:
            batch = _prompt_evidence(record["prompt"])["batch"]["index"]
            assert any(
                f"Batch {batch}/{batch_count}" in note
                and "RuntimeError: cleanup verification failed" in note
                and f"leader PID {record['pid']}" in note
                for note in notes
            )
    else:
        assert notes == []


def test_batch_cleanup_error_is_reported_even_when_all_verdicts_pass(
    repository: tuple[Path, str, str], fake_codex: Path, monkeypatch: MonkeyPatch
) -> None:
    repo, base, tree = repository
    _use_small_batches(monkeypatch)

    def fail_after_cleanup(*args: Any, **kwargs: Any) -> None:
        _terminate_tree(*args, **kwargs)
        raise RuntimeError("cleanup verification failed")

    monkeypatch.setattr(review_docs, "_terminate_tree", fail_after_cleanup)
    with pytest.raises(review_docs.ReviewError, match="cleanup verification failed"):
        review_docs.review(base, tree, repo=repo)
    records = _records(fake_codex)
    assert len(records) == 6
    _assert_reviewer_cleanup(records)
