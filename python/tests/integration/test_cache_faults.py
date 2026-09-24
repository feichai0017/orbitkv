"""Deterministic faults against the real Manager, CUDA mappings and SSD I/O.

Build orbitkv-server with test-hooks and set ORBITKV_FAULT_TESTS=1 explicitly.
The barriers are absent from normal release binaries.
"""

from __future__ import annotations

import os
import time
from concurrent.futures import ThreadPoolExecutor
from pathlib import Path

import pytest
import requests

from tests.support.cache_manager import (
    CacheManagerProcess,
    ClientContext,
    find_available_port,
)
from tests.support.metrics import fetch_orbitkv_metrics

pytestmark = [
    pytest.mark.integration,
    pytest.mark.gpu,
    pytest.mark.skipif(
        os.environ.get("ORBITKV_FAULT_TESTS") != "1", reason="requires test-hooks Manager"
    ),
]


def until(predicate, timeout=10):
    deadline = time.monotonic() + timeout
    while not (result := predicate()):
        assert time.monotonic() < deadline, "fault gate timed out"
        time.sleep(0.01)
    return result


@pytest.fixture
def fault_cache(tmp_path, monkeypatch, request):
    import torch

    from orbitkv import CacheManagerClient

    configuration = request.param if isinstance(getattr(request, "param", None), dict) else {}
    backend = configuration.get("ssd_backend", "uring")
    if backend == "cufile" and request.config.getoption("--ssd-backend") != "cufile":
        pytest.skip("pass --ssd-backend cufile for GPU storage qualification")
    monkeypatch.setenv("ORBITKV_TEST_FAULTS", str(tmp_path))
    server = CacheManagerProcess(
        find_available_port(),
        http_port=find_available_port(),
        ssd_cache_path=tmp_path / "ssd",
        ssd_backend=backend,
        extra_args=request.param
        if isinstance(getattr(request, "param", None), tuple)
        else configuration.get("extra_args", ()),
        channel_service=f"orbitkv/fault/{tmp_path.name}"
        if getattr(request, "param", None)
        else None,
    )
    assert server.start(), server.read_logs()
    client = CacheManagerClient(server.bootstrap_socket, timeout_ms=100)
    ctx = ClientContext(
        client=client,
        instance_id="fault-instance",
        namespace="fault-model",
        device_id=0,
        num_blocks=configuration.get("num_blocks", 4),
        block_size=configuration.get("block_size", 16),
        num_layers=configuration.get("num_layers", 1),
        dtype=getattr(torch, configuration.get("dtype", "bfloat16")),
    )
    ctx.register_kv_caches()
    try:
        yield server, client, ctx, tmp_path
    finally:
        for pause in tmp_path.glob("*.pause"):
            pause.unlink(missing_ok=True)
        client.close()
        server.stop()


def arm(directory: Path, name: str):
    (directory / f"{name}.reached").unlink(missing_ok=True)
    (directory / f"{name}.pause").touch()


def reached(directory, name):
    until(lambda: (directory / f"{name}.reached").exists())


def publish(client, ctx, hashes):
    return client.save(
        ctx.instance_id, 0, 0, 0, [(ctx._layer_names[0], list(range(len(hashes))), hashes)]
    )


def query(client, ctx, hashes, rid):
    from orbitkv import BlockHashes, QueryReady

    batch = BlockHashes(hashes)

    def poll():
        result = client.query_prefetch(ctx.instance_id, batch, rid)
        return result if isinstance(result, QueryReady) else None

    return until(poll)


def drain_ssd(server):
    def drained():
        stats = fetch_orbitkv_metrics(server.http_port)
        return stats.get("orbitkv_ssd_write_bytes_total", 0) > 0 and not any(
            stats.get(name, 0)
            for name in (
                "orbitkv_ssd_write_inflight",
                "orbitkv_ssd_write_queue_pending",
                "orbitkv_inflight_bytes",
            )
        )

    until(drained)
    response = requests.post(f"http://127.0.0.1:{server.http_port}/cache/memory/cleanup", timeout=5)
    response.raise_for_status()


