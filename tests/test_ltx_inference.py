from __future__ import annotations

import threading
import sys
from pathlib import Path
from types import SimpleNamespace

import pytest
import torch

from factories import AnsweredReply
from jasna.ltx import inference, restore
from jasna.ltx.model_files import LtxModelFiles
from jasna import license_api


def _files(suffix: str = "") -> LtxModelFiles:
    return LtxModelFiles(*(Path(name + suffix) for name in ("transformer", "vae", "decoder")))


@pytest.mark.parametrize("frozen,encrypted,expected", [(False, False, False), (True, False, True), (False, True, True)])
def test_licensed_bundle_routes_to_worker(monkeypatch, frozen, encrypted, expected):
    monkeypatch.setattr(inference, "is_frozen", lambda: frozen)
    assert inference.protected_bundle(_files(".enc" if encrypted else "")) is expected


def test_frozen_trial_stays_local_and_mixed_trial_is_rejected(monkeypatch):
    monkeypatch.setattr(inference, "is_frozen", lambda: True)
    trial = LtxModelFiles.placeholder("distilled", fast=False)
    assert not inference.protected_bundle(trial)
    with pytest.raises(ValueError, match="cannot be mixed"):
        inference.protected_bundle(LtxModelFiles(trial.transformer, Path("vae.enc"), Path("decoder.enc")))


def test_protected_runtime_never_loads_models_in_parent(monkeypatch):
    def forbidden(*_args):
        pytest.fail("protected model loaded in the parent")

    monkeypatch.setattr(inference, "load_video_encoder", forbidden)
    monkeypatch.setattr(inference, "load_video_decoder", forbidden)
    monkeypatch.setattr(inference, "LtxTransformer", forbidden)
    monkeypatch.setattr(inference, "device_free_bytes", lambda device: 9 << 30)
    runtime = inference.ModelRuntime(_files(".enc"), torch.device("cpu"), threading.Event())
    requests = []
    pixels = torch.zeros(1, 3, 121, 2, 2, dtype=torch.uint8)
    latent = torch.zeros(1, 128, 16, 1, 1, dtype=torch.bfloat16)
    decoded = torch.zeros(121, 3, 2, 2, dtype=torch.uint8)

    def request(op, params, tensors, advance=None):
        requests.append((op, params, tensors))
        if op == "load_transformer":
            return {"steps": 8, "resident": 40, "count": 48}, []
        if op == "encode":
            return {}, [latent]
        if op == "denoise_chain":
            advance(8)
            return {}, [latent]
        if op == "decode":
            return {}, [decoded]
        return {}, []

    monkeypatch.setattr(runtime, "request", request)
    monkeypatch.setattr(runtime, "send", lambda op, params, tensors: AnsweredReply(request(op, params, tensors)[1]))
    encoder = runtime.load_encoder()
    assert encoder(pixels) is latent
    assert runtime.load_encoder() is encoder
    runtime.unload_encoder()
    transformer = runtime.load_transformer()
    steps = []
    assert transformer.denoise_chain([latent], [43], 104, steps.append) == [latent]
    assert steps == [8]
    assert len(transformer.conditions) == 8
    assert transformer.blocks == inference.BlockLayout(40, 48)
    assert not [value for value in vars(transformer).values() if isinstance(value, torch.Tensor)]
    transformer.close()
    decoder = runtime.load_decoder()
    monkeypatch.setattr(torch.cuda, "empty_cache", lambda: None)
    reply, free = restore._send_window_decode(decoder, latent, 43, 512, lambda _canvas: 123)
    assert reply.tensors()[0] is decoded and free == 123
    runtime.unload_decoder()
    assert [op for op, _, _ in requests] == [
        "load_encoder", "encode", "unload_encoder", "load_transformer", "denoise_chain",
        "unload_transformer", "load_decoder", "decode", "unload_decoder",
    ]
    assert requests[3][1] == {"free_bytes": 9 << 30}
    assert requests[4][1] == {"seeds": [43], "window_hop": 104}
    assert requests[7][1] == {"seed": 43, "free_bytes": 123}


@pytest.mark.parametrize("models,protected,resuming,expected", [
    (frozenset({"ltx"}), True, False, True),
    (frozenset({"ltx"}), False, False, False),
    (frozenset({"ltx"}), True, True, False),
    (frozenset({"ltx", "basicvsrpp"}), True, False, False),
    (frozenset({"basicvsrpp"}), True, False, False),
])
def test_only_a_fresh_protected_ltx_only_job_starts_its_worker_with_the_job(models, protected, resuming, expected):
    assert inference.worker_starts_with_job(models, protected=protected, resuming=resuming) is expected


