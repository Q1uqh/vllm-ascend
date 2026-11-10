# SPDX-License-Identifier: Apache-2.0
"""Host-only execution of production planning/range methods without vLLM/NPU.

AST loading isolates framework imports, not the method bodies under test.
Run: python -m pytest --noconftest tests/host/test_dsv4_mooncake_offload.py
"""

import ast
import ctypes
import hashlib
import json
import re
from collections import defaultdict
from dataclasses import asdict, dataclass, field, replace
from pathlib import Path
from types import SimpleNamespace as NS
from typing import Any
from unittest.mock import MagicMock

import numpy as np
import pytest

ROOT = Path(__file__).resolve().parents[2]
STORE = "vllm_ascend/distributed/kv_transfer/kv_pool/ascend_store/"


def definitions(path, namespace, names=None):
    tree = ast.parse((ROOT / path).read_text())
    tree.body = [
        node
        for node in tree.body
        if isinstance(node, (ast.ClassDef, ast.FunctionDef)) and (names is None or node.name in names)
    ]
    exec(compile(ast.fix_missing_locations(tree), str(ROOT / path), "exec", flags=0x1000000), namespace)


@dataclass(frozen=True)
class Spec:
    block_size: int = 128
    head_size: int = 8
    dtype: str = "bf16"
    tokens_per_state: int = 4
    model_version: str = "deepseek_v4"
    sliding_window: int | None = None

    @property
    def page_size_bytes(self):
        return self.block_size // self.tokens_per_state * self.head_size * 2


@dataclass
class Uniform:
    kv_cache_specs: dict


@dataclass
class Tensor:
    size: int
    layers: list
    offset: int = 0
    layer_stride: int = 0
    block_stride: int = 0


@dataclass
class Cache:
    num_blocks: int
    kv_cache_tensors: list
    kv_cache_groups: list


@pytest.fixture
def ns():
    n = dict(
        dataclass=dataclass,
        field=field,
        replace=replace,
        Any=Any,
        re=re,
        np=np,
        defaultdict=defaultdict,
        hashlib=hashlib,
        json=json,
        asdict=asdict,
        logger=MagicMock(),
        KVCacheConfig=Cache,
        KVCacheTensor=Tensor,
        UniformTypeKVCacheSpecs=Uniform,
        KVCacheSpec=Spec,
        _NUM_SHARED_BUFFERS="layerwise_num_shared_buffers",
        _PREFETCH_LAYERS="layerwise_prefetch_layers",
        _INDEPENDENT_LAYERS="layerwise_independent_layers",
        _DEFAULT_MAX_PREFETCH_LAYERS=8,
        _INDEXER_CACHE_SUFFIX=".indexer.k_cache",
        AttentionSpec=Spec,
        MambaSpec=type("Mamba", (), {}),
        is_prefix_cacheable=lambda spec: True,
    )
    definitions(
        STORE + "layerwise/layerwise_cache_layout.py",
        n,
        {
            "LayerwiseCacheLayout",
            "NamedKVCacheSpec",
            "LayerwiseLayerCacheSpecs",
            "LayerwiseReuseLayout",
            "LayerwiseCacheTopology",
            "get_physical_layer_index",
            "_parse_int_config",
            "build_layerwise_cache_layout",
            "build_layerwise_reuse_layout",
            "_fold_main_packs",
        },
    )
    n["get_layerwise_reuse_config"] = lambda config: config.kv_connector_extra_config if config else None
    definitions("vllm_ascend/models/deepseek_v4/cache_config.py", n)
    definitions(STORE + "layerwise/metadata.py", n, {"SharedBlockData", "LayerRangeReqMeta", "get_partial_block_index"})
    definitions(STORE + "layerwise/kv_transfer.py", n, {"LayerBatchBuilder"})
    definitions(STORE + "backend/mooncake_offload.py", n, {"snapshot_key", "_load_entries", "_save_entries"})
    n["block_hash_to_str"] = lambda value: value.hex()
    return n


def configuration(buffers=2):
    return NS(
        kv_transfer_config=NS(
            kv_connector_extra_config=dict(layerwise_num_shared_buffers=buffers, layerwise_independent_layers=[])
        ),
        model_config=NS(get_num_layers=lambda parallel: 43, enforce_eager=True),
        parallel_config=NS(pipeline_parallel_size=1, prefill_context_parallel_size=1, decode_context_parallel_size=1),
        cache_config=NS(prefix_cache_retention_interval=None),
        scheduler_config=NS(async_scheduling=False),
        speculative_config=None,
    )