@pytest.mark.parametrize(
    "fault_cache",
    [
        {"ssd_backend": backend, "block_size": 64, "extra_args": ("--storage-codec", "fp8")}
        for backend in ("uring", "cufile")
    ],
    indirect=True,
)
def test_encoded_ssd_mixed_prefix_cancellation_and_corruption(fault_cache):
    import torch

    from orbitkv import BlockHashes, QueryLoading

    server, client, ctx, directory = fault_cache
    tensor = ctx.get_kv_cache()
    tensor[:, 0:1].fill_(1.25)
    tensor[:, 1:2].view(torch.uint8).random_(0, 256)
    expected = tensor[:, 0:2].view(torch.uint8).cpu().clone()
    torch.cuda.synchronize()
    hashes = [b"compressed", b"raw"]
    assert publish(client, ctx, hashes)[0]
    drain_ssd(server)
    stats = fetch_orbitkv_metrics(server.http_port)
    assert stats["orbitkv_storage_codec_bytes_total"] > 0
    assert stats["orbitkv_ssd_write_bytes_total"] < expected.numel()

    arm(directory, "ssd")
    pending = client.query_prefetch(ctx.instance_id, BlockHashes(hashes), "canceled-codec")
    assert isinstance(pending, QueryLoading)
    reached(directory, "ssd")
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_prefetch_inflight"] > 0
    client.cancel_query(ctx.instance_id, "canceled-codec")
    # Canceling demand must not release pinned encoded pages owned by submitted I/O.
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_prefetch_inflight"] > 0
    (directory / "ssd.pause").unlink()
    until(lambda: fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_prefetch_inflight"] == 0)
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_storage_codec_reserved_bytes"] == 0
    ready = query(client, ctx, hashes, "mixed-codec")
    assert ready.num_hit_blocks == 2
    restore = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[2, 3]])]
    )
    assert client.wait_restore(restore, timeout=10).success
    assert torch.equal(tensor[:, 2:4].view(torch.uint8).cpu(), expected)
    drain_ssd(server)

    # Damage the ephemeral file after all I/O drained. No corrupted block may
    # enter the cache, including when FP8 can still decode the damaged stream.
    with Path(server.ssd_cache_path).open("r+b", buffering=0) as stream:
        stream.write(bytes(int(stats["orbitkv_ssd_write_bytes_total"])))
    missing = query(client, ctx, [hashes[0]], "corrupt-codec")
    assert missing.num_hit_blocks == 0
    stats = fetch_orbitkv_metrics(server.http_port)
    assert stats["orbitkv_storage_codec_decode_failures_total"] > 0
    assert stats["orbitkv_storage_codec_reserved_bytes"] == 0
    # Recomputing the same key must replace the damaged disk generation.
    assert publish(client, ctx, [hashes[0]])[0]
    drain_ssd(server)
    repaired = query(client, ctx, [hashes[0]], "repaired-codec")
    assert repaired.num_hit_blocks == 1
    tensor[:, 2:3].zero_()
    torch.cuda.synchronize()
    restore = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(repaired.lease, [[2]])]
    )
    assert client.wait_restore(restore, timeout=10).success
    assert torch.equal(tensor[:, 2:3].view(torch.uint8).cpu(), expected[:, 0:1])


@pytest.mark.parametrize(
    "fault_cache",
    [
        {
            "dtype": dtype,
            "block_size": 64,
            "extra_args": ("--storage-codec", "fp8", "--storage-codec-budget", budget),
        }
        for dtype in ("bfloat16", "float16")
        for budget in ("64mb", "4kb")
    ],
    indirect=True,
)
def test_fp8_storage_matches_torch_scalar_cast_and_isolates_exact_registration(fault_cache):
    import torch

    from orbitkv.client.gpu import serialize_gpu_buffer

    server, client, ctx, _ = fault_cache
    tensor = ctx.get_kv_cache()
    values = torch.arange(65536, dtype=torch.int32).to(torch.uint16).view(tensor.dtype).float()
    values = values[torch.isfinite(values) & (values.abs() <= 448)].to(tensor.dtype).cuda()
    count = tensor[:, 0:1].numel()
    tensor[:, 0:1] = values.repeat((count + values.numel() - 1) // values.numel())[
        :count
    ].reshape_as(tensor[:, 0:1])
    original = tensor[:, 0:1].clone()
    expected = original.to(torch.float8_e4m3fn).to(original.dtype)
    assert torch.any(original != expected)
    torch.cuda.synchronize()
    hashes = [b"every-finite-scalar"]
    assert publish(client, ctx, hashes)[0]
    drain_ssd(server)
    stats = fetch_orbitkv_metrics(server.http_port)
    assert stats["orbitkv_ssd_write_bytes_total"] == original.numel()
    ready = query(client, ctx, hashes, "quantized")
    assert ready.num_hit_blocks == 1
    restore = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[2]])]
    )
    assert client.wait_restore(restore, timeout=10).success
    assert torch.equal(tensor[:, 2:3].view(torch.uint8), expected.view(torch.uint8))

    # The same namespace/hash with exact storage policy must not adopt lossy data.
    name = "exact-instance"
    stride = tensor.stride()
    ok, message = client.register_context_batch(
        name,
        ctx.namespace,
        0,
        0,
        1,
        1,
        0,
        ctx._layer_names,
        [serialize_gpu_buffer(tensor)],
        [ctx.num_blocks],
        [stride[1] * tensor.element_size()],
        [stride[0] * tensor.element_size()],
        [2],
        "direct",
        False,
        layer_formats=["exact"],
    )
    assert ok, message
    from orbitkv import BlockHashes, QueryReady

    result = client.query_prefetch(name, BlockHashes(hashes), "exact")
    assert isinstance(result, QueryReady) and result.num_hit_blocks == 0
    client.unregister_context(name)


