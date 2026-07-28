# SPDX-License-Identifier: Apache-2.0

from __future__ import annotations

import importlib.util
import json
import shutil
import sys
from pathlib import Path
from types import SimpleNamespace

import pytest

REPO_ROOT = Path(__file__).resolve().parents[3]
RUNTIME_SCRIPT = REPO_ROOT / ".github/scripts/tts_mps_runtime.py"
OVERLAP_SCRIPT = REPO_ROOT / ".github/scripts/tts_mps_overlap.py"


def _load(path: Path, name: str):
    assert path.is_file(), f"{path.name} is missing"
    spec = importlib.util.spec_from_file_location(name, path)
    assert spec is not None and spec.loader is not None
    module = importlib.util.module_from_spec(spec)
    sys.modules[name] = module
    spec.loader.exec_module(module)
    return module


def test_launch_contract_is_one_gpu_dp2_without_weight_sharing(tmp_path: Path) -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime")
    config = tmp_path / "config.yaml"
    config.write_text("config_cls: HiggsTtsPipelineConfig\n", encoding="utf-8")
    launcher = tmp_path / "examples/mps_dp/launch.sh"
    launcher.parent.mkdir(parents=True)
    launcher.write_text("#!/usr/bin/env bash\n", encoding="utf-8")

    spec = runtime.MpsLaunchSpec(
        repository_root=tmp_path,
        output_dir=tmp_path / "output",
        state_root=tmp_path / "state",
        run_id="run-unit",
        config_path=config,
        gpu_id=0,
        base_port=8801,
        core_blocks=("0-3", "4-7"),
        python_bin="python",
    )
    assert spec.environment["N"] == "2"
    assert spec.environment["GPU_ID"] == "0"
    assert spec.environment["WEIGHT_SHARE"] == "0"
    assert "SGLANG_OMNI_WEIGHT_SHARE" not in spec.environment
    assert spec.worker_urls == (
        "http://127.0.0.1:8801",
        "http://127.0.0.1:8802",
    )


def test_stale_launcher_state_is_archived_and_reconciled_before_launch(
    monkeypatch: pytest.MonkeyPatch,
    tmp_path: Path,
) -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_stale_reconcile")
    config = tmp_path / "config.yaml"
    config.write_text("config_cls: HiggsTtsPipelineConfig\n", encoding="utf-8")
    launcher = tmp_path / "examples/mps_dp/launch.sh"
    launcher.parent.mkdir(parents=True)
    launcher.write_text("#!/usr/bin/env bash\n", encoding="utf-8")
    spec = runtime.MpsLaunchSpec(
        repository_root=tmp_path,
        output_dir=tmp_path / "output",
        state_root=tmp_path / "state",
        run_id="run-current",
        config_path=config,
        gpu_id=0,
        base_port=8801,
        core_blocks=("0-3", "4-7"),
        python_bin="python",
    )
    stale = spec.state_root / "gpu-0" / "run-stale"
    stale.mkdir(parents=True)
    (stale / "mps_ctl.err").write_text("retained\n", encoding="utf-8")
    commands: list[tuple[str, ...]] = []

    def fake_run(command, **_kwargs):
        commands.append(tuple(command))
        shutil.rmtree(stale)
        return SimpleNamespace(returncode=0)

    monkeypatch.setattr(runtime.subprocess, "run", fake_run)
    recovered = runtime.reconcile_stale_launcher_states(spec)

    assert recovered is None
    assert commands == [
        (
            "bash",
            str(launcher),
            "down",
            "run-stale",
        )
    ]
    assert not stale.exists()
    assert (
        spec.output_dir
        / "recovered-stale-launcher-state"
        / "run-stale"
        / "raw"
        / "mps_ctl.err"
    ).read_text(encoding="utf-8") == "retained\n"