def groups():
    # Full-history group intentionally mixes shared main and resident indexer.
    full, auxiliary = {}, {}
    for layer in range(43):
        prefix = f"model.layers.{layer}.self_attn"
        auxiliary[prefix + ".swa_cache"] = Spec(16, tokens_per_state=1, sliding_window=128)
        if layer < 2:
            continue
        ratio = 4 if layer % 2 == 0 else 128
        full[prefix] = Spec(32 * ratio, tokens_per_state=ratio)
        auxiliary[prefix + ".compressor.state_cache"] = Spec(2, tokens_per_state=1, sliding_window=2)
        if ratio == 4:
            full[prefix + ".indexer.k_cache"] = Spec(128, head_size=4)
            auxiliary[prefix + ".indexer.compressor.state_cache"] = Spec(2, tokens_per_state=1, sliding_window=2)
    return [NS(layer_names=list(specs), kv_cache_spec=Uniform(specs)) for specs in (full, auxiliary)]


@pytest.mark.parametrize("buffers", [1, 2, 3, 4])
def test_component_slots_and_physical_capacity(ns, buffers):
    gs = groups()
    plan = ns["build_deepseek_v4_reuse_config"](configuration(buffers), gs, 7)
    layout = plan.layerwise_reuse_layout
    slots = [slot for slot in layout.buffer_slots if len(slot) > 1]
    assert len(slots) == 2 * buffers
    assert layout.independent_layers == [0, 1]
    assert len(layout.prefetch_layer_map) == 41 - 2 * buffers
    for layer, predecessor in layout.prefetch_layer_map.items():
        assert layer % 2 == predecessor % 2
        assert layer - predecessor == 2 * buffers
    owners = {name: index for index, tensor in enumerate(plan.kv_cache_tensors) for name in tensor.layers}
    resident = plan.dsv4_resident_cache_names
    assert len({owners[name] for name in resident}) == len(resident)
    assert not {owners[name] for name in resident} & {owners[name] for name in plan.dsv4_shared_cache_names}
    probe = ns["build_deepseek_v4_reuse_config"](configuration(buffers), gs, 1)
    assert sum(t.size for t in plan.kv_cache_tensors) == 7 * sum(t.size for t in probe.kv_cache_tensors)
    specs = {name: group.kv_cache_spec.kv_cache_specs[name] for group in gs for name in group.layer_names}
    expected = sum(specs[name].page_size_bytes for name in resident) + 2 * buffers * 512
    assert sum(t.size for t in probe.kv_cache_tensors) == expected


def test_all_resident_control(ns):
    config = configuration()
    config.kv_transfer_config.kv_connector_extra_config["layerwise_independent_layers"] = "all"
    plan = ns["build_deepseek_v4_reuse_config"](config, groups(), 1)
    assert not plan.layerwise_reuse_layout.has_layer_reuse
    assert not plan.dsv4_shared_cache_names
    assert all(len(t.layers) == 1 for t in plan.kv_cache_tensors)


def test_layout_identity_changes_with_format_but_not_ring_size(ns):
    gs = groups()
    a = ns["build_deepseek_v4_reuse_config"](configuration(1), gs, 2)
    b = ns["build_deepseek_v4_reuse_config"](configuration(4), gs, 9)
    assert a.dsv4_component_identity == b.dsv4_component_identity
    name = gs[0].layer_names[0]
    gs[0].kv_cache_spec.kv_cache_specs[name] = replace(gs[0].kv_cache_spec.kv_cache_specs[name], dtype="fp8")
    assert ns["component_layout_identity"](gs) != a.dsv4_component_identity


@pytest.mark.parametrize(
    "field_name,value",
    [("pipeline_parallel_size", 2), ("prefill_context_parallel_size", 2), ("decode_context_parallel_size", 2)],
)
def test_reject_unsupported_parallel(ns, field_name, value):
    config = configuration()
    setattr(config.parallel_config, field_name, value)
    with pytest.raises(ValueError, match="PP=PCP=DCP"):
        ns["build_deepseek_v4_reuse_config"](config, groups(), 1)


@pytest.mark.parametrize("mode", ["async", "speculative", "graph"])
def test_reject_unsupported_execution(ns, mode):
    config = configuration()
    if mode == "async":
        config.scheduler_config.async_scheduling = True
    elif mode == "speculative":
        config.speculative_config = object()
    else:
        config.model_config.enforce_eager = False
    with pytest.raises(ValueError):
        ns["build_deepseek_v4_reuse_config"](config, groups(), 1)