@pytest.mark.parametrize(
    "fault_cache",
    [
        {"num_layers": 6, "block_size": 64, "extra_args": ("--storage-codec", codec)}
        for codec in ("ans", "turboquant-4", "turboquant-3")
    ],
    indirect=True,
)
def test_gpu_codecs_restore_after_registration_and_ssd_eviction(fault_cache, request):
    import torch

    from tests.support.metrics import fetch_orbitkv_codec_bytes

    server, client, ctx, _ = fault_cache
    codec = request.node.callspec.params["fault_cache"]["extra_args"][-1]
    originals = [tensor[:, :1].clone() for tensor in ctx.gpu_kv_caches]
    hashes = [b"gpu-codec-roundtrip"]
    assert client.save(
        ctx.instance_id, 0, 0, 0, [(name, [0], hashes) for name in ctx._layer_names]
    )[0]
    drain_ssd(server)
    encoded = fetch_orbitkv_codec_bytes(server.http_port)
    assert encoded["logical"] > encoded["stored"] > 0
    client.unregister_context(ctx.instance_id)
    ctx._registered = False
    ctx.register_kv_caches()
    for tensor in ctx.gpu_kv_caches:
        tensor[:, 2:3].fill_(-123)
    torch.cuda.synchronize()
    ready = query(client, ctx, hashes, "restart-codec")
    assert ready.num_hit_blocks == 1
    before_restore = fetch_orbitkv_metrics(server.http_port)
    restore = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[2]])]
    )
    assert client.wait_restore(restore, timeout=10).success
    after_restore = fetch_orbitkv_metrics(server.http_port)
    assert after_restore["orbitkv_load_bytes_total"] - before_restore.get(
        "orbitkv_load_bytes_total", 0
    ) == sum(original.numel() * original.element_size() for original in originals)
    for index, (tensor, original) in enumerate(zip(ctx.gpu_kv_caches, originals, strict=True)):
        actual = tensor[:, 2:3]
        if codec == "ans" or index in (0, 1, 4, 5):
            assert torch.equal(actual.view(torch.uint8), original.view(torch.uint8))
        else:
            relative_error = (actual.float() - original.float()).norm() / original.float().norm()
            assert 0 < relative_error < (0.3 if codec == "turboquant-3" else 0.18)
            norms = actual[0].float().norm(dim=-1) / original[0].float().norm(dim=-1)
            assert torch.allclose(norms, torch.ones_like(norms), atol=0.01, rtol=0)
    assert after_restore["orbitkv_storage_codec_reserved_bytes"] == 0


def test_ssd_cancellation_revisions_hold_buffers_until_io_drains(fault_cache):
    from orbitkv import BlockHashes, QueryLoading

    server, client, ctx, directory = fault_cache
    hashes = [bytes([i]) * 32 for i in (1, 2)]
    publish(client, ctx, hashes)
    drain_ssd(server)
    arm(directory, "ssd")
    assert isinstance(
        client.query_prefetch(ctx.instance_id, BlockHashes(hashes), "slow"), QueryLoading
    )
    reached(directory, "ssd")
    reserved = fetch_orbitkv_metrics(server.http_port)["orbitkv_query_reserved_bytes"]
    assert reserved > 0
    client.cancel_query(ctx.instance_id, "slow")
    # A late result cannot reappear under a reused request name/revision.
    assert query(client, ctx, [b"different"], "slow").num_hit_blocks == 0
    assert client.health()[0]
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_query_reserved_bytes"] == reserved
    # Start and cancel a second interest while the same submitted read is live.
    assert isinstance(
        client.query_prefetch(ctx.instance_id, BlockHashes(hashes), "second"), QueryLoading
    )
    client.cancel_query(ctx.instance_id, "second")
    (directory / "ssd.pause").unlink()
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) == 0
    )
    ready = query(client, ctx, hashes, "fresh")
    assert ready.num_hit_blocks == 2
    client.release(ready.lease)
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) == 0
    )


