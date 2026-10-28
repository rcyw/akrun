from __future__ import annotations

import hashlib
import json
from collections.abc import Callable
from concurrent.futures import ThreadPoolExecutor
from dataclasses import replace
from pathlib import Path
from threading import Event
from typing import Any, cast

import pytest

from axrun.adapters.programbench_official import (
    ProgramBenchOfficialVerifierAdapter,
    _ExecutionStore,
)
from axrun.catalog import resolve_adapters
from axrun.datasets import ProgramBenchOfficialSingleResolver
from axrun.errors import ContractError, InfrastructureError, RecoveryRequiredError
from axrun.models import (
    Artifact,
    ExecutionRef,
    HarnessSpec,
    StagePlan,
    StageResult,
    VerifierSpec,
)
from axrun.runner import EpisodeRunner
from axrun.store import EpisodeStore


def _fixture(case: str = "tty-clock") -> Path:
    return Path(__file__).parents[1] / "fixtures" / "programbench" / f"{case}-1.2.4-official"


def _sha256(path: Path) -> str:
    return hashlib.sha256(path.read_bytes()).hexdigest()


def _artifact(name: str, path: Path) -> Artifact:
    return Artifact(name, str(path), path.stat().st_size, _sha256(path), "application/json")


def _episode(tmp_path: Path, variant: str, case: str = "tty-clock"):
    row = cast(dict[str, Any], json.loads((_fixture(case) / "row.json").read_text()))
    assets = tmp_path / "assets"
    lock = cast(dict[str, Any], json.loads((_fixture(case) / "asset-lock.json").read_text()))
    for branch, value in lock["test_blobs"]["branches"].items():
        path = assets / value["path"]
        path.parent.mkdir(parents=True, exist_ok=True)
        path.write_bytes(f"asset:{branch}".encode())
        value["size_bytes"] = path.stat().st_size
        value["sha256"] = _sha256(path)
    lock_path = tmp_path / "asset-lock.json"
    lock_path.write_text(json.dumps(lock))
    episode = ProgramBenchOfficialSingleResolver().resolve(
        row,
        source_dir=_fixture(case),
        episode_id=f"programbench-official-{variant}",
        inference_environment_id="official-inference",
        verification_environment_id="official-verification",
        verification_image="registry.invalid/evaluator@sha256:" + "a" * 64,
        harness=HarnessSpec("static-candidate", "1"),
        test_assets_dir=assets,
    )
    config = {**episode.verifier.config, "asset_lock_file": str(lock_path)}
    return replace(
        episode, verifier=VerifierSpec("programbench-official-single", "1", config=config)
    )