def test_mixed_batch_restores_only_shared_bytes_for_continuation(ns):
    # Indexer and main occupy disjoint entries of one logical remote object.
    indexer = np.full((4, 4), 11, dtype=np.uint8)
    main = np.full((4, 8), 22, dtype=np.uint8)
    db = NS(
        group_block_len={0: [4, 8]},
        group_block_stride={0: [4, 8]},
        group_kv_caches_base_addr={0: [indexer.ctypes.data, main.ctypes.data]},
        group_layer_cache_entry_offsets={0: [0, 2]},
    )
    builder = ns["LayerBatchBuilder"](db, 12, 1)
    builder.shared_cache_entries = [False, True]
    shared = ns["SharedBlockData"](
        np.array([1, 2]),
        None,
        ["continued", "external"],
        [False, False],
        block_keys=["a", "b"],
        previous_step_rows=[True, False],
    )
    result = builder.build_addrs(shared, 0)
    assert result.all_offsets == [[4], [0, 4]]
    assert result.all_sizes == [[8], [4, 8]]
    for buffers, sizes in zip(result.all_buffers, result.all_sizes, strict=True):
        for address, size in zip(buffers, sizes, strict=True):
            ctypes.memset(address, 33, size)
    assert (indexer[1] == 11).all()  # continued resident data survives
    assert (indexer[2] == 33).all()  # external prefix restores indexer
    assert (main[1:3] == 33).all()


def test_live_table_replaces_holes_and_copies_without_new_blocks():
    tree = ast.parse((ROOT / STORE / "metadata.py").read_text())
    cls = next(node for node in tree.body if isinstance(node, ast.ClassDef) and node.name == "RequestTracker")
    method = next(node for node in cls.body if isinstance(node, ast.FunctionDef) and node.name == "sync_live_block_ids")
    cls.body = [method]
    cls.decorator_list = []
    ns = {}
    exec(
        compile(ast.fix_missing_locations(ast.Module(body=[cls], type_ignores=[])), "tracker", "exec", flags=0x1000000),
        ns,
    )
    tracker = ns["RequestTracker"]()
    tracker.req_id = "request"
    tracker.allocated_block_ids_by_group = [[10, 20], [9]]
    live = [[0, 20, 35], [0, 18]]
    tracker.sync_live_block_ids(NS(kv_connector_block_state=NS(get_block_ids=lambda req: live)))
    live[0][1] = 99
    assert tracker.allocated_block_ids_by_group == [[0, 20, 35], [0, 18]]
    with pytest.raises(RuntimeError, match="requires"):
        tracker.sync_live_block_ids(NS())
    with pytest.raises(RuntimeError, match="no live"):
        tracker.sync_live_block_ids(NS(kv_connector_block_state=NS(get_block_ids=lambda req: None)))


def test_tail_snapshot_uses_raw_tokens_and_skips_resident_restore(ns):
    worker = NS(
        group_uses_align_state=[False],
        grouped_block_size=[128],
        use_eagle=False,
        kv_cache_config=NS(dsv4_shared_cache_names=("main",)),
        _group_reuses_buffer=lambda group: True,
        _layerwise_load_snapshot_start=lambda *args: 1,
        _make_layerwise_full_key=lambda group, key: f"{group}:{key}",
    )
    spec = NS(
        can_load=True,
        layerwise_previous_step=True,
        kvpool_cached_tokens=131,
        kvpool_store_skip_tokens=None,
        layerwise_snapshot_end_token=131,
    )
    request = NS(load_spec=spec, block_ids_by_group=[[4, 8]], layerwise_request_id="generation")
    entries = ns["_load_entries"](worker, request, 0, [b"hash"], None)
    assert entries == [("0:68617368", 0), ("0:offload_v1:generation:131:1", 1)]
    worker._group_reuses_buffer = lambda group: False
    assert ns["_load_entries"](worker, request, 0, [b"hash"], None) == []
    worker._group_reuses_buffer = lambda group: True
    spec.layerwise_previous_step = False
    worker._layerwise_load_snapshot_start = lambda *args: None
    with pytest.raises(ValueError, match="exact snapshot"):
        ns["_load_entries"](worker, request, 0, [b"hash"], None)


def test_glm_main_pack_planner_retains_group_predecessors(ns):
    names = [f"model.layers.{layer}.attn" for layer in range(6)]
    components = {name: Spec(tokens_per_state=1) for name in names}
    topology = ns["LayerwiseCacheTopology"](
        tuple(tuple(names[i : i + 2]) for i in (0, 2, 4)), tuple((name, i % 2) for i, name in enumerate(names))
    )
    layout = ns["build_layerwise_reuse_layout"](
        components, 6, dict(layerwise_num_shared_buffers=1, layerwise_independent_layers=[]), topology=topology
    )
    assert layout.prefetch_layer_map == {2: 0, 4: 2, 3: 1, 5: 3}