@pytest.mark.parametrize(
    ("fault_cache", "stop"),
    [
        (("--query-read-batch", "1"), "cancel"),
        (("--query-read-batch", "1", "--query-read-timeout-ms", "100"), "timeout"),
        (("--query-read-batch", "1", "--query-read-max-batches", "1"), "best-effort"),
    ],
    indirect=["fault_cache"],
)
def test_stopping_submits_no_second_ssd_batch_and_drains_the_first(fault_cache, stop):
    from orbitkv import BlockHashes, QueryLoading

    server, client, ctx, directory = fault_cache
    hashes = [bytes([i]) * 32 for i in range(1, 5)]
    publish(client, ctx, hashes)
    drain_ssd(server)
    before = fetch_orbitkv_metrics(server.http_port)
    arm(directory, "ssd")
    batch = BlockHashes(hashes)
    assert isinstance(client.query_prefetch(ctx.instance_id, batch, "bounded"), QueryLoading)
    reached(directory, "ssd")
    if stop == "cancel":
        client.cancel_query(ctx.instance_id, "bounded")
    elif stop == "timeout":
        time.sleep(0.15)
        timed_out = query(client, ctx, hashes, "bounded")
        assert timed_out.num_hit_blocks == 0 and not timed_out.lease
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_query_reserved_bytes"] > 0
    assert query(client, ctx, [b"independent"], "other").num_hit_blocks == 0
    observed_lookups = fetch_orbitkv_metrics(server.http_port).get("orbitkv_hll_total_requests", 0)
    (directory / "ssd.pause").unlink()
    if stop == "best-effort":
        result = query(client, ctx, hashes, "bounded")
        assert result.num_hit_blocks == 1
        client.release(result.lease)
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) == 0
    )
    after = fetch_orbitkv_metrics(server.http_port)
    page_bytes = ctx.get_kv_cache().numel() * ctx.get_kv_cache().element_size() // ctx.num_blocks
    assert (
        after["orbitkv_ssd_prefetch_bytes_total"]
        - before.get("orbitkv_ssd_prefetch_bytes_total", 0)
        == page_bytes
    )
    assert after.get("orbitkv_ssd_prefetch_inflight", 0) == 0
    assert after.get("orbitkv_hll_total_requests", 0) == observed_lookups, (
        "unread pages are not authoritative cache misses"
    )


@pytest.mark.parametrize("fault_cache", [("--query-read-batch", "1")], indirect=True)
def test_cancelled_preparation_does_not_stop_another_shared_read_owner(fault_cache):
    from orbitkv import BlockHashes, QueryLoading, RecoveryContract

    server, client, ctx, directory = fault_cache
    hashes = [bytes([i]) * 32 for i in range(1, 5)]
    publish(client, ctx, hashes)
    drain_ssd(server)
    arm(directory, "ssd")
    batch = BlockHashes(hashes)
    contract = RecoveryContract(ctx.namespace, 16, [(0, "attention", 0)])
    assert client.prepare_recovery(
        ctx.instance_id, batch, "forecast", contract, ctx.namespace, 0, 64, 0
    )
    reached(directory, "ssd")
    assert isinstance(client.query_prefetch(ctx.instance_id, batch, "demand"), QueryLoading)
    client.cancel_query(ctx.instance_id, "forecast")
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_query_reserved_bytes"] > 0
    (directory / "ssd.pause").unlink()
    result = query(client, ctx, hashes, "demand")
    assert result.num_hit_blocks == 4
    client.release(result.lease)
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) == 0
    )
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_query_coalesced_reads_total"] > 0


def test_prepared_result_expires_without_poll_then_claim_holds_bytes_through_restore(fault_cache):
    import torch

    from orbitkv import BlockHashes, QueryReady, RecoveryContract

    server, client, ctx, _ = fault_cache
    hashes = [b"prepared" * 4]
    expected = ctx.get_kv_cache()[:, 0:1].cpu().clone()
    publish(client, ctx, hashes)
    contract = RecoveryContract(ctx.namespace, 16, [(0, "attention", 0)])
    args = (ctx.instance_id, BlockHashes(hashes), "prepared", contract, ctx.namespace, 0, 16, 0)
    assert client.prepare_recovery(*args)
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) > 0
    )
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) == 0
    )
    assert client.prepare_recovery(*args), "the expired ticket cannot prevent new preparation"

    def claim():
        result = client.read_recovery(*args)
        return result if isinstance(result, QueryReady) else None

    ready = until(claim)
    assert ready.num_hit_blocks == 1 and ready.lease
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_query_reserved_bytes"] > 0
    ctx.get_kv_cache()[:, 1:2].zero_()
    torch.cuda.synchronize()
    restore = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[1]])]
    )
    assert client.wait_restore(restore, timeout=10).success
    assert torch.equal(ctx.get_kv_cache()[:, 1:2].cpu(), expected)
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) == 0
    )