class OfficialBackend:
    def __init__(
        self, *, variant: str, interrupt_branch_once: bool = False, case: str = "tty-clock"
    ) -> None:
        self.variant = variant
        self.interrupt_branch_once = interrupt_branch_once
        self.interrupted = False
        self.created: list[ExecutionRef] = []
        self.cancelled: list[str] = []
        self.deleted_environments: list[str] = []
        self.plans: dict[str, StagePlan] = {}
        raw = json.loads((_fixture(case) / "tests.json").read_text())
        self.tests = {
            branch: list(value["tests"])
            for branch, value in raw["branches"].items()
            if not value["ignored"]
        }

    def _new(self, plan: StagePlan, on_bound: Callable[[ExecutionRef], None]) -> ExecutionRef:
        execution = ExecutionRef(
            plan.environment_id,
            f"run-{len(self.created) + 1}",
            f"allocation-{len(self.created) + 1}",
        )
        self.created.append(execution)
        self.plans[execution.run_id] = plan
        on_bound(execution)
        return execution

    def execute(
        self,
        plan: StagePlan,
        *,
        artifact_dir: Path,
        on_bound: Callable[[ExecutionRef], None],
        lifecycle=None,
    ) -> StageResult:
        execution = self._new(plan, on_bound)
        if plan.labels["axrun.stage"] == "inference":
            artifact_dir.mkdir(parents=True, exist_ok=True)
            archive = artifact_dir / "workspace.tar"
            archive.write_bytes(b"canonical candidate archive")
            return StageResult(
                execution,
                0,
                "",
                (
                    Artifact(
                        "/outputs/workspace.tar",
                        str(archive),
                        archive.stat().st_size,
                        _sha256(archive),
                        "application/x-tar",
                    ),
                ),
            )
        if self.interrupt_branch_once and not self.interrupted:
            self.interrupted = True
            raise InfrastructureError("simulated caller interruption")
        return self._branch_result(plan, artifact_dir, execution)

    def execute_rootfs(
        self,
        plan: StagePlan,
        *,
        artifact_dir: Path,
        on_bound: Callable[[ExecutionRef], None],
    ) -> tuple[StageResult, str]:
        execution = self._new(plan, on_bound)
        if self.variant == "empty":
            return StageResult(execution, 22, "", ()), ""
        artifact_dir.mkdir(parents=True, exist_ok=True)
        result = artifact_dir / "compile.json"
        if self.variant == "corrupt-compile-result":
            result.write_text("{")
            return (
                StageResult(
                    execution,
                    0,
                    "",
                    (_artifact("/outputs/programbench-compile.json", result),),
                ),
                f"derived-{self.variant}",
            )
        result.write_text(
            json.dumps(
                {
                    "status": "succeeded",
                    "diagnostic_code": "",
                    "executable_sha256": "e" * 64,
                    "executable_mode": 0o755,
                }
            )
        )
        return (
            StageResult(
                execution, 0, "", (_artifact("/outputs/programbench-compile.json", result),)
            ),
            f"derived-{self.variant}",
        )

    def recover(
        self, execution: ExecutionRef, plan: StagePlan, *, artifact_dir: Path
    ) -> StageResult | None:
        return self._branch_result(plan, artifact_dir, execution)

    def recover_rootfs(
        self, execution: ExecutionRef, plan: StagePlan, *, artifact_dir: Path
    ) -> tuple[StageResult, str] | None:
        raise AssertionError("compile recovery is not used by this test")

    def wait(self, execution: ExecutionRef, *, timeout: float | None = None) -> None:
        return None

    def cancel(self, execution: ExecutionRef) -> None:
        if execution.run_id not in self.cancelled:
            self.cancelled.append(execution.run_id)

    def delete_environment(self, environment_id: str) -> None:
        if environment_id not in self.deleted_environments:
            self.deleted_environments.append(environment_id)

    def _branch_result(
        self, plan: StagePlan, artifact_dir: Path, execution: ExecutionRef
    ) -> StageResult:
        if self.variant == "infrastructure-failure":
            return StageResult(execution, 1, "RUNTIME_ERROR", ())
        branch = plan.labels["axrun.programbench.branch"]
        tests = [{"name": name, "status": "passed"} for name in self.tests[branch]]
        if self.variant == "partial" and branch == sorted(self.tests)[0]:
            tests[0]["status"] = "failure"
        if self.variant == "duplicate" and branch == sorted(self.tests)[0]:
            tests = [dict(tests[0], status="failure"), *tests]
        artifact_dir.mkdir(parents=True, exist_ok=True)
        path = artifact_dir / "branch.json"
        if self.variant == "corrupt-branch-result":
            path.write_text("{")
            return StageResult(
                execution,
                0,
                "",
                (_artifact("/outputs/programbench-branch.json", path),),
            )
        path.write_text(
            json.dumps(
                {
                    "schema_version": 1,
                    "branch": branch,
                    "status": (
                        "infrastructure_error"
                        if self.variant == "missing-dependency"
                        else "completed"
                    ),
                    "reason_code": (
                        "evaluator_environment_invalid"
                        if self.variant == "missing-dependency"
                        else ""
                    ),
                    "tests": [] if self.variant == "missing-dependency" else tests,
                }
            )
        )
        return StageResult(
            execution,
            0,
            "",
            (_artifact("/outputs/programbench-branch.json", path),),
        )


