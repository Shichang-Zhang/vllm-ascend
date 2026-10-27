# SPDX-License-Identifier: Apache-2.0
import ctypes
import math
import queue
import threading
from collections import defaultdict
from dataclasses import replace
from types import SimpleNamespace
from unittest.mock import MagicMock, patch

import pytest
import torch

from vllm_ascend.distributed.kv_transfer.kv_p2p import mooncake_connector
from vllm_ascend.distributed.kv_transfer.kv_p2p.mooncake_connector import (
    KVCacheRecvingThread,
    KVCacheTaskTracker,
    MooncakeConnectorWorker,
)
from vllm_ascend.distributed.kv_transfer.kv_p2p.mooncake_dsa_metadata import (
    DsaLocalResultKind,
    DsaStepRequest,
    RemoteEndpoint,
    RemoteSource,
)
from vllm_ascend.distributed.kv_transfer.kv_p2p.mooncake_dsa_transfer import (
    MAX_REGISTER_MEMORY_BYTES,
    DsaCacheLayout,
)

MAIN = "model.layers.0.self_attn.attn"
INDEXER = "model.layers.0.indexer.attn.index_cache"


def make_worker(rank=0, ptp=8, dcp=8, dtp=4):
    worker = object.__new__(MooncakeConnectorWorker)
    worker.tp_rank, worker.tp_size = rank, dtp
    worker._prefill_tp_size, worker._decode_tp_size = ptp, dtp
    worker._prefill_pp_size = 1
    worker.use_mla = worker.use_sparse = True
    worker.pcp_size = worker.dcp_size = 1
    worker.pcp_rank = worker.dcp_rank = 0
    worker.num_key_value_heads = 1
    worker.tp_num_need_pulls = 1
    worker.side_channel_port = 6000
    worker.handshake_port = 6000 + rank
    worker.engine_id = "decode"
    worker._dsa_decode = True
    worker._dsa_active_commands = {}
    worker._dsa_cancel_events = {}
    worker._dsa_results = queue.SimpleQueue()
    worker._dsa_collected_results = queue.SimpleQueue()
    worker._dsa_dispatch_lock = threading.Lock()
    worker._closing = False
    worker.vllm_config = SimpleNamespace(
        model_config=SimpleNamespace(is_deepseek_mla=True),
        parallel_config=SimpleNamespace(tensor_parallel_size=dtp),
        kv_transfer_config=SimpleNamespace(kv_port=5000),
    )
    thread = object.__new__(KVCacheRecvingThread)
    worker.kv_recv_thread = thread
    thread.tp_rank = rank
    thread.vllm_config = worker.vllm_config
    thread._prefill_pp_size = 1
    thread.pp_layer_indices = {0: (0, 1)}
    thread.num_draft_layers = 0
    thread.index_cache_plane_base = 1
    thread._dsa_transformer_layers = {MAIN: 0, INDEXER: 0}
    thread.request_queue = queue.Queue()
    thread.request_task_counts = defaultdict(int)
    thread.finished_request_markers = set()
    thread.request_task_counts_lock = threading.Lock()
    thread.failed_recv_requests = set()
    thread.use_request_level_recv_errors = False
    thread.dsa_failure_phases = {}
    thread.failed_recv_requests_lock = threading.Lock()
    thread.invalid_block_ids = set()
    thread.remote_metadata_lock = threading.Lock()
    groups = {0: ({"layer_names": [MAIN]}, [0]), 1: ({"layer_names": [INDEXER]}, [1])}
    thread.kv_group2layeridx = groups
    thread.remote_metadata_hosts = {"prefill": {5000 + p: "127.0.0.1" for p in range(ptp)}}
    thread.remote_kv_group2layeridx = {"prefill": {5000 + p: groups for p in range(ptp)}}
    thread.kv_caches_base_addr = {"prefill": {5000 + p: [[10000, 20000], [30000]] for p in range(ptp)}}
    thread.remote_block_stride_per_addr = {"prefill": {5000 + p: [[8, 8], [8]] for p in range(ptp)}}
    thread.remote_block_size_scale = {"prefill": {5000 + p: [[1, 1], [dcp]] for p in range(ptp)}}
    thread.remote_block_len_per_addr = {"prefill": {5000 + p: [[8, 8], [8]] for p in range(ptp)}}
    thread.remote_cache_dtypes = {"prefill": {5000 + p: [["bf16", "bf16"], ["bf16"]] for p in range(ptp)}}
    thread.remote_num_blocks = {"prefill": {5000 + p: 128 for p in range(ptp)}}
    thread.remote_te_port = {"prefill": {5000 + p: 7000 + p for p in range(ptp)}}
    thread._dsa_main_local_layout = [DsaCacheLayout(MAIN, i, 1000 + i * 1000, 8, 8, 1, 4, "bf16") for i in range(2)]
    thread._dsa_indexer_local_layout = [DsaCacheLayout(INDEXER, 0, 3000, 8, 8, 1, 4, "bf16")]
    thread.engine = SimpleNamespace(batch_transfer_sync_read=MagicMock(return_value=0))
    thread._send_done_recv_signal = MagicMock()
    endpoints = tuple(RemoteEndpoint("127.0.0.1", 5000 + p, "prefill") for p in range(ptp))
    command = DsaStepRequest(
        "request",
        RemoteSource(
            "remote",
            endpoints,
            (9, 7),
            (9, 7),
            remote_ptp_size=ptp,
            remote_dcp_size=dcp,
            remote_block_size=4,
            num_external_tokens=ptp * 4,
        ),
        tuple(range(20, 20 + ptp)),
        tuple(range(40, 40 + ptp)),
        invalid_block_ids=(81, 83),
    )
    return worker, thread, command