@pytest.mark.parametrize("fault_cache", [{"ssd_backend": "cufile"}], indirect=True)
@pytest.mark.parametrize("outcome", ["complete", "error", "kill"])
def test_cufile_write_holds_pages_and_publishes_only_completed_objects(fault_cache, outcome):
    import torch

    server, client, ctx, directory = fault_cache
    expected = ctx.get_kv_cache()[:, 0:1].cpu().clone()
    publish(client, ctx, [b"warm"])
    warm = query(client, ctx, [b"warm"], "warm")
    arm(directory, "cufile_write")
    pool = ThreadPoolExecutor(1)
    future = pool.submit(publish, client, ctx, [b"writing"])
    try:
        reached(directory, "cufile_write")
        time.sleep(0.15)
        assert not future.done(), "GPU sources must remain owned throughout cuFileWrite"
        assert query(client, ctx, [b"writing"], "uncommitted").num_hit_blocks == 0
        assert fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_write_inflight"] > 0
        handle = client.start_restore(
            ctx.instance_id, 0, 0, [ctx._layer_names], [(warm.lease, [[3]])]
        )
        assert client.wait_restore(handle, timeout=5).success
        assert torch.equal(ctx.get_kv_cache()[:, 3:4].cpu(), expected)
        if outcome == "kill":
            server.stop()
            with pytest.raises(Exception, match="exited|reconnect"):
                future.result(timeout=10)
            return
        if outcome == "error":
            arm(directory, "cufile_write_error")
        (directory / "cufile_write.pause").unlink()
        if outcome == "error":
            with pytest.raises(Exception, match="Internal"):
                future.result(timeout=10)
            assert query(client, ctx, [b"writing"], "failed").num_hit_blocks == 0
            assert (
                fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_cufile_write_failures_total"]
                > 0
            )
            (directory / "cufile_write_error.pause").unlink()
            assert publish(client, ctx, [b"writing"])[0], "an aborted extent must be retryable"
        else:
            assert future.result(timeout=10)[0]
        drain_ssd(server)
        ready = query(client, ctx, [b"writing"], "committed")
        assert ready.num_hit_blocks == 1
        handle = client.start_restore(
            ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[2]])]
        )
        assert client.wait_restore(handle, timeout=10).success
        assert torch.equal(ctx.get_kv_cache()[:, 2:3].cpu(), expected)
        stats = fetch_orbitkv_metrics(server.http_port)
        assert stats["orbitkv_ssd_cufile_write_bytes_total"] > 0
        assert stats["orbitkv_ssd_cufile_read_bytes_total"] > 0
        assert stats["orbitkv_ssd_write_inflight"] == 0
        assert client.unregister_context(ctx.instance_id)[0]
        until(lambda: fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_gpu_staging_bytes"] == 0)
    finally:
        (directory / "cufile_write.pause").unlink(missing_ok=True)
        (directory / "cufile_write_error.pause").unlink(missing_ok=True)
        if not future.done():
            server.stop()
        pool.shutdown(wait=True)


@pytest.mark.parametrize("fault_cache", [{"ssd_backend": "cufile"}], indirect=True)
@pytest.mark.parametrize("completion", ["cufile_write_completion", "ssd_host_completion"])
def test_submitted_cufile_write_allows_ssd_reads_and_delays_unregister(fault_cache, completion):
    import torch

    server, client, ctx, directory = fault_cache
    expected = ctx.get_kv_cache()[:, 0:1].cpu().clone()
    assert publish(client, ctx, [b"on-disk"])[0]
    drain_ssd(server)
    ready = query(client, ctx, [b"on-disk"], "read-during-write")
    arm(directory, completion)
    pool = ThreadPoolExecutor(2)
    writing = pool.submit(publish, client, ctx, [b"unconfirmed"])
    try:
        reached(directory, completion)
        before = fetch_orbitkv_metrics(server.http_port)
        if completion == "cufile_write_completion":
            assert before["orbitkv_ssd_cufile_inflight_batches"] == 1
        assert not writing.done()
        if completion == "cufile_write_completion":
            assert query(client, ctx, [b"unconfirmed"], "unpublished").num_hit_blocks == 0
        restore = client.start_restore(
            ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[2]])]
        )
        assert client.wait_restore(restore, timeout=5).success
        assert torch.equal(ctx.get_kv_cache()[:, 2:3].cpu(), expected)
        after = fetch_orbitkv_metrics(server.http_port)
        assert after["orbitkv_ssd_cufile_read_bytes_total"] > before.get(
            "orbitkv_ssd_cufile_read_bytes_total", 0
        )
        if completion == "cufile_write_completion":
            assert after["orbitkv_ssd_cufile_inflight_batches"] == 1
        unregistering = pool.submit(client.unregister_context, ctx.instance_id)
        time.sleep(0.15)
        assert not unregistering.done(), "unregister must retain submitted write ownership"
        if completion == "cufile_write_completion":
            assert after["orbitkv_ssd_write_inflight"] > 0
        (directory / f"{completion}.pause").unlink()
        assert writing.result(timeout=10)[0]
        assert unregistering.result(timeout=10)[0]
        until(
            lambda: all(
                fetch_orbitkv_metrics(server.http_port).get(name, 0) == 0
                for name in (
                    "orbitkv_ssd_cufile_inflight_batches",
                    "orbitkv_ssd_write_inflight",
                    "orbitkv_ssd_read_pinned_bytes",
                    "orbitkv_ssd_gpu_staging_bytes",
                )
            )
        )
    finally:
        (directory / f"{completion}.pause").unlink(missing_ok=True)
        pool.shutdown(wait=True)