@pytest.mark.parametrize(
    ("variant", "verdict", "score", "run_count"),
    (
        ("gold", "passed", 1.0, 8),
        ("duplicate", "passed", 1.0, 8),
        ("empty", "failed", 0.0, 2),
        ("partial", "failed", 280 / 281, 8),
    ),
)
def test_official_multirun_verifier_isolates_compile_and_branches(
    tmp_path: Path,
    variant: str,
    verdict: str,
    score: float,
    run_count: int,
) -> None:
    episode = _episode(tmp_path, variant)
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant=variant)
    store = EpisodeStore(tmp_path / "state")
    result = EpisodeRunner(backend=backend, store=store).run(
        episode,
        inference=selection.inference,
        candidate=selection.candidate,
        verifier=selection.verifier,
    )
    assert result.verdict == verdict
    assert result.score == pytest.approx(score)
    assert result.details["active_test_count"] == 281
    assert result.details["not_run"] == (281 if variant == "empty" else 0)
    assert len(backend.created) == run_count
    if variant != "empty":
        branch_plans = [
            plan
            for plan in backend.plans.values()
            if plan.labels.get("axrun.stage") == "verification-branch"
        ]
        assert len(branch_plans) == 6
        assert all(plan.environment_id == f"derived-{variant}" for plan in branch_plans)
        assert all(plan.env == {"PYTEST_XDIST_AUTO_NUM_WORKERS": "10"} for plan in branch_plans)
        assert all(plan.resources.limit_cpu == "10" for plan in branch_plans)
        assert len({ref.run_id for ref in backend.created}) == run_count
        assert all(plan.network_policy == "deny_all" for plan in branch_plans)
        assert backend.deleted_environments == [f"derived-{variant}"]
        compile_plan = next(
            plan
            for plan in backend.plans.values()
            if plan.labels.get("axrun.stage") == "verification-compile"
        )
        assert compile_plan.env == {"PYTHONPATH": "/opt/axrun"}
        assert compile_plan.network_policy == "deny_all"
        assert not any(item.target.endswith(".whl") for item in compile_plan.inputs)
        assert "--rerun-wheel" not in compile_plan.argv
        remove_index = compile_plan.argv.index("--remove-sha256")
        assert compile_plan.argv[remove_index + 1] == (
            "cd400708bcd6a5b9dd28bd450a211ec4625cde31470057e9d62f66072e297db0"
        )


def test_official_multirun_resume_reuses_the_bound_branch_run(tmp_path: Path) -> None:
    episode = _episode(tmp_path, "gold")
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant="gold", interrupt_branch_once=True)
    store = EpisodeStore(tmp_path / "state")
    runner = EpisodeRunner(backend=backend, store=store)
    with pytest.raises(InfrastructureError, match="simulated caller interruption"):
        runner.run(
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )
    created_before = len(backend.created)
    result = runner.recover(
        episode.episode_id,
        inference=selection.inference,
        candidate=selection.candidate,
        verifier=selection.verifier,
    )
    assert result.verdict == "passed"
    assert len(backend.created) == created_before + 5
    record = json.loads(
        (
            store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
        ).read_text()
    )
    assert record["state"] == "completed"
    assert record["aggregation_state"] == "completed"
    assert record["cleanup_state"] == "completed"
    assert backend.deleted_environments == ["derived-gold"]


def test_evaluator_setup_failure_is_infrastructure_failure_and_seals_diagnostic(tmp_path):
    episode = _episode(tmp_path, "missing-dependency")
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant="missing-dependency")
    store = EpisodeStore(tmp_path / "state")
    with pytest.raises(InfrastructureError, match="evaluator_environment_invalid"):
        EpisodeRunner(backend=backend, store=store).run(
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )
    assert backend.deleted_environments == ["derived-missing-dependency"]
    record = json.loads(
        (
            store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
        ).read_text()
    )
    assert record["state"] == "infrastructure_failed"
    assert record["cleanup_state"] == "completed"
    first = record["branches"][sorted(record["branches"])[0]]
    assert first["reason_code"] == "evaluator_environment_invalid"
    assert Path(first["result_path"]).is_file()
    assert not list((store.root / "verification-details").rglob("programbench.json"))


def test_official_multirun_cancel_cleans_owned_branch_and_environment(tmp_path: Path) -> None:
    episode = _episode(tmp_path, "gold")
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant="gold", interrupt_branch_once=True)
    store = EpisodeStore(tmp_path / "state")
    runner = EpisodeRunner(backend=backend, store=store)
    with pytest.raises(InfrastructureError, match="simulated caller interruption"):
        runner.run(
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )

    with pytest.raises(ContractError, match="required to cancel multi-Run verification"):
        runner.cancel(episode.episode_id)
    assert runner.inspect(episode.episode_id).phase.value == "verification_running"
    assert backend.cancelled == []
    assert backend.deleted_environments == []

    cancelled = runner.cancel(episode.episode_id, verifier=selection.verifier)

    assert cancelled.phase.value == "cancelled"
    assert backend.cancelled == ["run-2", "run-3"]
    assert backend.deleted_environments == ["derived-gold"]
    record = json.loads(
        (
            store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
        ).read_text()
    )
    assert record["state"] == "cancelled"
    assert record["cleanup_state"] == "completed"