def submit(worker, command):
    worker._dispatch_dsa_commands((command,))
    tasks = []
    while not worker.kv_recv_thread.request_queue.empty():
        task = worker.kv_recv_thread.request_queue.get_nowait()
        worker.kv_recv_thread._mark_request_task_submitted(task)
        tasks.append(task)
    return tasks


@pytest.mark.parametrize("ptp,dcp,dtp", [(8, 8, 4), (16, 16, 8), (4, 1, 4), (8, 1, 4)])
def test_real_endpoint_handlers_cover_main_once_and_full_indexer_per_rank(ptp, dcp, dtp):
    writes = []
    done_counts = defaultdict(int)
    expected_counts = {}
    for rank in range(dtp):
        worker, thread, command = make_worker(rank, ptp, dcp, dtp)
        if dcp == 1:
            command = replace(
                command,
                source=replace(command.source, main_block_ids=tuple(range(ptp)), indexer_block_ids=tuple(range(ptp))),
            )
        tasks = submit(worker, command)
        for task in reversed(tasks):
            thread._handle_dsa_request(task)
        (result,) = worker.build_connector_worker_meta().results
        assert result.kind is DsaLocalResultKind.RECEIVE_COMPLETE
        assert worker.build_connector_worker_meta() is None
        indexer_bytes = 0
        for call in thread.engine.batch_transfer_sync_read.call_args_list:
            _, dsts, _, sizes = call.args
            for dst, size in zip(dsts, sizes):
                if dst >= 3000:
                    indexer_bytes += size
                else:
                    writes.extend(range(dst, dst + size))
        assert indexer_bytes == ptp * 8
        for call in thread._send_done_recv_signal.call_args_list:
            _, _, port, counts = call.args
            if counts[port]["num"]:
                done_counts[port] += 1
                expected_counts[port] = counts[port]["num"]
    assert len(writes) == len(set(writes)) == ptp * 8 * 2
    assert dict(done_counts) == expected_counts


def test_failure_and_last_task_first_wait_for_all_pending_and_report_group_zero_ids():
    worker, thread, command = make_worker()
    tasks = submit(worker, command)
    thread.engine.batch_transfer_sync_read.return_value = -1
    thread._handle_dsa_request(tasks[-1])
    assert worker.build_connector_worker_meta() is None
    for task in tasks[:-1]:
        thread._handle_dsa_request(task)
    (result,) = worker.build_connector_worker_meta().results
    assert result.kind is DsaLocalResultKind.TRANSFER_FAILED
    assert thread.get_and_clear_invalid_block_ids() == {81, 83}
    assert thread._send_done_recv_signal.call_count == len(tasks)