@pytest.mark.parametrize(
    "fault_cache", [{"ssd_backend": "cufile", "num_blocks": 10}], indirect=True
)
def test_full_gpu_write_queue_uses_host_writeback_without_waiting(fault_cache):
    import torch

    from orbitkv import CacheManagerClient

    server, client, ctx, directory = fault_cache
    tensor = ctx.get_kv_cache()
    expected = tensor[:, 8:9].cpu().clone()
    arm(directory, "cufile_write_completion")

    # Each Publish descriptor session has one outstanding call. Independent
    # producers are needed to exercise the shared worker's admission limit.
    producers = [CacheManagerClient(server.bootstrap_socket, timeout_ms=100) for _ in range(8)]

    def save_page(producer, index):
        return producer.save(
            ctx.instance_id, 0, 0, 0, [(ctx._layer_names[0], [index], [bytes([index]) * 32])]
        )

    pool = ThreadPoolExecutor(8)
    writes = [pool.submit(save_page, producer, i) for i, producer in enumerate(producers)]
    try:
        reached(directory, "cufile_write_completion")
        until(lambda: fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_write_inflight"] == 8)
        assert all(not write.done() for write in writes)
        assert save_page(client, 8)[0], "saturated GPU writes must not block host publication"
        stats = fetch_orbitkv_metrics(server.http_port)
        assert stats["orbitkv_ssd_gpu_write_fallbacks_total"] == 1
        assert stats["orbitkv_ssd_cufile_inflight_batches"] == 1
        assert stats["orbitkv_ssd_gpu_staging_bytes"] == 8 << 20
        (directory / "cufile_write_completion.pause").unlink()
        assert all(write.result(timeout=10)[0] for write in writes)
        drain_ssd(server)
        ready = query(client, ctx, [bytes([8]) * 32], "fallback-on-disk")
        assert ready.num_hit_blocks == 1
        handle = client.start_restore(
            ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[9]])]
        )
        assert client.wait_restore(handle, timeout=10).success
        assert torch.equal(tensor[:, 9:10].cpu(), expected)
        assert client.unregister_context(ctx.instance_id)[0]
        until(lambda: fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_gpu_staging_bytes"] == 0)
    finally:
        (directory / "cufile_write_completion.pause").unlink(missing_ok=True)
        pool.shutdown(wait=True)
        for producer in producers:
            producer.close()


@pytest.mark.parametrize(
    "fault_cache", [{"ssd_backend": "cufile", "block_size": 1024}], indirect=True
)
def test_submitted_cufile_reads_keep_two_slots_and_leases_until_unregister(fault_cache):
    import torch

    server, client, ctx, directory = fault_cache
    tensor = ctx.get_kv_cache()
    expected = tensor.cpu().clone()
    hashes = [bytes([i]) * 32 for i in range(ctx.num_blocks)]
    assert publish(client, ctx, hashes)[0]
    drain_ssd(server)
    ready = query(client, ctx, hashes, "large-read")
    tensor.zero_()
    torch.cuda.synchronize()
    arm(directory, "cufile_read_completion")
    handle = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [list(range(ctx.num_blocks))])]
    )
    pool = ThreadPoolExecutor(1)
    try:
        reached(directory, "cufile_read_completion")
        until(
            lambda: (
                fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_cufile_inflight_batches"] == 2
            )
        )
        client.cancel_query(ctx.instance_id, "large-read")
        unregistering = pool.submit(client.unregister_context, ctx.instance_id)
        time.sleep(0.15)
        assert not unregistering.done()
        assert not client.poll_restore(handle).done
        held = fetch_orbitkv_metrics(server.http_port)
        assert held["orbitkv_ssd_gpu_staging_bytes"] == 8 << 20
        assert held["orbitkv_ssd_read_pinned_bytes"] == tensor.numel() * tensor.element_size()
        (directory / "cufile_read_completion.pause").unlink()
        assert client.wait_restore(handle, timeout=10).success
        assert unregistering.result(timeout=10)[0]
        assert torch.equal(tensor.cpu(), expected)
        after = fetch_orbitkv_metrics(server.http_port)
        assert after["orbitkv_ssd_cufile_read_seconds_count"] == 4
        assert after["orbitkv_ssd_cufile_inflight_batches"] == 0
        assert after["orbitkv_ssd_read_pinned_bytes"] == 0
        assert after["orbitkv_ssd_gpu_staging_bytes"] == 0
    finally:
        (directory / "cufile_read_completion.pause").unlink(missing_ok=True)
        pool.shutdown(wait=True)