def test_a_runtime_started_ahead_loads_the_encoder_before_the_encode_pass_asks_for_it(monkeypatch):
    runtime = inference.ModelRuntime(_files(".enc"), torch.device("cpu"), threading.Event())
    requests, encoder_loaded = [], threading.Event()

    def request(op, params, tensors, advance=None):
        requests.append((op, threading.current_thread() is threading.main_thread()))
        if op == "load_encoder":
            encoder_loaded.set()
        return {}, []

    monkeypatch.setattr(runtime, "request", request)
    runtime.start_ahead()
    assert encoder_loaded.wait(5)
    runtime.prepare_transformer()
    assert isinstance(runtime.load_encoder(), inference.WorkerEncoder)
    assert requests == [("prepare_transformer", False), ("load_encoder", False)]


def test_a_failed_start_ahead_fails_the_pass_that_waits_for_it_and_closing_only_logs_it(monkeypatch):
    runtime = inference.ModelRuntime(_files(".enc"), torch.device("cpu"), threading.Event())

    def request(op, params, tensors, advance=None):
        raise RuntimeError("LTX worker could not start")

    monkeypatch.setattr(runtime, "request", request)
    runtime.start_ahead()
    with pytest.raises(RuntimeError, match="could not start"):
        runtime.load_encoder()
    runtime.close()


def test_runtime_construction_and_unused_close_do_not_start_worker(monkeypatch):
    runtime = inference.ModelRuntime(_files(".enc"), torch.device("cpu"), threading.Event())
    monkeypatch.setattr(runtime, "request", lambda *_args: pytest.fail("unused worker started"))
    runtime.close()
    assert runtime._client is None


@pytest.fixture
def allocator(monkeypatch):
    """PyTorch's peak allocation stats for a backend on the CPU (the worker runs on CUDA)."""
    stats = {"peak": 0, "allocated": 0}
    monkeypatch.setattr(torch.cuda, "is_initialized", lambda: True)
    monkeypatch.setattr(torch.cuda, "reset_peak_memory_stats", lambda device: stats.update(peak=stats["allocated"]))
    monkeypatch.setattr(torch.cuda, "max_memory_allocated", lambda device: stats["peak"])
    monkeypatch.setattr(torch.cuda, "memory_allocated", lambda device: stats["allocated"])
    return stats


def test_backend_rejects_inference_before_load_and_arbitrary_dispatch(allocator):
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    for op in ("encode", "denoise_chain", "decode"):
        with pytest.raises(RuntimeError, match="is not loaded"):
            backend.dispatch(op, {}, [], lambda _n: None)
    with pytest.raises(ValueError, match="unsupported"):
        backend.dispatch("state_dict", {}, [], lambda _n: None)
    backend.close()


def test_backend_module_unload_wipes_parameters(monkeypatch, allocator):
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    backend.encoder = torch.nn.Linear(2, 2)
    parameters = list(backend.encoder.parameters())
    monkeypatch.setattr(torch.cuda, "empty_cache", lambda: None)
    backend.dispatch("unload_encoder", {}, [], lambda _n: None)
    assert backend.encoder is None
    assert all(torch.count_nonzero(parameter).item() == 0 for parameter in parameters)


def test_runtime_reuses_transport_updates_cancel_and_translates_cancellation(monkeypatch):
    clients = []

    class WorkerCancelled(Exception):
        pass

    class Client:
        def __init__(self, config, cancel):
            self.config, self.cancel, self.closed = config, cancel, False
            clients.append(self)

        def request(self, op, params, tensors, advance=None):
            if self.cancel.is_set():
                raise WorkerCancelled()
            return {}, []

        def close(self):
            self.closed = True

    monkeypatch.setattr(license_api, "require_protection", lambda: None)
    monkeypatch.setitem(sys.modules, "jasna.protection.ltx_worker", SimpleNamespace(WorkerClient=Client, WorkerCancelled=WorkerCancelled))
    runtime = inference.ModelRuntime(_files(".enc"), torch.device("cuda:0"), threading.Event())
    runtime.request("load_encoder", {}, [])
    assert Path(clients[0].config["transformer"]).is_absolute()
    next_cancel = threading.Event()
    runtime.cancel = next_cancel
    runtime.request("load_decoder", {}, [])
    assert len(clients) == 1 and clients[0].cancel is next_cancel
    next_cancel.set()
    with pytest.raises(restore.Cancelled):
        runtime.request("load_transformer", {}, [])
    assert clients[0].closed and runtime._client is None