def test_mrv2_allocates_the_exact_plan_and_validates_before_allocation(ns):
    plan = ns["build_deepseek_v4_reuse_config"](configuration(), groups(), 3)
    specs = {name: g.kv_cache_spec.kv_cache_specs[name] for g in groups() for name in g.layer_names}
    allocations = []

    def allocate(size, alignment, device):
        backing = NS(data_ptr=lambda: len(allocations) * alignment)
        allocations.append((size, backing))
        return backing

    ns.update(
        get_current_vllm_config=lambda: configuration(),
        KVPPConfig=NS(from_vllm_config=lambda c: NS(size=1)),
        _is_dsv4_model=lambda c: True,
        _get_layer_kv_cache_specs=lambda c: specs,
        enable_sfa=lambda c: True,
        is_deepseek_v41_cache=lambda s: False,
        _allocate_int8_cache_tensor=allocate,
        offload_event=lambda *args, **kwargs: None,
        get_kv_cache_tensor_layers=lambda t: t.layers,
    )
    definitions("vllm_ascend/worker/v2/attn_utils.py", ns, {"_allocate_kv_cache"})
    result = ns["_allocate_kv_cache"](plan, {}, "cpu")
    assert sum(size for size, _ in allocations) == sum(t.size for t in plan.kv_cache_tensors)
    assert len(allocations) == len(plan.kv_cache_tensors)
    for tensor, (_, backing) in zip(plan.kv_cache_tensors, allocations, strict=True):
        assert all(result[name] is backing for name in tensor.layers)
    allocations.clear()
    plan.kv_cache_tensors[-1].offset = 1
    with pytest.raises(ValueError, match="slot geometry"):
        ns["_allocate_kv_cache"](plan, {}, "cpu")
    assert not allocations


@pytest.mark.parametrize("operation", ["get", "put", "commit"])
def test_backend_faults_are_one_shot_and_delay_is_observed(ns, operation):
    import threading

    recorded = []
    ns.update(time=NS(sleep=lambda seconds: recorded.append(seconds)), offload_event=lambda *args, **kwargs: None)
    tree = ast.parse((ROOT / STORE / "backend/mooncake_backend.py").read_text())
    cls = next(n for n in tree.body if isinstance(n, ast.ClassDef) and n.name == "MooncakeBackend")
    method = next(n for n in cls.body if isinstance(n, ast.FunctionDef) and n.name == "_inject_offload_debug_fault")
    cls.body = [method]
    cls.bases = []
    cls.decorator_list = []
    exec(
        compile(ast.fix_missing_locations(ast.Module(body=[cls], type_ignores=[])), "backend", "exec", flags=0x1000000),
        ns,
    )
    backend = ns["MooncakeBackend"]()
    backend._offload_debug_delay_ms = 250
    backend._offload_debug_fault = operation
    backend._offload_debug_used = set()
    backend._offload_debug_lock = threading.Lock()
    assert not backend._inject_offload_debug_fault(operation, [])
    assert backend._inject_offload_debug_fault(operation, ["key"])
    assert not backend._inject_offload_debug_fault(operation, ["key"])
    assert recorded == ([0.25] if operation == "put" else [])


def test_missing_required_compressed_page_fails_closed(ns):
    worker = NS(
        group_uses_align_state=[False],
        grouped_block_size=[128],
        use_eagle=False,
        kv_cache_config=NS(dsv4_shared_cache_names=("main",)),
        _group_reuses_buffer=lambda group: True,
        _layerwise_load_snapshot_start=lambda *args: None,
    )
    request = NS(
        load_spec=NS(
            can_load=True, layerwise_previous_step=True, kvpool_cached_tokens=128, kvpool_store_skip_tokens=None
        ),
        block_ids_by_group=[[0]],
    )
    with pytest.raises(ValueError, match="required null"):
        ns["_load_entries"](worker, request, 0, [b"hash"], None)


def isolated_method(path, cls_name, method_name, ns):
    tree = ast.parse((ROOT / path).read_text())
    cls = next(n for n in tree.body if isinstance(n, ast.ClassDef) and n.name == cls_name)
    cls.body = [n for n in cls.body if isinstance(n, ast.FunctionDef) and n.name == method_name]
    cls.bases = []
    cls.decorator_list = []
    exec(compile(ast.fix_missing_locations(ast.Module(body=[cls], type_ignores=[])), path, "exec", flags=0x1000000), ns)
    return ns[cls_name]