@pytest.mark.parametrize(
    "fault_cache,selected,read_calls",
    [
        ({"ssd_backend": "cufile"}, (0, 1, 2, 3), 1),
        (
            {"ssd_backend": "cufile", "extra_args": ("--ssd-cache-shards", "2")},
            (0, 1, 2, 3),
            2,
        ),
        ({"ssd_backend": "cufile"}, (0, 2), 2),
    ],
    indirect=["fault_cache"],
    ids=["adjacent-leases", "separate-files", "unrequested-gap"],
)
def test_cufile_batches_keep_all_leases_and_only_read_selected_pages(
    fault_cache, selected, read_calls
):
    import torch

    server, client, ctx, directory = fault_cache
    cache_path = directory / "ssd"
    files = [cache_path] if cache_path.is_file() else list(cache_path.glob("shard-*.dat"))
    assert files
    for file in files:
        stat = file.stat()
        assert stat.st_size > 0 and stat.st_blocks * 512 >= stat.st_size
    tensor = ctx.get_kv_cache()
    expected = tensor.cpu().clone()
    hashes = [bytes([i]) * 32 for i in range(ctx.num_blocks)]
    # Establish physical file order explicitly; a multi-page Publish may group
    # hashes in any order, so logical pages 0/2 need not have a disk gap.
    for page, block_hash in enumerate(hashes):
        assert client.save(ctx.instance_id, 0, 0, 0, [(ctx._layer_names[0], [page], [block_hash])])[
            0
        ]
    drain_ssd(server)
    ready = query(client, ctx, hashes, "batched")
    assert ready.num_hit_blocks == len(hashes)
    before = fetch_orbitkv_metrics(server.http_port)
    assert before["orbitkv_ssd_read_pinned_bytes"] == tensor.numel() * tensor.element_size()
    assert before["orbitkv_ssd_cufile_write_seconds_sum"] > 0
    page_bytes = expected[:, 0].numel() * expected.element_size()
    tensor.zero_()
    torch.cuda.synchronize()

    arm(directory, "cufile")
    destinations = [i if i in selected else None for i in range(ctx.num_blocks)]
    handle = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [destinations])]
    )
    reached(directory, "cufile")
    client.cancel_query(ctx.instance_id, "batched")
    assert not client.poll_restore(handle).done
    # Cancellation releases unselected query sources; every submitted source
    # must remain pinned, including all extents merged into a single read.
    assert fetch_orbitkv_metrics(server.http_port)[
        "orbitkv_ssd_read_pinned_bytes"
    ] == page_bytes * len(selected)
    (directory / "cufile.pause").unlink()
    assert client.wait_restore(handle, timeout=10).success
    actual = tensor.cpu()
    for page in range(ctx.num_blocks):
        if page in selected:
            assert torch.equal(actual[:, page], expected[:, page])
        else:
            assert torch.count_nonzero(actual[:, page]) == 0
    until(lambda: fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_read_pinned_bytes"] == 0)
    after = fetch_orbitkv_metrics(server.http_port)
    count = "orbitkv_ssd_cufile_read_seconds_count"
    assert after[count] - before.get(count, 0) == read_calls
    assert after["orbitkv_ssd_cufile_read_seconds_sum"] > 0
    size = "orbitkv_ssd_cufile_read_bytes_total"
    assert after[size] - before.get(size, 0) == page_bytes * len(selected)


@pytest.mark.parametrize("fault_cache", [{"ssd_backend": "cufile"}], indirect=True)
def test_cufile_delay_keeps_sources_and_allows_dram_restores(fault_cache):
    import torch

    server, client, ctx, directory = fault_cache
    hashes = [b"disk-restore"]
    expected = ctx.get_kv_cache()[:, 0:1].cpu().clone()
    publish(client, ctx, hashes)
    drain_ssd(server)
    warm_hashes = [b"dram-restore"]
    publish(client, ctx, warm_hashes)
    ready = query(client, ctx, hashes, "disk")
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_read_pinned_bytes"] > 0
    arm(directory, "cufile")
    handle = client.start_restore(ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[2]])])
    reached(directory, "cufile")
    client.cancel_query(ctx.instance_id, "disk")
    with pytest.raises(TimeoutError):
        client.wait_restore(handle, timeout=0.02)
    assert not client.poll_restore(handle).done
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_read_pinned_bytes"] > 0

    # A real DRAM restore, not just a miss, must complete while storage is paused.
    warm = query(client, ctx, warm_hashes, "dram")
    other = client.start_restore(ctx.instance_id, 0, 0, [ctx._layer_names], [(warm.lease, [[3]])])
    assert client.wait_restore(other, timeout=5).success
    assert torch.equal(ctx.get_kv_cache()[:, 3:4].cpu(), expected)
    arm(directory, "notification")
    (directory / "cufile.pause").unlink()
    assert client.wait_restore(handle, timeout=10).success
    reached(directory, "notification")
    assert torch.equal(ctx.get_kv_cache()[:, 2:3].cpu(), expected)
    until(
        lambda: all(
            fetch_orbitkv_metrics(server.http_port).get(name, 0) == 0
            for name in ("orbitkv_query_reserved_bytes", "orbitkv_ssd_read_pinned_bytes")
        )
    )
    assert fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_gpu_staging_bytes"] == 8 << 20
    ok, message = client.unregister_context(ctx.instance_id)
    assert ok, message
    until(lambda: fetch_orbitkv_metrics(server.http_port)["orbitkv_ssd_gpu_staging_bytes"] == 0)