@pytest.mark.parametrize("pause_at", ("before_branch_bind", "after_branch_result"))
def test_cancel_during_branch_creation_or_completion_keeps_terminal_state(
    tmp_path: Path, pause_at: str
) -> None:
    class PausedBackend(OfficialBackend):
        def __init__(self) -> None:
            super().__init__(variant="gold")
            self.entered = Event()
            self.resume = Event()

        def _new(self, plan: StagePlan, on_bound: Callable[[ExecutionRef], None]) -> ExecutionRef:
            if (
                pause_at == "before_branch_bind"
                and plan.labels.get("axrun.stage") == "verification-branch"
            ):
                execution = ExecutionRef(
                    plan.environment_id,
                    f"run-{len(self.created) + 1}",
                    f"allocation-{len(self.created) + 1}",
                )
                self.created.append(execution)
                self.plans[execution.run_id] = plan
                self.entered.set()
                assert self.resume.wait(10)
                try:
                    on_bound(execution)
                except BaseException:
                    # The real backend cancels a Run if its bound callback rejects it.
                    self.cancel(execution)
                    raise
                return execution
            return super()._new(plan, on_bound)

        def execute(
            self,
            plan: StagePlan,
            *,
            artifact_dir: Path,
            on_bound: Callable[[ExecutionRef], None],
            lifecycle=None,
        ) -> StageResult:
            result = super().execute(
                plan, artifact_dir=artifact_dir, on_bound=on_bound, lifecycle=lifecycle
            )
            if (
                pause_at == "after_branch_result"
                and plan.labels.get("axrun.stage") == "verification-branch"
            ):
                self.entered.set()
                assert self.resume.wait(10)
            return result

    episode = _episode(tmp_path, f"gold-{pause_at}")
    selection = resolve_adapters(episode)
    backend = PausedBackend()
    store = EpisodeStore(tmp_path / "state")
    runner = EpisodeRunner(backend=backend, store=store)
    with ThreadPoolExecutor(max_workers=1) as pool:
        future = pool.submit(
            runner.run,
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )
        try:
            assert backend.entered.wait(10)
            cancelled = runner.cancel(episode.episode_id, verifier=selection.verifier)
        finally:
            backend.resume.set()
        with pytest.raises(RecoveryRequiredError, match="cancelled"):
            future.result(timeout=10)

    assert cancelled.phase.value == "cancelled"
    assert len(backend.created) == 3
    assert set(backend.cancelled) == {"run-2", "run-3"}
    assert backend.deleted_environments == ["derived-gold"]
    record = json.loads(
        (
            store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
        ).read_text()
    )
    assert record["state"] == "cancelled"
    assert record["cleanup_state"] == "completed"


def test_cancel_before_derived_environment_publication_cleans_late_result(
    tmp_path: Path,
) -> None:
    class PausedRootfsBackend(OfficialBackend):
        def __init__(self) -> None:
            super().__init__(variant="gold")
            self.entered = Event()
            self.resume = Event()

        def execute_rootfs(
            self,
            plan: StagePlan,
            *,
            artifact_dir: Path,
            on_bound: Callable[[ExecutionRef], None],
        ) -> tuple[StageResult, str]:
            result = super().execute_rootfs(plan, artifact_dir=artifact_dir, on_bound=on_bound)
            self.entered.set()
            assert self.resume.wait(10)
            return result

    episode = _episode(tmp_path, "gold-late-environment")
    selection = resolve_adapters(episode)
    backend = PausedRootfsBackend()
    store = EpisodeStore(tmp_path / "state")
    runner = EpisodeRunner(backend=backend, store=store)
    with ThreadPoolExecutor(max_workers=1) as pool:
        future = pool.submit(
            runner.run,
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )
        try:
            assert backend.entered.wait(10)
            cancelled = runner.cancel(episode.episode_id, verifier=selection.verifier)
        finally:
            backend.resume.set()
        with pytest.raises(RecoveryRequiredError, match="cancelled"):
            future.result(timeout=10)

    assert cancelled.phase.value == "cancelled"
    assert len(backend.created) == 2
    assert backend.deleted_environments == ["derived-gold"]
    record = json.loads(
        (
            store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
        ).read_text()
    )
    assert record["state"] == "cancelled"
    assert record["derived_environment_id"] == ""