def test_launcher_state_fails_closed_on_shared_weights_or_unequal_kv(
    tmp_path: Path,
) -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_state")
    state = tmp_path / "run-unit"
    logs = state / "logs"
    logs.mkdir(parents=True)
    manifest = {
        "run_id": "run-unit",
        "gpu_id": "0",
        "gpu_uuid": "GPU-test",
        "numa_node": "0",
        "config": "/tmp/config.yaml",
        "n": "2",
        "base_port": "8801",
        "core_blocks": "0-3 4-7",
        "max_total_tokens": "30000",
        "weight_share": "1",
    }
    (state / "manifest").write_text(
        "".join(f"{key}={value}\n" for key, value in manifest.items()),
        encoding="utf-8",
    )
    (state / "replicas.tsv").write_text(
        "0\t11\t11\t8801\tlogs/replica_0.log\t1\n"
        "1\t22\t22\t8802\tlogs/replica_1.log\t2\n",
        encoding="utf-8",
    )
    (logs / "replica_0.log").write_text("KV Pool is allocated. #tokens: 30000\n")
    (logs / "replica_1.log").write_text("KV Pool is allocated. #tokens: 20000\n")
    (state / "mps_attach.txt").write_text(
        "replica 0 (port 8801): attached clients: 11\n"
        "replica 1 (port 8802): attached clients: 22\n"
        "RESULT: PASS\n",
        encoding="utf-8",
    )

    with pytest.raises(ValueError, match="independent-weight DP2"):
        runtime.read_launcher_state(state)

    text = (
        (state / "manifest")
        .read_text(encoding="utf-8")
        .replace("weight_share=1", "weight_share=0")
    )
    (state / "manifest").write_text(text, encoding="utf-8")
    with pytest.raises(ValueError, match="equal resolved KV"):
        runtime.read_launcher_state(state)


def test_overlap_requires_repeated_server_monotonic_intervals() -> None:
    overlap = _load(OVERLAP_SCRIPT, "tts_mps_overlap")
    events = []
    for replica, intervals in {
        0: [(100, 500), (600, 1000)],
        1: [(200, 550), (700, 1100)],
    }.items():
        for index, (start, end) in enumerate(intervals):
            request_id = f"r{replica}-{index}"
            events.extend(
                [
                    {
                        "run_id": "run-unit",
                        "replica_id": replica,
                        "request_id": request_id,
                        "event": "model_path_start",
                        "clock": "CLOCK_MONOTONIC",
                        "monotonic_ns": start,
                        "host_boot_id": "boot",
                    },
                    {
                        "run_id": "run-unit",
                        "replica_id": replica,
                        "request_id": request_id,
                        "event": "model_path_end",
                        "clock": "CLOCK_MONOTONIC",
                        "monotonic_ns": end,
                        "host_boot_id": "boot",
                        "status": "success",
                    },
                ]
            )
    verdict = overlap.build_overlap_verdict(
        events,
        expected_run_id="run-unit",
        min_successes_per_replica=2,
        min_matched_overlap_count=2,
        measurement_uncertainty_ns=10,
    )
    assert verdict["matched_overlap_count"] == 2
    assert verdict["aggregate_overlap_ns"] == 600

    with pytest.raises(ValueError, match="at least two"):
        overlap.build_overlap_verdict(
            events[:2],
            expected_run_id="run-unit",
            min_successes_per_replica=2,
            min_matched_overlap_count=2,
            measurement_uncertainty_ns=10,
        )
    with pytest.raises(ValueError, match="expected run"):
        overlap.build_overlap_verdict(
            events,
            expected_run_id="run-other",
            min_successes_per_replica=2,
            min_matched_overlap_count=2,
            measurement_uncertainty_ns=10,
        )


def test_atomic_summary_validation_rejects_dirty_or_partial_evidence(
    tmp_path: Path,
) -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_summary")
    summary = runtime.new_summary(
        exact_sha="a" * 40,
        run_id="run-unit",
        run_attempt="1",
        selected_model="higgs",
    )
    path = tmp_path / "tts_mps_summary.json"
    runtime.atomic_write_json(path, summary)
    loaded = json.loads(path.read_text(encoding="utf-8"))
    with pytest.raises(ValueError, match="incomplete"):
        runtime.validate_final_summary(loaded)

    loaded["runtime"] = {"status": "pass"}
    loaded["correctness"] = {"status": "pass"}
    loaded["cleanup"] = {"status": "dirty"}
    with pytest.raises(ValueError, match="cleanup"):
        runtime.validate_final_summary(loaded)


def test_scheduler_mps_activity_is_monotonic_and_default_off(
    monkeypatch: pytest.MonkeyPatch,
    tmp_path: Path,
) -> None:
    from sglang_omni.profiler import event_recorder

    recorder = event_recorder.get_recorder()
    recorder.stop()
    event_recorder.emit_mps_model_path_start("request-off")
    assert recorder.is_active() is False

    path = recorder.start("run-unit", str(tmp_path), "tts_engine")
    monkeypatch.setattr(event_recorder.time, "monotonic_ns", lambda: 123456)
    monkeypatch.setattr(event_recorder, "_read_host_boot_id", lambda: "boot-test")
    event_recorder.emit_mps_model_path_start("request-on")
    event_recorder.emit_mps_model_path_end("request-on", status="success")
    recorder.stop()
    emitted = [
        json.loads(line) for line in Path(path).read_text(encoding="utf-8").splitlines()
    ]
    assert [item["event_name"] for item in emitted] == [
        "mps_model_path_start",
        "mps_model_path_end",
    ]
    assert all(item["metadata"]["monotonic_ns"] == 123456 for item in emitted)
    assert all(item["metadata"]["clock"] == "CLOCK_MONOTONIC" for item in emitted)
    assert all(item["metadata"]["host_boot_id"] == "boot-test" for item in emitted)
    assert emitted[-1]["metadata"]["status"] == "success"