@pytest.mark.parametrize("fault", [None, "put", "commit"])
def test_publication_requires_all_layer_copies_and_failures_revoke(ns, fault):
    ns.update(
        require_aligned_batch_results=lambda operation, keys, results: results,
        _emit_range_debug_event=lambda *args: None,
        _emit_commit_debug_event=lambda *args: None,
    )
    cls = isolated_method(
        STORE + "layerwise/kv_transfer.py", "KVCacheStoreLayerSendingThread", "_handle_range_request", ns
    )
    sender = cls()
    sender._active_put_keys = None
    sender.sync_save_events = [MagicMock(), MagicMock()]
    sender.final_layer_id = 1
    sender.raise_on_transfer_failure = True
    sender.max_transfer_blocks = 16
    sender.max_transfer_bytes = 1024
    sender._session_tracker = MagicMock()
    sender._remove_started_keys = MagicMock()
    sender._revoke_range_keys = MagicMock()
    sender._range_transfer_batches = lambda keys, buffers, sizes, offsets, *args: [(keys, buffers, sizes, offsets)]
    sender.m_store = NS(
        batch_copy_put=MagicMock(return_value=[-1 if fault == "put" else 0]),
        batch_commit=MagicMock(return_value=[-1 if fault == "commit" else 0]),
    )
    meta = NS(layer_id=0, keys=["object"], all_buffers=[[1234]], all_sizes=[[8]], all_offsets=[[0]])
    if fault == "put":
        with pytest.raises(RuntimeError, match="PUT failed"):
            sender._handle_range_request(meta, False)
        sender.m_store.batch_commit.assert_not_called()
        sender._revoke_range_keys.assert_called_once_with(["object"])
        return
    sender._handle_range_request(meta, False)
    sender.m_store.batch_commit.assert_not_called()
    sender._session_tracker.commit_put_keys.assert_not_called()
    meta.layer_id = 1
    if fault == "commit":
        with pytest.raises(RuntimeError, match="commit failed"):
            sender._handle_range_request(meta, True)
        sender._revoke_range_keys.assert_called_once_with(["object"])
        sender._session_tracker.commit_put_keys.assert_not_called()
    else:
        sender._handle_range_request(meta, True)
        sender._session_tracker.commit_put_keys.assert_called_once_with(["object"])


@pytest.mark.parametrize("save_failed", [False, True])
def test_actual_receive_handler_waits_for_source_before_overwrite(ns, save_failed):
    import threading

    events = []
    ns["offload_event"] = lambda event, **fields: events.append(event)
    cls = isolated_method(
        STORE + "layerwise/kv_transfer.py", "KVCacheStoreLayerRecvingThread", "_handle_range_layer_task", ns
    )
    receiver = cls()
    receiver.layer_save_finished_events = [threading.Event(), threading.Event()]
    receiver.layer_load_finished_events = [threading.Event(), threading.Event()]
    receiver.sync_save_events = [MagicMock(), MagicMock()]
    receiver._active_load_indices = None
    receiver._group_load_indices = {}
    receiver._load_abort_event = threading.Event()
    receiver._mark_invalid_transfer_task_blocks = MagicMock()
    receiver.request_queue = MagicMock()
    receiver.get_event = threading.Event()
    receiver.external_slot_release_waiter = None
    receiver._wait_for_event = lambda event, *args: event.wait(timeout=2)
    started_wait = threading.Event()

    def record(event, **fields):
        events.append(event)
        if event == "slot_wait":
            started_wait.set()

    ns["offload_event"] = record

    def check_failure():
        if save_failed:
            raise RuntimeError("source PUT failed")

    receiver.save_failure_checker = check_failure
    shared = NS()
    meta = ns["LayerRangeReqMeta"]([], 1, [], [], [], [], [])
    receiver.group_builders = [NS(build_addrs=lambda *args: meta)]
    receiver._handle_range_request = lambda *args: events.append("actual_write")
    task = NS(shared_block_data=shared, group_id=0, layer_idx_in_group=0, final_group_layer=True)
    data = NS(layer_id=1, wait_for_save_layer=0, attention_start_gate=None, transfer_tasks=[task])
    failures = []

    def run():
        try:
            receiver._handle_range_layer_task(data)
        except RuntimeError as error:
            failures.append(str(error))

    thread = threading.Thread(target=run)
    thread.start()
    try:
        assert started_wait.wait(timeout=2)
        assert not receiver.layer_load_finished_events[1].is_set()
        assert "actual_write" not in events
        receiver.layer_save_finished_events[0].set()
        thread.join(timeout=2)
        assert not thread.is_alive()
        if save_failed:
            assert failures == ["source PUT failed"]
            assert "actual_write" not in events
            assert receiver._load_abort_event.is_set()
        else:
            assert not failures
            assert events.index("slot_release") < events.index("actual_write")
    finally:
        receiver.layer_save_finished_events[0].set()
        thread.join(timeout=2)


def test_summary_preserves_failures_and_never_reports_empty_run_as_pass(tmp_path):
    import importlib.util

    path = ROOT / "tests/e2e/cases/features/kv_pool/tools/summarize_dsv4_offload.py"
    spec = importlib.util.spec_from_file_location("dsv4_summary_test", path)
    module = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(module)
    log = tmp_path / "server.log"
    log.write_text("ERROR failure\n" * 1000)
    result = module.summarize([log])
    assert len(result) <= 280
    assert result[1].startswith("ERROR ")
    assert result[-1] == "RESULT FAIL"
    log.write_text("")
    assert "INSUFFICIENT" in module.summarize([log])[-1]