def test_runtime_reports_its_own_and_the_workers_peak_apart(monkeypatch):
    class Client:
        def __init__(self, config, cancel):
            pass

        def request(self, op, params, tensors, advance=None):
            return ({"peak_vram_bytes": 9 << 30} if op == "stats" else {}), []

    monkeypatch.setattr(license_api, "require_protection", lambda: None)
    monkeypatch.setitem(sys.modules, "jasna.protection.ltx_worker", SimpleNamespace(WorkerClient=Client, WorkerCancelled=RuntimeError))
    monkeypatch.setattr(torch.cuda, "max_memory_allocated", lambda device: 2 << 30)
    runtime = inference.ModelRuntime(_files(".enc"), torch.device("cuda:0"), threading.Event())
    assert runtime.peak_vram_bytes() == (2 << 30, None)
    runtime.request("load_encoder", {}, [])
    assert runtime.peak_vram_bytes() == (2 << 30, 9 << 30)


def test_worker_peak_vram_counts_the_native_block_store(monkeypatch, allocator):
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    monkeypatch.setattr(torch.cuda, "empty_cache", lambda: None)

    class Transformer:
        def native_vram_bytes(self):
            return 13 << 30

        def denoise_chain(self, references, seeds, window_hop, advance):
            allocator["peak"] = 5 << 30
            return references

        def close(self):
            pass

    backend.encoder = lambda pixels: allocator.update(peak=9 << 30) or torch.zeros(1, 128, 16, 16, 16)
    backend.dispatch("encode", {}, [torch.zeros(1, 3, 121, 512, 512, dtype=torch.uint8)], lambda _n: None)
    backend.transformer = Transformer()
    backend.dispatch("denoise_chain", {"seeds": [1], "window_hop": 88}, [torch.zeros(1)], lambda _n: None)
    backend.dispatch("unload_transformer", {}, [], lambda _n: None)

    stats, _ = backend.dispatch("stats", {}, [], lambda _n: None)
    assert stats["peak_vram_bytes"] == (5 << 30) + (13 << 30)


def test_worker_peak_vram_does_not_add_the_freed_load_probe_to_the_blocks(monkeypatch, allocator):
    """Loading probes how much VRAM it can allocate and frees it before the native store
    allocates the blocks, so the probe and the blocks never coexist."""
    gib = 1 << 30
    monkeypatch.setattr(torch.cuda, "mem_get_info", lambda device: (20 * gib, 24 * gib))

    class Transformer:
        conditions = [None] * 8
        blocks = SimpleNamespace(resident=48, count=48)

        def __init__(self, source, device, free_vram):
            allocator["peak"] = 15 * gib
            self.native = 12 * gib

        def native_vram_bytes(self):
            return self.native

    monkeypatch.setattr(inference, "TransformerSource", lambda path: path)
    monkeypatch.setattr(inference, "LtxTransformer", Transformer)
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    backend.dispatch("load_transformer", {"free_bytes": 20 * gib}, [], lambda _n: None)

    stats, _ = backend.dispatch("stats", {}, [], lambda _n: None)
    assert stats["peak_vram_bytes"] == 15 * gib


@pytest.mark.parametrize("torch_peak,torch_end,native_before,native_after,expected", [
    pytest.param(15994, 120, 0, 12831, 15994, id="load-probe-freed-before-the-blocks"),
    pytest.param(8000, 120, 0, 12831, 12951, id="load-blocks-outlast-a-smaller-probe"),
    pytest.param(5000, 300, 12831, 12831, 17831, id="denoise-beside-resident-blocks"),
    pytest.param(400, 0, 12831, 0, 13231, id="unload-frees-the-blocks"),
])
def test_operation_peak_counts_native_bytes_only_while_they_exist(torch_peak, torch_end, native_before, native_after, expected):
    assert inference.operation_peak_vram_bytes(torch_peak, torch_end, native_before, native_after) == expected


def test_worker_reports_denoise_progress_after_gpu_completion(monkeypatch, allocator):
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    events = []
    monkeypatch.setattr(torch.cuda, "synchronize", lambda device: events.append(("synchronize", device)))

    class Transformer:
        def native_vram_bytes(self):
            return 0

        def denoise_chain(self, references, seeds, window_hop, advance):
            for count in (1, 2):
                events.append(("queued", count))
                advance(count)
            return references

    backend.transformer = Transformer()
    latent = torch.zeros(1)
    _, result = backend.dispatch(
        "denoise_chain", {"seeds": [1], "window_hop": 88}, [latent],
        lambda count: events.append(("progress", count)),
    )
    assert result == [latent]
    assert events == [
        ("queued", 1), ("synchronize", backend.device), ("progress", 1),
        ("queued", 2), ("synchronize", backend.device), ("progress", 2),
    ]