def test_mps_activity_preserves_the_profiler_wall_clock_domain(
    monkeypatch: pytest.MonkeyPatch,
    tmp_path: Path,
) -> None:
    from sglang_omni.profiler import event_recorder
    from sglang_omni.profiler.views import reconstruct_timelines

    recorder = event_recorder.get_recorder()
    recorder.stop()
    path = recorder.start("run-clock-domain", str(tmp_path), "tts_engine")
    monkeypatch.setattr(event_recorder.time, "time_ns", lambda: 2_000_000_000)
    monkeypatch.setattr(event_recorder.time, "monotonic_ns", lambda: 123456)
    event_recorder.emit(
        request_id="request-clock-domain",
        stage="tts_engine",
        event_name="request_started",
    )
    event_recorder.emit_mps_model_path_start("request-clock-domain")
    event_recorder.emit_mps_model_path_end(
        "request-clock-domain",
        status="success",
    )
    event_recorder.emit(
        request_id="request-clock-domain",
        stage="tts_engine",
        event_name="request_finished",
    )
    recorder.stop()

    emitted = [
        json.loads(line) for line in Path(path).read_text(encoding="utf-8").splitlines()
    ]
    mps_events = [
        item for item in emitted if item["event_name"].startswith("mps_model_path_")
    ]
    assert all(item["timestamp_ns"] == 2_000_000_000 for item in emitted)
    assert all(item["metadata"]["monotonic_ns"] == 123456 for item in mps_events)
    assert reconstruct_timelines(path)["request-clock-domain"].total_ms == 0.0


def test_profile_start_waits_for_each_engine_process_recorder(
    monkeypatch: pytest.MonkeyPatch,
    tmp_path: Path,
) -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_profile_start")
    snapshot = SimpleNamespace(
        state_dir=tmp_path,
        replicas=(SimpleNamespace(index=0), SimpleNamespace(index=1)),
    )
    first = tmp_path / "activity-0"
    first.mkdir()
    (first / "events_coordinator_9.jsonl").touch()
    (first / "events_preprocessing_10.jsonl").touch()

    def create_second(_seconds: float) -> None:
        second = tmp_path / "activity-1"
        second.mkdir(exist_ok=True)
        (second / "events_coordinator_19.jsonl").touch()
        (second / "events_preprocessing_20.jsonl").touch()

    monkeypatch.setattr(runtime.time, "sleep", create_second)
    runtime.wait_for_profile_activity_files(
        snapshot,
        timeout_s=1.0,
        poll_interval_s=0.0,
    )


def test_activity_reader_waits_for_all_terminal_events(
    monkeypatch: pytest.MonkeyPatch,
    tmp_path: Path,
) -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_profile_stop")
    snapshot = SimpleNamespace(
        state_dir=tmp_path,
        replicas=(SimpleNamespace(index=0), SimpleNamespace(index=1)),
    )
    for index in (0, 1):
        directory = tmp_path / f"activity-{index}"
        directory.mkdir()
        (directory / f"events_tts_engine_{index}.jsonl").touch()

    def flush_events(_seconds: float) -> None:
        for index in (0, 1):
            event = {
                "run_id": "run-unit",
                "request_id": f"request-{index}",
                "event_name": "mps_model_path_end",
                "metadata": {
                    "clock": "CLOCK_MONOTONIC",
                    "monotonic_ns": 100 + index,
                    "host_boot_id": "boot-unit",
                    "status": "success",
                },
            }
            path = tmp_path / f"activity-{index}" / f"events_tts_engine_{index}.jsonl"
            path.write_text(json.dumps(event) + "\n", encoding="utf-8")

    monkeypatch.setattr(runtime.time, "sleep", flush_events)
    events = runtime.read_model_path_activity(
        snapshot,
        min_terminal_events=2,
        timeout_s=1.0,
        poll_interval_s=0.0,
    )

    assert len(events) == 2
    assert all(item["event"] == "model_path_end" for item in events)