@pytest.mark.parametrize("window", [None, 4])
def test_d2d_component_copy_uses_each_peer_stride_and_live_window(ns, window):
    definitions("vllm_ascend/distributed/kv_transfer/kv_p2p/dsv4_layerwise.py", ns)
    # Same payload with distinct P scratch and D overlay page strides.
    source = ctypes.create_string_buffer(128)
    target = ctypes.create_string_buffer(b"x" * 256, 256)
    for index in range(128):
        source[index] = bytes([index])
    local = NS(block_len=[8], block_stride=[8], kv_caches_base_addr=[ctypes.addressof(source)])
    remote = NS(block_len=[8], block_stride=[16], kv_caches_base_addr=[ctypes.addressof(target)])
    spec = NS(block_size=4, sliding_window=window)
    src, dst, sizes = ns["component_transfer_ranges"](local, remote, [1, 2, 3], [4, 5, 6], spec, 9)
    expected_pages = [1, 2] if window else [0, 1, 2]
    assert len(src) == len(expected_pages)
    for a, b, size in zip(src, dst, sizes, strict=True):
        ctypes.memmove(b, a, size)
    for page in expected_pages:
        assert target.raw[(4 + page) * 16 : (4 + page) * 16 + 8] == source.raw[(1 + page) * 8 : (1 + page) * 8 + 8]
        assert target.raw[(4 + page) * 16 + 8 : (5 + page) * 16] == b"x" * 8
    with pytest.raises(ValueError, match="null block"):
        ns["component_transfer_ranges"](local, remote, [1, 2, 0], [4, 5, 6], spec, 9)
    with pytest.raises(ValueError, match="payload differs"):
        ns["component_transfer_ranges"](
            local, NS(**{**remote.__dict__, "block_len": [7]}), [1, 2, 3], [4, 5, 6], spec, 9
        )


def test_d2d_final_chunk_only_and_current_tables(ns):
    path = "vllm_ascend/distributed/kv_transfer/kv_p2p/mooncake_layerwise_connector.py"
    captured = []
    ns["MooncakeLayerwiseConnectorMetadata"] = lambda: NS(add_new_req=lambda **kw: captured.append(kw))
    ns["round_down"] = lambda x, size: x // size * size
    ns["logging"] = NS(DEBUG=10)
    cls = isolated_method(path, "MooncakeLayerwiseConnectorScheduler", "build_connector_meta", ns)
    scheduler = cls()
    scheduler.is_dsv4 = True
    scheduler.vllm_config = NS(kv_transfer_config=NS(is_kv_consumer=False))
    scheduler.block_size = [4]
    req = NS(all_token_ids=list(range(9)), kv_transfer_params={"remote_cached_tokens": 0})
    info = NS(request=req, local_computed_tokens=0, local_block_ids=[[8]])
    info.update_transferred_tokens = lambda x: setattr(info, "transferred", x)
    info.update_computed_tokens = lambda x: setattr(info, "local_computed_tokens", x)
    info.unpack = lambda: (info.local_block_ids, info.transferred, info.local_computed_tokens, req)
    scheduler._reqs_need_send_layerwise = {"r": info}
    live = [[0, 11, 12]]
    output = NS(
        scheduled_cached_reqs=NS(req_ids=["r"], new_block_ids=[None], num_computed_tokens=[0]),
        scheduled_new_reqs=[],
        scheduled_spec_decode_tokens={},
        num_scheduled_tokens={"r": 4},
        kv_connector_block_state=NS(get_block_ids=lambda _: live),
    )
    scheduler.build_connector_meta(output)
    assert not captured
    output.scheduled_cached_reqs.num_computed_tokens = [4]
    output.num_scheduled_tokens = {"r": 5}
    scheduler.build_connector_meta(output)
    assert len(captured) == 1 and captured[0]["chunk_finish"]
    assert captured[0]["local_block_ids"] == live
    live[0][1] = 99
    assert captured[0]["local_block_ids"][0][1] == 11
    assert not scheduler._reqs_need_send_layerwise


def test_shared_store_accepts_only_explicit_dsv4_p2p_sibling(ns):
    ns["get_backend_class"] = lambda _: NS(layerwise_data_plane="block_key")
    definitions(STORE + "layerwise/layerwise_cache_layout.py", ns, {"get_layerwise_reuse_config"})
    store = dict(
        kv_connector="AscendStoreConnector",
        kv_role="kv_producer",
        kv_connector_extra_config=dict(backend="mooncake", use_layerwise=True, layerwise_num_shared_buffers=2),
    )
    peer = dict(kv_connector="MooncakeLayerwiseConnector", kv_connector_extra_config={"dsv4_final_handoff": True})
    config = NS(
        kv_connector="MultiConnector", kv_role="kv_producer", kv_connector_extra_config={"connectors": [store, peer]}
    )
    assert ns["get_layerwise_reuse_config"](config) is store["kv_connector_extra_config"]
    peer["kv_connector_extra_config"] = {}
    with pytest.raises(ValueError):
        ns["get_layerwise_reuse_config"](config)