def test_worker_sizes_the_transformer_from_the_parents_device_wide_free_vram(monkeypatch, allocator):
    """On Windows the worker's CUDA view misses the parent's and other programs' VRAM."""
    gib = 1 << 30
    worker_view = {"free": 30 * gib}
    monkeypatch.setattr(torch.cuda, "mem_get_info", lambda device: (worker_view["free"], 32 * gib))
    readers = []

    class Transformer:
        conditions = [None] * 8
        blocks = SimpleNamespace(resident=40, count=48)

        def __init__(self, path, device, free_vram):
            readers.append(free_vram)

        def native_vram_bytes(self):
            return 0

    monkeypatch.setattr(inference, "TransformerSource", lambda path: path)
    monkeypatch.setattr(inference, "LtxTransformer", Transformer)
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    backend.dispatch("load_transformer", {"free_bytes": 14 * gib}, [], lambda _n: None)
    worker_view["free"] = 25 * gib
    assert readers[0](torch.device("cpu")) == 9 * gib


def test_local_transformer_reads_device_wide_free_vram(monkeypatch):
    received = []
    monkeypatch.setattr(inference, "TransformerSource", lambda path: path)
    monkeypatch.setattr(inference, "LtxTransformer", lambda path, device, free_vram: received.append(free_vram))
    runtime = inference.ModelRuntime(LtxModelFiles.placeholder("distilled", fast=False), torch.device("cpu"), threading.Event())
    runtime.load_transformer()
    assert received == [inference.device_free_bytes]


@pytest.mark.skipif(not torch.cuda.is_available(), reason="needs CUDA")
def test_worker_decode_returns_its_vram_before_the_parent_reads_the_next_budget(monkeypatch):
    """The parent sizes the next window's decode from device-wide free VRAM, which counts the
    worker's allocator cache."""
    device = torch.device("cuda")
    monkeypatch.setattr(
        inference, "decode_latent", lambda decoder, latent, free_bytes, generator: torch.rand(1, 3, 33, 512, 512, device=device)
    )
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cuda"})
    backend.decoder = object()
    torch.cuda.empty_cache()
    reserved = torch.cuda.memory_reserved(device)
    _, (frames,) = backend.dispatch("decode", {"seed": 1, "free_bytes": 4 << 30}, [torch.zeros(1, 128, 5, 16, 16)], lambda _n: None)
    assert frames.device.type == "cpu" and frames.shape == (33, 3, 512, 512)
    assert torch.cuda.memory_reserved(device) == reserved


@pytest.mark.skipif(not torch.cuda.is_available(), reason="needs CUDA")
def test_parent_returns_its_cached_vram_before_the_worker_sizes_the_resident_blocks(monkeypatch):
    """The worker cannot use the blocks this process's allocator keeps cached (an encode pass's
    window pixels), so they must not shrink the free VRAM the resident blocks are sized from."""
    device = torch.device("cuda")
    reserved_at_load = []

    class Client:
        def __init__(self, config, cancel):
            pass

        def request(self, op, params, tensors, advance=None):
            if op == "load_transformer":
                reserved_at_load.append(torch.cuda.memory_reserved(device))
                return {"steps": 4, "resident": 36, "count": 48}, []
            return {}, []

    monkeypatch.setattr(license_api, "require_protection", lambda: None)
    monkeypatch.setitem(sys.modules, "jasna.protection.ltx_worker", SimpleNamespace(WorkerClient=Client, WorkerCancelled=RuntimeError))
    runtime = inference.ModelRuntime(_files(".enc"), device, threading.Event())
    torch.cuda.empty_cache()
    reserved = torch.cuda.memory_reserved(device)
    window_pixels = torch.empty((3, 121, 512, 512), dtype=torch.uint8, device=device)
    del window_pixels
    runtime.load_transformer()
    assert reserved_at_load == [reserved]