def test_external_router_config_targets_only_the_two_mps_workers() -> None:
    from tests.test_model import omni_router_utils

    command = omni_router_utils.build_external_router_command(
        python_bin="python",
        router_port=9000,
        worker_urls=["http://127.0.0.1:8801", "http://127.0.0.1:8802"],
        model_name="model-under-test",
    )
    assert command == [
        "python",
        "-m",
        "sglang_omni_router.serve",
        "--host",
        "0.0.0.0",
        "--port",
        "9000",
        "--worker-urls",
        "http://127.0.0.1:8801",
        "http://127.0.0.1:8802",
        "--model",
        "model-under-test",
        "--policy",
        "least_request",
        "--health-success-threshold",
        "1",
        "--health-failure-threshold",
        "2",
        "--health-check-interval-secs",
        "2",
        "--log-level",
        "info",
    ]


def test_model_specific_mps_floor_catches_only_obvious_regressions() -> None:
    from benchmarks.benchmarker.data import RequestResult
    from benchmarks.metrics.performance import compute_speed_metrics

    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_performance")
    healthy = compute_speed_metrics(
        [
            RequestResult(
                is_success=True,
                latency_s=1.5,
                audio_duration_s=3.75,
                rtf=0.4,
                completion_tokens=100,
                engine_time_s=1.0,
            )
            for _ in range(12)
        ],
        wall_clock_s=1.0,
    )
    verdict = runtime.check_mps_performance(
        model="higgs",
        concurrency=16,
        summary=healthy,
    )
    assert verdict["status"] == "pass"
    assert verdict["provenance"]["temporary"] is True

    regressed = {**healthy, "throughput_qps": 2.0}
    verdict = runtime.check_mps_performance(
        model="higgs",
        concurrency=16,
        summary=regressed,
    )
    assert verdict["status"] == "fail"
    assert verdict["failed_checks"] == ["throughput_qps"]
    assert verdict["checks"]["throughput_qps"]["observed"] == 2.0


def test_gpu_client_delta_flags_only_clients_created_by_the_mps_stage() -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_gpu")
    baseline = [
        {"gpu_uuid": "GPU-0", "pid": 10, "process_name": "foreign"},
    ]
    post = [
        {"gpu_uuid": "GPU-0", "pid": 10, "process_name": "foreign"},
        {"gpu_uuid": "GPU-0", "pid": 20, "process_name": "replica"},
        {"gpu_uuid": "GPU-1", "pid": 30, "process_name": "other-gpu"},
    ]
    assert runtime.new_gpu_clients(
        baseline,
        post,
        gpu_uuid="GPU-0",
    ) == [{"gpu_uuid": "GPU-0", "pid": 20, "process_name": "replica"}]
    with pytest.raises(RuntimeError, match="visibility"):
        runtime.verify_active_gpu_visibility(
            baseline,
            baseline,
            gpu_uuid="GPU-0",
        )
    assert runtime.verify_active_gpu_visibility(
        baseline,
        post,
        gpu_uuid="GPU-0",
    ) == [{"gpu_uuid": "GPU-0", "pid": 20, "process_name": "replica"}]


def test_dirty_cleanup_verdict_is_not_treated_as_success() -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_cleanup")
    dirty = {
        "status": "dirty",
        "checks": {"tracked_processes_exited": False},
    }
    with pytest.raises(RuntimeError, match="dirty"):
        runtime.require_clean_cleanup(dirty)
    runtime.require_clean_cleanup({"status": "pass", "checks": {}})
    merged = runtime.record_cleanup_recovery(
        dirty,
        {"status": "pass", "checks": {"tracked_processes_exited": True}},
    )
    assert merged["status"] == "dirty"
    assert merged["recovery_attempt"]["status"] == "pass"


def test_gpu_client_cleanup_waits_for_nvml_to_settle(
    monkeypatch: pytest.MonkeyPatch,
) -> None:
    runtime = _load(RUNTIME_SCRIPT, "tts_mps_runtime_settle")
    baseline = [{"gpu_uuid": "GPU-0", "pid": 10, "process_name": "foreign"}]
    lingering = [
        *baseline,
        {"gpu_uuid": "GPU-0", "pid": 20, "process_name": "mps-server"},
    ]
    snapshots = iter([lingering, baseline])
    monkeypatch.setattr(runtime, "capture_gpu_clients", lambda: next(snapshots))
    monkeypatch.setattr(runtime.time, "sleep", lambda _: None)

    assert (
        runtime.wait_for_gpu_clients_to_settle(
            baseline,
            gpu_uuid="GPU-0",
            timeout_s=1.0,
            poll_interval_s=0.0,
        )
        == baseline
    )