def test_restore_timeout_and_lost_notification_preserve_destinations(fault_cache):
    import torch

    server, client, ctx, directory = fault_cache
    hashes = [b"restore" * 4]
    expected = ctx.get_kv_cache()[:, 0:1].cpu().clone()
    publish(client, ctx, hashes)
    ready = query(client, ctx, hashes, "load")
    arm(directory, "restore")
    arm(directory, "notification")
    handle = client.start_restore(ctx.instance_id, 0, 0, [ctx._layer_names], [(ready.lease, [[2]])])
    reached(directory, "restore")
    with pytest.raises(TimeoutError):
        client.wait_restore(handle, timeout=0.02)
    assert not client.poll_restore(handle).done
    assert query(client, ctx, [b"unrelated"], "independent").num_hit_blocks == 0
    (directory / "restore.pause").unlink()
    assert client.wait_restore(handle, timeout=5).success
    reached(directory, "notification")
    torch.cuda.synchronize()
    assert torch.equal(ctx.get_kv_cache()[:, 2:3].cpu(), expected)
    until(
        lambda: fetch_orbitkv_metrics(server.http_port).get("orbitkv_query_reserved_bytes", 0) == 0
    )


@pytest.mark.parametrize("end", ["complete", "kill", "corrupt-ack"])
def test_publish_stall_keeps_source_owned_without_stalling_queries(fault_cache, end, capfd):
    server, client, ctx, directory = fault_cache
    name = "publish_ack" if end == "corrupt-ack" else "publish"
    arm(directory, name)
    # Always terminate/release the peer before joining a potentially fenced publisher.
    pool = ThreadPoolExecutor(1)
    future = pool.submit(publish, client, ctx, [b"publish"])
    try:
        reached(directory, name)
        time.sleep(0.15)  # Past the client's 100ms ordinary call deadline.
        assert not future.done(), "publisher released GPU sources on an ambiguous timeout/ack"
        assert query(client, ctx, [b"unrelated"], "independent").num_hit_blocks == 0
        expected_log = "holding source pages" if end == "corrupt-ack" else "retaining source pages"
        assert expected_log in capfd.readouterr().err
        if end == "complete":
            (directory / "publish.pause").unlink()
            assert future.result(timeout=5)[0]
        else:
            server.stop()
            with pytest.raises(Exception, match="exited|reconnect"):
                future.result(timeout=5)
    finally:
        (directory / f"{name}.pause").unlink(missing_ok=True)
        if not future.done():
            server.stop()
        pool.shutdown(wait=True)


@pytest.mark.parametrize("fault_cache", [None, "configured-prefix"], indirect=True)
def test_manager_restart_rejects_old_leases_and_restore_handles(fault_cache):
    from orbitkv import CacheManagerClient, OrbitKVError

    server, client, ctx, directory = fault_cache
    publish(client, ctx, [b"restart"])
    ready = query(client, ctx, [b"restart"], "old-lease")
    another = query(client, ctx, [b"restart"], "old-restore")
    arm(directory, "restore")
    handle = client.start_restore(
        ctx.instance_id, 0, 0, [ctx._layer_names], [(another.lease, [[2]])]
    )
    reached(directory, "restore")
    server.stop()
    (directory / "restore.pause").unlink()
    assert server.start(), server.read_logs()
    fresh = CacheManagerClient(server.bootstrap_socket)
    try:
        with pytest.raises(OrbitKVError):
            client.poll_restore(handle)
        with pytest.raises(OrbitKVError, match="reconnect"):
            fresh.poll_restore(handle)
        with pytest.raises(OrbitKVError):
            fresh.release(ready.lease)
        replacement = ClientContext(
            client=fresh,
            instance_id=ctx.instance_id,
            namespace=ctx.namespace,
            device_id=0,
            num_blocks=4,
            num_layers=1,
        )
        replacement.register_kv_caches()
        publish(fresh, replacement, [b"new-engine"])
        new = query(fresh, replacement, [b"new-engine"], "fresh")
        assert new.num_hit_blocks == 1
        fresh.release(new.lease)
        replacement.unregister_context()
    finally:
        fresh.close()