def test_d2d_sender_selects_each_components_group(ns):
    path = "vllm_ascend/distributed/kv_transfer/kv_p2p/mooncake_layerwise_connector.py"
    ns["TransferMeta"] = lambda **kw: NS(**kw)
    ns["offload_event"] = MagicMock()
    ns["time"] = NS(perf_counter=lambda: 0)
    cls = isolated_method(path, "KVCacheSendingLayerThread", "_transfer_kv_cache", ns)
    sender = cls()
    sender.pd_head_ratio = 1
    sender.enable_kv_quant = sender.enable_c8_quant = False
    sender.layer_metadata = {
        "main": NS(tensor_group_idx=[0]),
        "swa": NS(tensor_group_idx=[2]),
        "state": NS(tensor_group_idx=[4]),
    }
    groups_seen = []

    def ranges(task, req_id, req, name, group):
        groups_seen.append(group)
        return [100 + group], [200 + group], [8]

    sender.get_transfer_meta = ranges
    sender.engine = NS(batch_transfer_sync_write=MagicMock(return_value=0))
    sender.failed_reqs = set()
    task = NS(
        k_cache=None,
        v_cache=None,
        k_quant_cache=None,
        layer_idx=3,
        wait_event=MagicMock(),
        layer_name="main",
        layer_names=["main", "swa", "state"],
        send_request={"r": NS(remote_host="D", remote_te_rpc_port=123)},
    )
    assert sender._transfer_kv_cache(task) is None
    assert groups_seen == [0, 2, 4]
    sender.engine.batch_transfer_sync_write.assert_called_once_with("D:123", [100, 102, 104], [200, 202, 204], [8] * 3)


def test_cold_slot_wait_has_evidence_without_get(ns):
    import threading

    ns["offload_event"] = MagicMock()
    cls = isolated_method(STORE + "layerwise/kv_transfer.py", "KVCacheStoreLayerRecvingThread", "_copy_gva_layers", ns)
    receiver = cls()
    receiver.layer_save_finished_events = [threading.Event()]
    receiver.layer_save_finished_events[0].set()
    receiver.layer_load_finished_events = [threading.Event(), threading.Event()]
    receiver.sync_save_events = [MagicMock()]
    receiver.save_failure_checker = MagicMock()
    receiver._wait_for_event = lambda event, *args: event.wait(timeout=1)
    receiver.load_disabled = threading.Event()
    receiver.external_slot_release_waiter = MagicMock()
    task = NS(wait_for_save_layer=0, transfer_tasks=[], layer_id=1, attention_start_gate=None)
    assert receiver._copy_gva_layers(task)
    assert [call.args[0] for call in ns["offload_event"].call_args_list] == ["slot_wait", "slot_release"]
    receiver.external_slot_release_waiter.assert_called_once_with(1)


@pytest.mark.parametrize("failure", [None, "D2D failed"])
def test_p2p_shared_slot_blocks_until_device_copy_and_propagates_failure(ns, failure):
    import threading

    path = "vllm_ascend/distributed/kv_transfer/kv_p2p/mooncake_layerwise_connector.py"
    names = ["_mark_layer_reuse_pending", "_complete_layer_reuse", "wait_for_layer_reuse"]
    methods = {
        name: getattr(isolated_method(path, "MooncakeLayerwiseConnectorWorker", name, ns), name) for name in names
    }
    worker = type("Worker", (), methods)()
    worker.layer_storage_slots = {2: (0,), 6: (0,)}
    worker.storage_send_done_events = [threading.Event()]
    worker.storage_send_done_events[0].set()
    worker._pending_reuse_layers = set()
    worker._storage_send_errors = {}
    worker.kv_send_layer_thread = NS(is_alive=lambda: True)
    ns["LAYERWISE_REUSE_WAIT_LOG_INTERVAL_SECONDS"] = 0.1
    entered = threading.Event()
    events = []

    def record(event, **fields):
        events.append(event)
        if event == "p2p_slot_wait":
            entered.set()

    ns["offload_event"] = record
    worker._mark_layer_reuse_pending(2)
    outcomes = []

    def wait():
        try:
            worker.wait_for_layer_reuse(6)
            outcomes.append("released")
        except RuntimeError:
            outcomes.append("failed")

    thread = threading.Thread(target=wait)
    thread.start()
    try:
        assert entered.wait(timeout=1)
        assert not outcomes
        worker._complete_layer_reuse(2, failure)
        thread.join(timeout=1)
        assert outcomes == ["failed" if failure else "released"]
        if not failure:
            assert events.index("p2p_source_done") < events.index("p2p_slot_release")
    finally:
        worker.storage_send_done_events[0].set()
        thread.join(timeout=1)