def test_cancel_skips_reads_but_preserves_all_notifications_and_terminal_result():
    worker, thread, command = make_worker()
    tasks = submit(worker, command)
    tasks[0]["cancelled"].set()
    for task in tasks:
        thread._handle_dsa_request(task)
    thread.engine.batch_transfer_sync_read.assert_not_called()
    assert thread._send_done_recv_signal.call_count == len(tasks)
    assert len(worker.build_connector_worker_meta().results) == 1


def test_notification_only_does_not_report_a_new_receive():
    worker, thread, command = make_worker()
    command = replace(command, notify_only=True, main_host_block_ids=(), indexer_hbm_block_ids=())
    tasks = submit(worker, command)
    for task in tasks:
        thread._handle_dsa_request(task)
    thread.engine.batch_transfer_sync_read.assert_not_called()
    assert thread._send_done_recv_signal.call_count == len(tasks)
    assert worker.build_connector_worker_meta() is None


def test_submission_gap_does_not_finish_before_last_marker():
    worker, thread, command = make_worker()
    worker._dispatch_dsa_commands((command,))
    while not thread.request_queue.empty():
        task = thread.request_queue.get_nowait()
        thread._mark_request_task_submitted(task)
        thread._handle_dsa_request(task)
        if not task["all_task_done"]:
            assert worker.build_connector_worker_meta() is None
    assert worker.build_connector_worker_meta() is not None


def test_duplicate_and_late_done_do_not_release_early_or_recreate_state():
    tracker = KVCacheTaskTracker()
    tracker.add_req_to_process("r")
    tracker.record_participant_done("r", "engine-A:port:0", 2)
    tracker.record_participant_done("r", "engine-A:port:0", 2)
    assert tracker.get_and_clear_finished_requests() == set()
    tracker.record_participant_done("r", "engine-B:port:0", 2)
    assert tracker.get_and_clear_finished_requests() == {"r"}
    tracker.record_participant_done("r", "engine-A:port:0", 2)
    assert not tracker.received_participants
    assert tracker.get_and_clear_finished_requests() == set()


@pytest.mark.parametrize("rank", [0, 1])
def test_all_ranks_build_layouts_from_local_main_views_without_registration(rank, monkeypatch):
    worker = object.__new__(MooncakeConnectorWorker)
    worker.tp_rank = rank
    worker.num_blocks = 4
    worker.engine = MagicMock()
    worker._get_layer_spec = lambda name: SimpleNamespace(block_size=4)
    host_k = torch.empty((4, 4, 1), dtype=torch.bfloat16)
    host_v = torch.empty_like(host_k)
    manager = SimpleNamespace(get_local_host_kv_views=lambda name: (host_k, host_v))
    monkeypatch.setattr(mooncake_connector, "get_sparse_kv_offload_manager", lambda: manager)
    indexer = torch.empty_like(host_k)
    indexer_layout, main_layout = worker._build_dsa_local_layouts({MAIN: (None,) * 6, INDEXER: (indexer,)})
    assert main_layout[0].base == host_k.data_ptr()
    assert main_layout[1].base == host_v.data_ptr()
    assert indexer_layout[0].base == indexer.data_ptr()


def test_dsa_consumer_registers_indexer_hbm_but_not_shared_main():
    worker = object.__new__(MooncakeConnectorWorker)
    indexer = torch.empty((4, 8), dtype=torch.bfloat16)
    indexer_layouts = [DsaCacheLayout(INDEXER, 0, indexer.data_ptr(), 16, 16, 1, 4, "bf16", 4)]

    regions, locations = worker._dsa_consumer_indexer_register_regions({INDEXER: (indexer,)}, indexer_layouts)

    assert regions.ptrs == [indexer.data_ptr()]
    assert regions.lengths == [indexer.nbytes]
    assert regions.logical_tensor_count == 1
    assert locations == ["*"]