def test_cancel_before_verifier_record_initialization_prevents_first_run(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    entered = Event()
    resume = Event()
    initialize = _ExecutionStore.initialize

    def paused_initialize(self: _ExecutionStore, **kwargs: Any):
        entered.set()
        assert resume.wait(10)
        return initialize(self, **kwargs)

    monkeypatch.setattr(_ExecutionStore, "initialize", paused_initialize)
    episode = _episode(tmp_path, "gold-before-initialize")
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant="gold")
    store = EpisodeStore(tmp_path / "state")
    runner = EpisodeRunner(backend=backend, store=store)
    with ThreadPoolExecutor(max_workers=1) as pool:
        future = pool.submit(
            runner.run,
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )
        try:
            assert entered.wait(10)
            cancelled = runner.cancel(episode.episode_id, verifier=selection.verifier)
        finally:
            resume.set()
        with pytest.raises(RecoveryRequiredError, match="cancelled"):
            future.result(timeout=10)

    assert cancelled.phase.value == "cancelled"
    assert [item.run_id for item in backend.created] == ["run-1"]
    assert not (
        store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
    ).exists()


def test_cancel_during_branch_planning_prevents_new_branch_run(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    entered = Event()
    resume = Event()
    branch_asset = ProgramBenchOfficialVerifierAdapter._branch_asset

    def paused_branch_asset(
        self: ProgramBenchOfficialVerifierAdapter, episode: Any, branch: str
    ) -> Path:
        if not entered.is_set():
            entered.set()
            assert resume.wait(10)
        return branch_asset(self, episode, branch)

    monkeypatch.setattr(ProgramBenchOfficialVerifierAdapter, "_branch_asset", paused_branch_asset)
    episode = _episode(tmp_path, "gold-branch-planning")
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant="gold")
    store = EpisodeStore(tmp_path / "state")
    runner = EpisodeRunner(backend=backend, store=store)
    with ThreadPoolExecutor(max_workers=1) as pool:
        future = pool.submit(
            runner.run,
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )
        try:
            assert entered.wait(10)
            cancelled = runner.cancel(episode.episode_id, verifier=selection.verifier)
        finally:
            resume.set()
        with pytest.raises(RecoveryRequiredError, match="cancelled"):
            future.result(timeout=10)

    assert cancelled.phase.value == "cancelled"
    assert [item.run_id for item in backend.created] == ["run-1", "run-2"]
    assert backend.deleted_environments == ["derived-gold"]


def test_official_terminal_branch_infrastructure_failure_cleans_derived_environment(
    tmp_path: Path,
) -> None:
    episode = _episode(tmp_path, "infrastructure-failure")
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant="infrastructure-failure")
    store = EpisodeStore(tmp_path / "state")
    with pytest.raises(InfrastructureError, match="RUNTIME_ERROR"):
        EpisodeRunner(backend=backend, store=store).run(
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )
    assert backend.deleted_environments == ["derived-infrastructure-failure"]
    record = json.loads(
        (
            store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
        ).read_text()
    )
    assert record["state"] == "infrastructure_failed"
    assert record["cleanup_state"] == "completed"


@pytest.mark.parametrize(
    ("variant", "message"),
    (
        ("corrupt-compile-result", "compile result is invalid"),
        ("corrupt-branch-result", "branch result is invalid"),
    ),
)
def test_evaluator_result_corruption_is_infrastructure_failure_and_cleans_environment(
    tmp_path: Path, variant: str, message: str
) -> None:
    episode = _episode(tmp_path, variant)
    selection = resolve_adapters(episode)
    backend = OfficialBackend(variant=variant)
    store = EpisodeStore(tmp_path / "state")

    with pytest.raises(InfrastructureError, match=message):
        EpisodeRunner(backend=backend, store=store).run(
            episode,
            inference=selection.inference,
            candidate=selection.candidate,
            verifier=selection.verifier,
        )

    assert backend.deleted_environments == [f"derived-{variant}"]
    record = json.loads(
        (
            store.root / "verifications" / f"{episode.episode_id}-programbench" / "execution.json"
        ).read_text()
    )
    assert record["state"] == "infrastructure_failed"
    assert record["cleanup_state"] == "completed"