def test_p2p_wire_preserves_page_strides_and_identity(ns, monkeypatch):
    import sys
    from types import ModuleType

    import msgspec

    module = ModuleType("dsv4_wire_test")
    monkeypatch.setitem(sys.modules, module.__name__, module)
    ns["__name__"] = module.__name__
    ns["msgspec"] = msgspec
    path = "vllm_ascend/distributed/kv_transfer/kv_p2p/mooncake_layerwise_connector.py"
    definitions(path, ns, {"LayerMetadata", "MooncakeAgentMetadata"})
    module.__dict__.update(ns)
    layer = ns["LayerMetadata"]([2], [1024], [64], [1], [320])
    wire = ns["MooncakeAgentMetadata"](1234, {"swa": layer}, "identity")
    decoded = msgspec.msgpack.decode(msgspec.msgpack.encode(wire), type=ns["MooncakeAgentMetadata"])
    assert decoded.layer_metadata["swa"].block_stride == [320]
    assert decoded.dsv4_identity == "identity"


def test_dsv4_reserves_final_token_and_skips_empty_remote_prefix(ns):
    path = "vllm_ascend/distributed/kv_transfer/kv_p2p/mooncake_layerwise_connector.py"
    cls = isolated_method(path, "MooncakeLayerwiseConnectorScheduler", "get_num_new_matched_tokens", ns)
    scheduler = cls()
    scheduler.is_dsv4 = True
    scheduler.block_size = [2, 128]
    scheduler._hybrid_prefill_token_count = lambda count: count - 1 if count > 1 else count
    req = NS(prompt_token_ids=[1], kv_transfer_params={"do_remote_prefill": True})
    assert scheduler.get_num_new_matched_tokens(req, 0) == (0, False)
    assert not req.kv_transfer_params["do_remote_prefill"]
    req.prompt_token_ids = [1] * 4097
    req.kv_transfer_params["do_remote_prefill"] = True
    assert scheduler.get_num_new_matched_tokens(req, 0) == (4096, True)


@pytest.mark.parametrize("endpoint", [4095, 4096, 4097, 8193, 122798])
@pytest.mark.parametrize("size", [128, 4096])
@pytest.mark.parametrize("hash_lag", [0, 2])
def test_transfer_suffix_snapshots_match_next_step_keys(ns, endpoint, size, hash_lag):
    total = (endpoint + size - 1) // size
    hashes = [str(i).encode() for i in range(max(0, endpoint // size - hash_lag))]
    transfer = 4096
    cutoff = min(endpoint // transfer, len(hashes) * size // transfer) * transfer // size
    needs_snapshot = bool(endpoint % transfer or endpoint // transfer > len(hashes) * size // transfer)
    worker = NS(
        grouped_block_size=[size], group_uses_align_state=[False],
        cache_transfer_granularity=transfer, use_eagle=False,
        kv_cache_config=NS(dsv4_shared_cache_names=("main",)),
        _group_reuses_buffer=lambda group: True,
        _is_layerwise_save_owner=lambda group: True,
        _make_layerwise_full_key=lambda group, key: key,
    )
    worker._layerwise_save_full_end = lambda req, group, span, partial: (
        min(req.target_token_len // span, partial)
        if partial is not None else req.target_token_len // span
    )
    worker._layerwise_load_snapshot_start = lambda req, group, tokens: cutoff if needs_snapshot else None
    request = NS(
        target_token_len=endpoint, save_start_token=0, can_save=True,
        block_ids_by_group=[list(range(1, total + 1))], store_masks=None,
        layerwise_request_id="incarnation",
        load_spec=NS(
            can_load=True, layerwise_previous_step=True, kvpool_cached_tokens=endpoint,
            kvpool_store_skip_tokens=None, layerwise_snapshot_end_token=endpoint,
        ),
    )
    saved = ns["_save_entries"](worker, request, NS(), 0, hashes)
    saved_keys = {key for key, _ in saved}
    # Hashes arriving on the next scheduler step must not change which
    # namespace the preceding save used.
    for restore_hashes in (hashes, hashes + [b"new"] * 8):
        loaded = ns["_load_entries"](worker, request, 0, restore_hashes, None)
        assert {key for key, _ in loaded} <= saved_keys
    if endpoint == 122798 and size == 128 and not hash_lag:
        assert sum("offload_v1:" in key and slot is not None for key, slot in saved) == 31
        assert sum("offload_v1:" in key for key, _ in saved) == 32