def test_dsa_producer_oversized_atom_uses_layout_base_chunks():
    base = 4096
    span = MAX_REGISTER_MEMORY_BYTES + 1

    class FakeStorage:
        def data_ptr(self):
            return base

        def nbytes(self):
            return span

    class FakeTensor:
        ndim = 1
        shape = (2,)

        def numel(self):
            return 2

        def element_size(self):
            return 1

        def stride(self, dim):
            assert dim == 0
            return MAX_REGISTER_MEMORY_BYTES

        def data_ptr(self):
            return base

        def untyped_storage(self):
            return FakeStorage()

    worker = object.__new__(MooncakeConnectorWorker)
    regions, locations = worker._dsa_producer_register_regions({MAIN: (FakeTensor(),)})
    assert regions.ptrs == [base, base + MAX_REGISTER_MEMORY_BYTES]
    assert regions.lengths == [MAX_REGISTER_MEMORY_BYTES, 1]
    assert locations == ["*", "*"]


def test_dsa_shutdown_drains_workers_before_unregister(monkeypatch):
    events = []
    worker = object.__new__(MooncakeConnectorWorker)
    worker._dsa_decode = True
    worker._closing = False
    worker._dsa_dispatch_lock = threading.Lock()
    worker.kv_send_thread = None
    worker.kv_recv_thread = SimpleNamespace(
        request_queue=SimpleNamespace(
            join=lambda: events.append("queue_join"),
            put=lambda value: events.append(("queue_put", value)),
        ),
        join=lambda: events.append("thread_join"),
        executor=SimpleNamespace(shutdown=lambda wait: events.append(("executor_shutdown", wait))),
    )
    monkeypatch.setattr(
        mooncake_connector.global_te,
        "unregister_buffer",
        lambda: events.append("unregister"),
    )
    worker.shutdown()
    assert worker._closing
    assert events == [
        "queue_join",
        ("queue_put", None),
        "thread_join",
        ("executor_shutdown", True),
        "unregister",
    ]


def test_producer_shutdown_stops_server_before_unregister(monkeypatch):
    events = []
    worker = object.__new__(MooncakeConnectorWorker)
    worker._dsa_decode = False
    worker.kv_recv_thread = None
    worker.kv_send_thread = SimpleNamespace(
        stop=lambda: events.append("server_stop"),
        join=lambda: events.append("server_join"),
    )
    monkeypatch.setattr(
        mooncake_connector.global_te,
        "unregister_buffer",
        lambda: events.append("unregister"),
    )

    worker.shutdown()

    assert events == ["server_stop", "server_join", "unregister"]


def test_non_dsa_consumer_shutdown_unregisters_after_drain(monkeypatch):
    events = []
    worker = object.__new__(MooncakeConnectorWorker)
    worker._dsa_decode = False
    worker.kv_send_thread = None
    worker.kv_recv_thread = SimpleNamespace(
        request_queue=SimpleNamespace(
            join=lambda: events.append("queue_join"),
            put=lambda value: events.append(("queue_put", value)),
        ),
        join=lambda: events.append("thread_join"),
        executor=SimpleNamespace(shutdown=lambda wait: events.append(("executor_shutdown", wait))),
    )
    monkeypatch.setattr(
        mooncake_connector.global_te,
        "unregister_buffer",
        lambda: events.append("unregister"),
    )

    worker.shutdown()

    assert events == [
        "queue_join",
        ("queue_put", None),
        "thread_join",
        ("executor_shutdown", True),
        "unregister",
    ]


def test_cancel_inflight_read_waits_for_sync_return_before_terminal_callback():
    worker, thread, command = make_worker()
    tasks = submit(worker, command)
    entered, release = threading.Event(), threading.Event()

    def read(*args):
        entered.set()
        assert release.wait(5)
        return 0

    thread.engine.batch_transfer_sync_read.side_effect = read
    running = threading.Thread(target=thread._handle_dsa_request, args=(tasks[0],))
    running.start()
    assert entered.wait(5)
    tasks[0]["cancelled"].set()
    for task in tasks[1:]:
        thread._handle_dsa_request(task)
    assert worker.build_connector_worker_meta() is None
    assert "request" in worker._dsa_active_commands
    release.set()
    running.join(5)
    assert not running.is_alive()
    assert worker.build_connector_worker_meta() is not None
    thread.engine.batch_transfer_sync_read.assert_called_once()


