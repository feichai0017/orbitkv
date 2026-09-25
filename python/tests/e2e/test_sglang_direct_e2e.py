"""SGLang restores GPU KV through OrbitKV's CUDA IPC data path."""

from __future__ import annotations

import contextlib
import json
import math
import os
import signal
import subprocess
import sys
import time
from concurrent.futures import ThreadPoolExecutor
from pathlib import Path
from threading import Barrier

import pytest
import requests

from tests.support.cache_manager import evict_dram_after_ssd_writes, find_available_port
from tests.support.metrics import fetch_orbitkv_codec_bytes, fetch_orbitkv_metrics
from tests.support.paths import PYTHON_ROOT

pytestmark = [pytest.mark.e2e, pytest.mark.gpu]


@pytest.mark.parametrize(
    "channel_server",
    [
        pytest.param({"tier": tier, "pool_size": "512mb", "ssd_cache_capacity": "8gb"}, id=tier)
        for tier in ("dram", "ssd")
    ],
    indirect=True,
)
def test_sglang_direct_gpu_cache_recovery(channel_server, request, tmp_path):
    pytest.importorskip("sglang")
    model = request.config.getoption("--model")
    if not Path(model).exists():
        pytest.skip("pass --model with a local model path")

    # A source checkout has no installed entry-point metadata. Publish only the
    # test plugin metadata into PYTHONPATH so every SGLang subprocess discovers it.
    plugin_dir = tmp_path / "orbitkv_source_plugin-0.0.dist-info"
    plugin_dir.mkdir()
    (plugin_dir / "METADATA").write_text("Name: orbitkv-source-plugin\nVersion: 0.0\n")
    (plugin_dir / "entry_points.txt").write_text(
        "[sglang.srt.plugins]\norbitkv = orbitkv.sglang.plugin:register\n"
    )

    cmd = [
        sys.executable,
        "-m",
        "sglang.launch_server",
        "--model-path",
        model,
        "--trust-remote-code",
        "--kv-cache-dtype",
        request.config.getoption("--kv-cache-dtype"),
        "--load-format",
        request.config.getoption("--sglang-load-format"),
        "--host",
        "127.0.0.1",
        "--port",
        "0",
        "--context-length",
        "2048",
        "--max-total-tokens",
        "4096",
        "--max-prefill-tokens",
        "2048",
        "--random-seed",
        "42",
        "--enable-deterministic-inference",
        "--page-size",
        "64",
        "--radix-cache-backend",
        "orbitkv",
        "--enable-unified-cache-external-linker",
        "--enable-cache-report",
    ]
    model_config = json.loads((Path(model) / "config.json").read_text())
    text_config = model_config.get("text_config", model_config)
    if (
        "linear_attention" in (text_config.get("layer_types") or ())
        or (text_config.get("linear_attn_config") or {}).get("kda_layers")
        or text_config.get("use_sconv")
    ):
        cmd += [
            "--max-mamba-cache-size",
            "64",
            "--cuda-graph-max-bs-decode",
            "4",
            "--cuda-graph-max-bs-prefill",
            "512",
        ]
    if text_config.get("use_sconv"):
        # The pinned deterministic Triton backend does not capture Inkling EXTEND.
        cmd += [
            "--cuda-graph-backend-prefill",
            "disabled",
            "--swa-full-tokens-ratio",
            "1",
        ]
    env = dict(os.environ)
    env["PYTHONPATH"] = os.pathsep.join(
        [str(PYTHON_ROOT), str(tmp_path), env.get("PYTHONPATH", "")]
    )
    env["ORBITKV_SGLANG_ENDPOINT"] = f"unix://{channel_server.bootstrap_socket}"
    env["ORBITKV_TRANSFER_BACKEND"] = request.config.getoption("--orbitkv-transfer-backend")
    env["FLASHINFER_WORKSPACE_BASE"] = str(tmp_path / "flashinfer")
    log_path = tmp_path / "sglang-direct.log"

    def start_server(fingerprint: str | None = None) -> tuple[subprocess.Popen, str]:
        port = find_available_port()
        base_url = f"http://127.0.0.1:{port}"
        launch_cmd = list(cmd)
        launch_cmd[launch_cmd.index("--port") + 1] = str(port)
        # Torch's listener starts after worker initialization; avoid an
        # intervening outgoing connection claiming its selected port.
        launch_cmd += ["--nccl-port", str(find_available_port())]
        launch_env = dict(env)
        if fingerprint is not None:
            launch_env["ORBITKV_MODEL_FINGERPRINT"] = fingerprint
        with log_path.open("a") as log_file:
            process = subprocess.Popen(
                launch_cmd,
                env=launch_env,
                stdout=log_file,
                stderr=subprocess.STDOUT,
                start_new_session=True,
            )
        try:
            deadline = time.monotonic() + 600
            while time.monotonic() < deadline:
                if process.poll() is not None:
                    pytest.fail(f"SGLang exited during startup:\n{log_path.read_text()[-8000:]}")
                try:
                    if requests.get(f"{base_url}/health", timeout=2).ok:
                        break
                except requests.RequestException:
                    pass
                time.sleep(1)
            else:
                pytest.fail(f"SGLang startup timed out:\n{log_path.read_text()[-8000:]}")
            return process, base_url
        except BaseException:
            stop_server(process)
            raise

    def stop_server(process: subprocess.Popen) -> None:
        with contextlib.suppress(ProcessLookupError):
            os.killpg(process.pid, signal.SIGTERM)
        try:
            process.wait(timeout=10)
        except subprocess.TimeoutExpired:
            with contextlib.suppress(ProcessLookupError):
                os.killpg(process.pid, signal.SIGKILL)
            process.wait(timeout=5)

    from transformers import AutoTokenizer

    tokenizer = AutoTokenizer.from_pretrained(model, local_files_only=True, trust_remote_code=True)
    fragment = tokenizer.encode("A CUDA IPC cache correctness test for a long context. ")
    # Keep one uncached token after a sealed recurrent checkpoint. Matching a
    # 512-token prompt excludes its last token and cannot use checkpoint 512.
    tokens = (fragment * (513 // len(fragment) + 1))[:513]
    payload = {
        "input_ids": tokens,
        "sampling_params": {"temperature": 0, "max_new_tokens": 8, "ignore_eos": True},
        "return_logprob": True,
    }
    process, base_url = start_server()
    try:
        first = requests.post(f"{base_url}/generate", json=payload, timeout=90)
        first.raise_for_status()
        time.sleep(3)
        before_native = fetch_orbitkv_metrics(channel_server.http_port).get(
            "orbitkv_load_bytes_total", 0
        )
        native = requests.post(f"{base_url}/generate", json=payload, timeout=90)
        native.raise_for_status()
        assert native.json()["meta_info"]["cached_tokens"] >= 512
        assert (
            fetch_orbitkv_metrics(channel_server.http_port).get("orbitkv_load_bytes_total", 0)
            == before_native
        )
        flushed = requests.post(f"{base_url}/flush_cache?timeout=30", timeout=40)
        flushed.raise_for_status()
        second = requests.post(f"{base_url}/generate", json=payload, timeout=90)
        second.raise_for_status()
        assert second.json()["meta_info"]["cached_tokens"] >= 64, (
            second.json(),
            fetch_orbitkv_metrics(channel_server.http_port),
            channel_server.read_logs()[-8000:],
        )
    finally:
        stop_server(process)

    # Keep the Cache Manager alive while SGLang's HBM prefix tree disappears.
    if channel_server.ssd_cache_path is not None:
        evict_dram_after_ssd_writes(channel_server.http_port)
    before_restart = fetch_orbitkv_metrics(channel_server.http_port)
    process, base_url = start_server()
    try:
        # One request can restore the shared prefix while the others still have
        # pending queries. Their new HBM hits must retire that obsolete interest.
        arrivals = Barrier(4)

        def restore(_):
            arrivals.wait(timeout=10)
            response = requests.post(f"{base_url}/generate", json=payload, timeout=90)
            response.raise_for_status()
            return response

        with ThreadPoolExecutor(max_workers=4) as executor:
            restored = list(executor.map(restore, range(4)))
        restored_tokens = [response.json()["meta_info"]["cached_tokens"] for response in restored]
        assert all(tokens >= 512 for tokens in restored_tokens), (
            restored_tokens,
            {
                name: value
                for name, value in fetch_orbitkv_metrics(channel_server.http_port).items()
                if name.startswith(("orbitkv_ssd_", "orbitkv_load_", "orbitkv_query_"))
            },
            channel_server.read_logs()[-8000:],
        )
        after_restart_load = fetch_orbitkv_metrics(channel_server.http_port).get(
            "orbitkv_load_bytes_total", 0
        )
        assert after_restart_load > before_restart.get("orbitkv_load_bytes_total", 0), (
            "Cache Manager did not restore GPU KV"
        )
        if channel_server.ssd_cache_path is not None:
            compression = request.config.getoption("--storage-codec") != "none"
            if channel_server.ssd_backend == "cufile":
                assert (
                    fetch_orbitkv_metrics(channel_server.http_port).get(
                        "orbitkv_ssd_cufile_write_bytes_total", 0
                    )
                    > 0
                )
            read_path = channel_server.ssd_read_path or channel_server.ssd_backend
            read_metrics = {
                "uring": ("orbitkv_ssd_prefetch_bytes_total",),
                "cufile": ("orbitkv_ssd_cufile_read_bytes_total",),
                "auto": ("orbitkv_ssd_prefetch_bytes_total", "orbitkv_ssd_cufile_read_bytes_total"),
            }[read_path]
            recovered = fetch_orbitkv_metrics(channel_server.http_port)
            if read_path == "cufile":
                assert recovered.get("orbitkv_ssd_prefetch_bytes_total", 0) == before_restart.get(
                    "orbitkv_ssd_prefetch_bytes_total", 0
                ), "cuFile recovery bounced through host SSD prefetch"
            elif read_path == "uring":
                assert recovered.get(
                    "orbitkv_ssd_cufile_read_bytes_total", 0
                ) == before_restart.get("orbitkv_ssd_cufile_read_bytes_total", 0), (
                    "io_uring recovery unexpectedly used cuFile reads"
                )
            if compression:
                assert recovered.get("orbitkv_storage_codec_duration_seconds_count", 0) > 0
                assert recovered.get("orbitkv_storage_codec_decode_failures_total", 0) == 0
                encoded = fetch_orbitkv_codec_bytes(channel_server.http_port)
                print(f"Encoded slot bytes: {encoded}")
                if request.config.getoption("--kv-cache-dtype") == "auto":
                    assert encoded["logical"] > 0, "no KV segments were encoded"
                    limit = 0.875 if request.config.getoption("--storage-codec") == "ans" else 0.55
                    assert encoded["stored"] <= encoded["logical"] * limit
            assert (
                sum(recovered.get(key, 0) - before_restart.get(key, 0) for key in read_metrics) > 0
            )
    finally:
        stop_server(process)

    # A changed model identity must miss even with identical page hashes and the
    # same model, sampling seed, and Cache Manager process.
    process, base_url = start_server(fingerprint="9" * 64)
    try:
        cold = requests.post(f"{base_url}/generate", json=payload, timeout=90)
        cold.raise_for_status()
        assert cold.json()["meta_info"]["cached_tokens"] == 0
        # Cold and prefix-reuse execution can differ numerically, even in native
        # SGLang. Compare the same computation shape, not two different baselines.
        for reference, responses in ((cold, (first,)), (native, (second, *restored))):
            expected_probs = [
                item[0] for item in reference.json()["meta_info"]["output_token_logprobs"]
            ]
            assert len(expected_probs) == 8 and all(map(math.isfinite, expected_probs))
            for response in responses:
                assert response.json()["text"] == reference.json()["text"]
                assert response.json()["output_ids"] == reference.json()["output_ids"]
                probabilities = [
                    item[0] for item in response.json()["meta_info"]["output_token_logprobs"]
                ]
                assert probabilities == pytest.approx(expected_probs, abs=0.05)
        registrations = [
            line
            for line in log_path.read_text().splitlines()
            if "OrbitKV GPU linker registered" in line
        ]
        assert len(registrations) >= 3
        assert all(
            f"transfer backend {env['ORBITKV_TRANSFER_BACKEND']}" in line for line in registrations
        )
    finally:
        stop_server(process)
