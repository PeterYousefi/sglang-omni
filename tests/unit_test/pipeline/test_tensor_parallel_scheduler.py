# SPDX-License-Identifier: Apache-2.0
"""Collective ordering during cancellation and shutdown."""

import multiprocessing
import threading
from pathlib import Path
from typing import Literal

import pytest
import torch

from sglang_omni.scheduling.message import IncomingMessage
from sglang_omni.scheduling.tensor_parallel_scheduler import TensorParallelScheduler
from tests.unit_test.fixtures.process_failure import drain_collective_worker


@pytest.mark.parametrize(
    "backend", ["gloo", pytest.param("nccl", marks=pytest.mark.accelerator)]
)
def test_distributed_abort_and_stop_drain_dispatched_collectives(
    tmp_path: Path,
    backend: Literal["gloo", "nccl"],
) -> None:
    """Skipping a cancelled queued forward strands its peer in an all-reduce."""
    if backend == "nccl" and torch.cuda.device_count() < 2:
        pytest.skip("Requires two CUDA devices")
    else:
        pass
    context = multiprocessing.get_context("spawn")
    collective_entered = context.Event()
    stop_requested = context.Event()
    processes = [
        context.Process(
            target=drain_collective_worker,
            args=(
                rank,
                backend,
                (tmp_path / "rendezvous").as_uri(),
                collective_entered,
                stop_requested,
            ),
        )
        for rank in range(2)
    ]
    try:
        for process in processes:
            process.start()
        assert collective_entered.wait(30)
        stop_requested.set()
        for process in processes:
            process.join(timeout=40)
            assert process.exitcode == 0
    finally:
        stop_requested.set()
        for process in processes:
            if process.pid is not None:
                if process.is_alive():
                    process.kill()
                else:
                    pass
                process.join(timeout=5)
                process.close()
            else:
                pass


def request(request_id: str) -> IncomingMessage:
    return IncomingMessage(request_id=request_id, type="new_request", data=request_id)


def test_asymmetric_abort_preserves_collective_order() -> None:
    collective = threading.Barrier(2, timeout=3)
    entered = threading.Event()
    calls: list[list[str]] = [[], []]

    def compute(rank: int, request_id: str) -> str:
        calls[rank].append(request_id)
        entered.set()
        collective.wait()
        return request_id

    schedulers = [
        TensorParallelScheduler(
            lambda value, rank=rank: compute(rank, value),
            shutdown_join_timeout_s=5.0,
        )
        for rank in range(2)
    ]
    threads = [
        threading.Thread(target=scheduler.start, daemon=True)
        for scheduler in schedulers
    ]
    for scheduler in schedulers:
        scheduler.inbox.put(request("cancelled"))
        scheduler.inbox.put(request("next"))
    try:
        threads[0].start()
        assert entered.wait(2)
        # note (Wes): Rank one must execute the cancelled forward to release rank zero's collective.
        schedulers[0].abort("cancelled")
        schedulers[1].abort("cancelled")
        for scheduler in schedulers:
            scheduler.stop()
        threads[1].start()
        for scheduler in schedulers:
            assert scheduler.outbox.get(timeout=4).data == "cancelled"
            assert scheduler.outbox.get(timeout=4).data == "next"
        assert calls == [["cancelled", "next"], ["cancelled", "next"]]
    finally:
        for scheduler in schedulers:
            scheduler.stop()
        for thread in threads:
            if thread.ident is not None:
                thread.join(timeout=4)
            else:
                pass
    assert all(not thread.is_alive() for thread in threads)


def test_shutdown_drains_work_before_cleanup_on_compute_thread() -> None:
    entered = threading.Event()
    release = threading.Event()
    events: list[str] = []
    cleanup_threads: list[int] = []

    def compute(request_id: str) -> str:
        if request_id == "active":
            entered.set()
            assert release.wait(3)
        else:
            pass
        events.append(request_id)
        return request_id

    def cleanup() -> None:
        events.append("cleanup")
        cleanup_threads.append(threading.get_ident())

    scheduler = TensorParallelScheduler(
        compute, shutdown_join_timeout_s=5.0, shutdown_callback=cleanup
    )
    thread = threading.Thread(target=scheduler.start, daemon=True)
    scheduler.inbox.put(request("active"))
    scheduler.inbox.put(request("queued"))
    thread.start()
    try:
        assert entered.wait(2)
        scheduler.stop()
        scheduler.stop()
        assert events == []
    finally:
        release.set()
        scheduler.stop()
        thread.join(timeout=4)
    assert not thread.is_alive()
    assert events == ["active", "queued", "cleanup"]
    assert cleanup_threads == [thread.ident]
    scheduler.stop()
    assert events.count("cleanup") == 1


def test_stop_before_thread_start_still_drains_and_cleans_up() -> None:
    events: list[str] = []
    scheduler = TensorParallelScheduler(
        lambda value: events.append(value),
        shutdown_join_timeout_s=5.0,
        shutdown_callback=lambda: events.append("cleanup"),
    )
    scheduler.abort("queued")
    scheduler.inbox.put(request("queued"))
    scheduler.stop()
    thread = threading.Thread(target=scheduler.start, daemon=True)
    thread.start()
    thread.join(timeout=3)
    assert not thread.is_alive()
    assert events == ["queued", "cleanup"]


def test_failure_is_reported_while_cleanup_is_blocked() -> None:
    cleanup_entered = threading.Event()
    release_cleanup = threading.Event()
    failures: list[BaseException] = []
    errors: list[RuntimeError] = []

    def compute(value: str) -> str:
        raise RuntimeError("rank-local allocation failed")

    def cleanup() -> None:
        cleanup_entered.set()
        assert release_cleanup.wait(3)

    scheduler = TensorParallelScheduler(
        compute, shutdown_join_timeout_s=5.0, shutdown_callback=cleanup
    )
    scheduler.failure_callback = failures.append
    scheduler.inbox.put(request("failed"))

    def run() -> None:
        try:
            scheduler.start()
        except RuntimeError as exc:
            errors.append(exc)

    thread = threading.Thread(target=run, daemon=True)
    thread.start()
    try:
        assert cleanup_entered.wait(2)
        assert thread.is_alive()
        assert len(failures) == 1
        assert str(failures[0].__cause__) == "rank-local allocation failed"
        assert scheduler.shutdown_join_timeout_s is None
        assert scheduler.outbox.get_nowait().type == "error"
    finally:
        release_cleanup.set()
        thread.join(timeout=4)
    assert not thread.is_alive()
    assert errors == failures


def test_forward_failure_does_not_reuse_collectives_for_the_next_request() -> None:
    calls: list[str] = []

    def compute(request_id: str) -> str:
        calls.append(request_id)
        raise RuntimeError("rank-local allocation failed")

    scheduler = TensorParallelScheduler(
        compute,
        shutdown_join_timeout_s=5.0,
        shutdown_callback=lambda: calls.append("cleanup"),
    )
    scheduler.inbox.put(request("failed"))
    scheduler.inbox.put(request("next"))
    with pytest.raises(RuntimeError, match="collective sequence cannot be reused"):
        scheduler.start()
    assert calls == ["failed", "cleanup"]
    error = scheduler.outbox.get_nowait()
    assert error.request_id == "failed"
    assert error.type == "error"