def test_missing_remote_component_reports_failure_without_any_read():
    worker, thread, command = make_worker()
    tasks = submit(worker, command)
    thread.remote_cache_dtypes["prefill"][5000] = [["bf16"], ["bf16"]]
    for task in tasks:
        thread._handle_dsa_request(task)
    (result,) = worker.build_connector_worker_meta().results
    assert result.kind is DsaLocalResultKind.TRANSFER_FAILED
    thread.engine.batch_transfer_sync_read.assert_not_called()
    assert thread.get_and_clear_invalid_block_ids() == {81, 83}


def test_expiry_removes_participant_state(monkeypatch):
    tracker = KVCacheTaskTracker()
    tracker.add_req_to_process("r")
    tracker.add_delayed_request("r", 0)
    tracker.record_participant_done("r", "engine:port:0", 2)
    monkeypatch.setattr(mooncake_connector.time, "time", lambda: 10**12)
    assert tracker.get_and_clear_finished_requests() == {"r"}
    assert not tracker.received_participants
    tracker.record_participant_done("r", "engine:port:1", 2)
    assert tracker.get_and_clear_finished_requests() == set()


def test_changed_expected_count_is_rejected():
    tracker = KVCacheTaskTracker()
    tracker.add_req_to_process("r")
    tracker.record_participant_done("r", "a", 2)
    with pytest.raises(ValueError, match="count changed"):
        tracker.record_participant_done("r", "b", 1)
    assert tracker.get_and_clear_finished_requests() == set()


def test_cross_host_endpoint_translation_preserves_source_counts():
    worker, _, command = make_worker()
    endpoints = tuple(RemoteEndpoint(f"192.0.2.{p + 1}", 8000 + p, f"engine{p}") for p in range(8))
    command = replace(command, source=replace(command.source, endpoints_by_prefill_rank=endpoints))
    tasks = submit(worker, command)
    assert [t["dsa_remote_endpoint"] for t in tasks] == list(endpoints)
    assert [t["expected"] for t in tasks] == [4] * 8
    assert [t["cp_rank"] for t in tasks] == list(range(8))


def test_prefill_pp_keeps_indexer_task_in_every_stage():
    worker, _, command = make_worker(ptp=4, dcp=1, dtp=4)
    worker._prefill_pp_size = 2
    endpoints = tuple(RemoteEndpoint("127.0.0.1", 5000 + p, "prefill") for p in range(8))
    command = replace(command, source=replace(command.source, remote_pp_size=2, endpoints_by_prefill_rank=endpoints))
    plan = worker._plan_dsa_endpoints(command)
    readers = [task for task in plan if task[4] > 0]
    assert [(rank, pp, indexer) for rank, _, pp, indexer, _, _ in readers] == [(0, 0, True), (4, 1, True)]


def test_dcp_pp_missing_source_stage_is_reported_before_transfer():
    worker, thread, command = make_worker(ptp=8, dcp=8, dtp=4)
    worker._prefill_pp_size = 2
    endpoints = tuple(RemoteEndpoint("127.0.0.1", 5000 + p, "prefill") for p in range(16))
    command = replace(command, source=replace(command.source, remote_pp_size=2, endpoints_by_prefill_rank=endpoints))
    with pytest.raises(ValueError, match="Mooncake DSA source coverage incomplete") as error:
        worker._dispatch_dsa_commands((command,))
    message = str(error.value)
    assert "request=remote" in message
    assert f"missing_(pp_rank,dcp_rank)={[(1, rank) for rank in range(8)]}" in message
    assert "selected_ports=[5000, 5001, 5002, 5003, 5004, 5005, 5006, 5007]" in message
    assert thread.request_queue.empty()
    thread.engine.batch_transfer_sync_read.assert_not_called()


def test_dsa_main_and_indexer_have_distinct_metadata_indices():
    worker = object.__new__(MooncakeConnectorWorker)
    worker._dsa_pd_offload = True
    worker.total_layers = 4
    worker.vllm_config = SimpleNamespace(
        model_config=SimpleNamespace(hf_text_config=SimpleNamespace(model_type="deepseek_v3"))
    )
    names = [MAIN, "model.layers.0.self_attn.indexer.k_cache", "model.mtp.layers.0.attn"]
    worker.kv_cache_config = SimpleNamespace(
        kv_cache_groups=[SimpleNamespace(layer_names=names, kv_cache_spec=SimpleNamespace(num_kv_heads=1))]
    )
    worker._get_layer_spec = lambda name: SimpleNamespace(num_kv_heads=1)
    worker._get_spec_total_num_kv_heads = lambda spec, index: 1
    groups = worker._build_kv_group2layeridx()
    mapping = mooncake_connector.build_layer_name_to_metadata_idx(groups)
    assert len(set(mapping.values())) == len(names)
    assert set(mapping) == set(names)