def test_worker_opens_the_transformer_file_ahead_on_its_own_thread(monkeypatch, allocator):
    """``prepare_transformer`` runs while the encoder holds the GPU: the file is opened on another
    thread and the later load takes that source instead of opening the file again."""
    opened, loaded, released = [], [], []

    class Source:
        def __init__(self, path):
            opened.append((path, threading.current_thread() is not threading.main_thread()))

        def close(self):
            released.append(self)

    class Transformer:
        conditions = [None] * 4
        blocks = SimpleNamespace(resident=48, count=48)

        def __init__(self, source, device, free_vram):
            loaded.append(source)

        def native_vram_bytes(self):
            return 0

        def close(self):
            pass

    monkeypatch.setattr(torch.cuda, "mem_get_info", lambda device: (8 << 30, 32 << 30))
    monkeypatch.setattr(torch.cuda, "empty_cache", lambda: None)
    monkeypatch.setattr(inference, "TransformerSource", Source)
    monkeypatch.setattr(inference, "LtxTransformer", Transformer)
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    backend.dispatch("prepare_transformer", {}, [], lambda _n: None)
    backend.dispatch("prepare_transformer", {}, [], lambda _n: None)
    backend.dispatch("load_transformer", {"free_bytes": 8 << 30}, [], lambda _n: None)
    backend.dispatch("prepare_transformer", {}, [], lambda _n: None)
    assert opened == [(Path("t.enc"), True)] and len(loaded) == 1 and isinstance(loaded[0], Source)
    backend.dispatch("unload_transformer", {}, [], lambda _n: None)
    backend.dispatch("prepare_transformer", {}, [], lambda _n: None)
    backend.close()
    assert len(opened) == 2 and len(released) == 1 and released[0] is not loaded[0]


def test_unused_transformer_file_opened_ahead_closes_with_the_worker_even_after_failing(monkeypatch, allocator):
    def failing(path):
        raise RuntimeError("synthetic license failure")

    monkeypatch.setattr(torch.cuda, "mem_get_info", lambda device: (8 << 30, 32 << 30))
    monkeypatch.setattr(inference, "TransformerSource", failing)
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    backend.dispatch("prepare_transformer", {}, [], lambda _n: None)
    backend.close()
    backend = inference.WorkerBackend({"transformer": "t.enc", "vae": "v.enc", "tuned_decoder": "d.enc", "encoder": "v.enc", "device": "cpu"})
    backend.dispatch("prepare_transformer", {}, [], lambda _n: None)
    with pytest.raises(RuntimeError, match="synthetic license failure"):
        backend.dispatch("load_transformer", {"free_bytes": 8 << 30}, [], lambda _n: None)
    backend.close()


def test_runtime_asks_the_worker_to_open_the_transformer_only_while_none_is_loaded(monkeypatch):
    requests = []
    runtime = inference.ModelRuntime(_files(".enc"), torch.device("cpu"), threading.Event())
    monkeypatch.setattr(inference, "device_free_bytes", lambda device: 9 << 30)

    def request(op, params, tensors, advance=None):
        requests.append(op)
        return ({"steps": 4, "resident": 48, "count": 48} if op == "load_transformer" else {}), []

    monkeypatch.setattr(runtime, "request", request)
    runtime.prepare_transformer()
    runtime.load_transformer()
    runtime.prepare_transformer()
    assert requests == ["prepare_transformer", "load_transformer"]
    local = inference.ModelRuntime(LtxModelFiles.placeholder("distilled", fast=False), torch.device("cpu"), threading.Event())
    monkeypatch.setattr(local, "request", lambda *_args: pytest.fail("trial files have no worker"))
    monkeypatch.setattr(inference, "TransformerSource", lambda path: SimpleNamespace(close=lambda: None))
    local.prepare_transformer()


def test_local_runtime_opens_the_transformer_file_ahead_once(monkeypatch):
    """Without a worker the runtime opens the file itself in ``prepare_transformer`` (the scan's
    thread); the load takes that source, and one never loaded is closed with the runtime."""
    opened, loaded, closed = [], [], []

    class Source:
        def __init__(self, path):
            opened.append(path)

        def close(self):
            closed.append(self)

    monkeypatch.setattr(inference, "TransformerSource", Source)
    monkeypatch.setattr(
        inference, "LtxTransformer",
        lambda source, device, free_vram: loaded.append(source) or SimpleNamespace(close=lambda: None),
    )
    files = LtxModelFiles.placeholder("distilled", fast=False)
    runtime = inference.ModelRuntime(files, torch.device("cpu"), threading.Event())
    runtime.prepare_transformer()
    runtime.prepare_transformer()
    runtime.load_transformer()
    runtime.prepare_transformer()
    assert len(opened) == 1 and len(loaded) == 1 and isinstance(loaded[0], Source)
    runtime.unload_transformer()
    runtime.prepare_transformer()
    runtime.close()
    assert len(opened) == 2 and len(closed) == 1 and closed[0] is not loaded[0]