def test_remote_group_and_layer_order_does_not_change_component_addresses():
    worker, thread, command = make_worker()
    tasks = submit(worker, command)
    port = tasks[0]["remote_handshake_port"]
    # Remote metadata order differs from Decode, as do its transfer group IDs.
    thread.remote_kv_group2layeridx["prefill"][port] = {
        7: ({"layer_names": [INDEXER]}, [0]),
        9: ({"layer_names": [MAIN]}, [1]),
    }
    for table in (
        thread.kv_caches_base_addr,
        thread.remote_block_stride_per_addr,
        thread.remote_block_size_scale,
        thread.remote_block_len_per_addr,
        thread.remote_cache_dtypes,
    ):
        table["prefill"][port] = list(reversed(table["prefill"][port]))
    thread._execute_dsa_receive(tasks[0])
    assert thread.engine.batch_transfer_sync_read.call_count == 2
    indexer_call, main_call = thread.engine.batch_transfer_sync_read.call_args_list
    assert all(src >= 30000 for src in indexer_call.args[2])
    assert all(10000 <= src < 30000 for src in main_call.args[2])


@pytest.mark.parametrize("api", ["get_finished", "get_transfer_results"])
def test_main_completion_apis_cancel_dsa_without_changing_failure_results(api):
    worker, thread, command = make_worker()
    worker.kv_role = "kv_consumer"
    event = threading.Event()
    worker._dsa_cancel_events[command.request_id] = event
    thread.get_and_clear_finished_requests = MagicMock(return_value={command.request_id})
    thread.get_and_clear_failed_recv_requests = MagicMock(return_value=set())

    result = getattr(worker, api)({command.request_id})

    assert event.is_set()
    if api == "get_finished":
        assert result == (set(), {command.request_id})
    else:
        assert result.finished_recving == {command.request_id}
        assert result.failed_recving == set()


def test_receiver_executor_uses_local_view_without_full_main_hbm():
    view = SimpleNamespace(device="npu:1")
    model = SimpleNamespace(
        is_deepseek_mla=True,
        hf_text_config=SimpleNamespace(num_hidden_layers=1),
        get_total_num_hidden_layers=lambda: 1,
    )
    config = SimpleNamespace(
        model_config=model,
        cache_config=SimpleNamespace(block_size=128),
        speculative_config=None,
    )
    with (
        patch.object(mooncake_connector, "enable_sfa_dcp_replicated_indexer", return_value=False),
        patch.object(mooncake_connector, "ThreadPoolExecutor") as executor,
    ):
        thread = KVCacheRecvingThread(
            1,
            2,
            1,
            MagicMock(),
            "decode",
            6001,
            6000,
            [],
            [],
            [],
            vllm_config=config,
            kv_caches={MAIN: (None, None, view, view)},
        )
    executor.assert_called_once_with(max_workers=32, initializer=torch.npu.set_device, initargs=("npu:1",))
    assert not thread.use_request_level_recv_errors


@pytest.mark.parametrize("transfer_result", [0, -1])
def test_request_level_results_reach_core_before_worker_metadata(transfer_result):
    from vllm.v1.core.sched.scheduler import Scheduler
    from vllm.v1.request import RequestStatus

    worker, thread, command = make_worker()
    worker.kv_role = "kv_consumer"
    thread.use_request_level_recv_errors = True
    thread.task_tracker = KVCacheTaskTracker()
    thread.engine.batch_transfer_sync_read.return_value = transfer_result
    for task in reversed(submit(worker, command)):
        thread._handle_dsa_request(task)

    # A callback between get_transfer_results and metadata collection must not
    # release a failed receive before vLLM can consume its request-level error.
    assert worker.build_connector_worker_meta() is None
    native = worker.get_transfer_results()
    expected_failed = {command.request_id} if transfer_result < 0 else set()
    assert native.failed_recving == expected_failed
    assert not native.finished_recving
    assert not worker.get_block_ids_with_load_errors()
    (result,) = worker.build_connector_worker_meta().results
    expected_kind = DsaLocalResultKind.TRANSFER_FAILED if transfer_result < 0 else DsaLocalResultKind.RECEIVE_COMPLETE
    assert result.kind is expected_kind
    assert worker.build_connector_worker_meta() is None
    assert not worker.get_transfer_results().failed_recving

    # Exercise the real vLLM fail-policy handler for a multi-group request.
    request = SimpleNamespace(status=RequestStatus.WAITING_FOR_REMOTE_KVS, num_computed_tokens=128)
    core = SimpleNamespace(requests={command.request_id: request}, recompute_kv_load_failures=False)
    assert Scheduler._handle_failed_recving(core, native.failed_recving) == expected_failed
    assert request.num_computed_tokens == 128


@pytest.mark.parametrize(
    "ptp,pcp,dcp,dtp", [(4, 1, 4, 2), (4, 2, 1, 2), (4, 2, 2, 2), (4, 2, 8, 2), (8, 2, 2, 4), (8, 2, 16, 4)]
)
@pytest.mark.parametrize("start,length", [(0, 37), (5, 32)])
def test_mrv2_pcp_dcp_copies_global_tokens_to_shared_host(ptp, pcp, dcp, dtp, start, length):
    # Build source contents from logical DCP groups, independently of the
    # connector's physical-port decoder. PCP varies first within each group.
    block, capacity = 4, 128
    stop = start + length
    request_blocks = math.ceil(stop / block)
    source_ids = (9, 7, 11, 5, 13, 3, 15, 1, 17, 19)[: math.ceil(request_blocks / dcp)]
    destination_ids = tuple(range(20, 20 + request_blocks))
    indexer_ids = tuple(range(40, 40 + request_blocks))
    physical_order = [p * ptp + t for t in range(ptp) for p in range(pcp)]
    source_caches = {}
    source_regions = []
    for ordinal, physical_rank in enumerate(physical_order):
        cache = [torch.full((capacity, block), -3, dtype=torch.bfloat16) for _ in range(2)]
        indexer = torch.full((capacity * dcp, block), -3, dtype=torch.bfloat16)
        for virtual_block, block_id in enumerate(source_ids):
            global_block = virtual_block * dcp + ordinal % dcp
            for position in range(block):
                for component, tensor in enumerate(cache):
                    tensor[block_id, position] = global_block * block + position + 100 * component
            for offset in range(dcp * block):
                indexer.view(capacity, dcp * block)[block_id, offset] = virtual_block * dcp * block + offset
        source_caches[physical_rank] = (*cache, indexer)
        source_regions.extend(
            (tensor.data_ptr(), tensor.data_ptr() + tensor.numel() * 2) for tensor in (*cache, indexer)
        )

    host = [torch.full((capacity, block), -1, dtype=torch.bfloat16) for _ in range(2)]
    expected_host = [tensor.clone() for tensor in host]
    for token in range(start, stop):
        ordinal, offset = divmod(token, block)
        for component, tensor in enumerate(expected_host):
            tensor[destination_ids[ordinal], offset] = token + 100 * component
    written_main_bytes = set()
    notifications = defaultdict(int)
    expected_notifications = {}
    for rank in range(dtp):
        worker, thread, command = make_worker(rank, ptp, dcp, dtp)
        worker.block_size = block
        endpoints = tuple(RemoteEndpoint("127.0.0.1", 5000 + p, "prefill") for p in range(ptp * pcp))
        command = replace(
            command,
            source=replace(
                command.source,
                endpoints_by_prefill_rank=endpoints,
                remote_pcp_size=pcp,
                main_block_ids=source_ids,
                indexer_block_ids=source_ids,
                num_computed_tokens=start,
                num_external_tokens=length,
            ),
            main_host_block_ids=destination_ids,
            indexer_hbm_block_ids=indexer_ids,
        )
        local_indexer = torch.full((capacity, block), -1, dtype=torch.bfloat16)
        expected_indexer = local_indexer.clone()
        for token in range(start, stop):
            ordinal, offset = divmod(token, block)
            expected_indexer[indexer_ids[ordinal], offset] = token
        thread._dsa_main_local_layout = [
            DsaCacheLayout(MAIN, i, tensor.data_ptr(), 8, 8, 1, block, "bf16") for i, tensor in enumerate(host)
        ]
        thread._dsa_indexer_local_layout = [
            DsaCacheLayout(INDEXER, 0, local_indexer.data_ptr(), 8, 8, 1, block, "bf16")
        ]
        groups = thread.kv_group2layeridx
        thread.remote_metadata_hosts = {"prefill": {5000 + p: "127.0.0.1" for p in range(ptp * pcp)}}
        thread.remote_kv_group2layeridx = {"prefill": {5000 + p: groups for p in range(ptp * pcp)}}
        thread.kv_caches_base_addr = {
            "prefill": {
                5000 + p: [[cache[0].data_ptr(), cache[1].data_ptr()], [cache[2].data_ptr()]]
                for p, cache in source_caches.items()
            }
        }
        for attr, value in (
            ("remote_block_stride_per_addr", [[8, 8], [8]]),
            ("remote_block_size_scale", [[1, 1], [dcp]]),
            ("remote_block_len_per_addr", [[8, 8], [8]]),
            ("remote_cache_dtypes", [["bf16", "bf16"], ["bf16"]]),
            ("remote_num_blocks", capacity),
        ):
            setattr(thread, attr, {"prefill": {5000 + p: value for p in range(ptp * pcp)}})
        thread.remote_te_port = {"prefill": {5000 + p: 7000 + p for p in range(ptp * pcp)}}
        destination_regions = [
            (tensor.data_ptr(), tensor.data_ptr() + tensor.numel() * 2) for tensor in (*host, local_indexer)
        ]

        def transfer(_session, dsts, srcs, lengths, *, destination_regions=destination_regions):
            for src, dst, size in zip(srcs, dsts, lengths):
                assert any(begin <= src and src + size <= end for begin, end in source_regions)
                target = next(
                    i for i, (begin, end) in enumerate(destination_regions) if begin <= dst and dst + size <= end
                )
                if target < 2:
                    addresses = set(range(dst, dst + size))
                    assert not written_main_bytes.intersection(addresses)
                    written_main_bytes.update(addresses)
                ctypes.memmove(dst, src, size)
            return 0

        thread.engine.batch_transfer_sync_read.side_effect = transfer
        tasks = submit(worker, command)
        if dcp == 1:
            selected_pcp = worker._get_selected_pcp_rank(command.source.remote_request_id, pcp)
            assert all(
                (task["dsa_remote_endpoint"].remote_port - 5000) // ptp == selected_pcp
                for task in tasks
                if task["expected"]
            )
        for task in reversed(tasks):
            thread._handle_dsa_request(task)
        (result,) = worker.build_connector_worker_meta().results
        assert result.kind is DsaLocalResultKind.RECEIVE_COMPLETE
        torch.testing.assert_close(local_indexer, expected_indexer)
        for call in thread._send_done_recv_signal.call_args_list:
            _, _, port, counts = call.args
            if counts[port]["num"]:
                notifications[port] += 1
                expected_notifications[port] = counts[port]["num"]
    assert len(written_main_bytes) == length * 2 * len(host)
    for actual, expected in zip(host, expected_host):
        torch.testing.assert_close(actual, expected)
    assert dict(notifications) == expected_notifications


@pytest.mark.parametrize("pcp_rank", [0, 1])
def test_dsa_without_dcp_uses_the_same_pcp_replica_as_prefill(pcp_rank):
    worker, _, command = make_worker(ptp=4, dcp=1, dtp=2)
    endpoints = tuple(RemoteEndpoint("127.0.0.1", 5000 + rank, "prefill") for rank in range(8))
    command = replace(command, source=replace(command.source, remote_pcp_size=2, endpoints_by_prefill_rank=endpoints))
    with patch.object(worker, "_get_selected_pcp_rank", return_value=pcp_rank) as select:
        plan = worker._plan_dsa_endpoints(command)
    select.assert_called_once_with(command.source.remote_request_id, 2)
    assert all(rank // 4 == pcp_rank for rank, _, _, _, expected, _ in plan if expected)
    assert {pp for _, _, pp, _, expected, _ in plan if expected} == {0}
