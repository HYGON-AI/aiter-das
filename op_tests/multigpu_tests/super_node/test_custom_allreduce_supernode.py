# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Multi-node functional test for the custom-allreduce fabric transport.

Launch one torchrun agent on each four-GPU node. For two nodes use ``--nnodes=2``
and node ranks 0/1; for eight nodes use ``--nnodes=8`` and node ranks 0..7.
Example (same command on all nodes, with a different ``--node-rank``):

    AITER_AR_TRANSPORT=fabric HIP_VISIBLE_DEVICES=0,1,2,3 \
      torchrun --nnodes=8 --nproc-per-node=4 --node-rank=<0..7> \
      --master-addr=<node0-em1-ip> --master-port=29610 \
      op_tests/multigpu_tests/super_node/test_custom_allreduce_supernode.py \
      --expect-world-size=32

The test disables QuickAllReduce after initialization and asserts the selected
CustomAllreduce transport so a passing result cannot be produced by QR/PyNccl.
"""

import argparse
import os

import torch
import torch.distributed as dist
import aiter.dist.device_communicators.custom_all_reduce as custom_ar_module

from aiter.dist.communication_op import tensor_model_parallel_all_reduce
from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
from aiter.dist.parallel_state import (
    destroy_distributed_environment,
    destroy_model_parallel,
    ensure_model_parallel_initialized,
    get_tp_group,
    graph_capture,
    init_distributed_environment,
    set_custom_all_reduce,
)


DTYPES = {
    "fp16": torch.float16,
    "bf16": torch.bfloat16,
    "fp32": torch.float32,
}


def parse_shape(value: str) -> tuple[int, ...]:
    shape = tuple(int(x) for x in value.split(","))
    if not shape or any(x <= 0 for x in shape):
        raise argparse.ArgumentTypeError(f"invalid shape: {value}")
    return shape


def parse_args() -> argparse.Namespace:
    parser = argparse.ArgumentParser()
    parser.add_argument(
        "--transport",
        choices=("ipc", "fabric", "auto"),
        default=os.environ.get("AITER_AR_TRANSPORT", "fabric").lower(),
    )
    parser.add_argument(
        "--shape",
        action="append",
        type=parse_shape,
        default=None,
        help="repeatable comma-separated shape; defaults to 2,7168 and 128,8192",
    )
    parser.add_argument(
        "--dtype",
        action="append",
        choices=tuple(DTYPES),
        default=None,
    )
    parser.add_argument("--repeats", type=int, default=5)
    parser.add_argument("--with-graph", action="store_true")
    parser.add_argument(
        "--dist-backend",
        choices=("nccl", "gloo"),
        default="nccl",
        help="torch.distributed control-plane backend",
    )
    parser.add_argument(
        "--direct-custom-ar",
        action="store_true",
        help="construct CustomAllreduce directly without model-parallel fallback communicators",
    )
    parser.add_argument(
        "--direct-max-size-mib",
        type=int,
        default=8,
        help="registered input/temp buffer size for direct mode (default: 8 MiB)",
    )
    parser.add_argument(
        "--direct-max-size-kib",
        type=int,
        default=None,
        help="override the direct-mode buffer size in KiB for tiny smoke tests",
    )
    parser.add_argument(
        "--expect-world-size",
        type=int,
        default=None,
        help="assert the torchrun world size (use 32 for eight nodes, 40 for ten)",
    )
    parser.add_argument(
        "--expect-transport",
        choices=("ipc", "fabric"),
        default=None,
        help="override the selected transport assertion (use ipc for single-node auto)",
    )
    return parser.parse_args()


def assert_close(actual: torch.Tensor, expected: torch.Tensor, label: str) -> None:
    torch.testing.assert_close(actual, expected, rtol=1e-3, atol=1e-3, msg=label)


def run_graph_case(inp: torch.Tensor) -> torch.Tensor:
    graph = torch.cuda.CUDAGraph()
    with graph_capture() as gc:
        with torch.cuda.graph(graph, stream=gc.stream):
            out = tensor_model_parallel_all_reduce(inp)
    graph.replay()
    torch.cuda.synchronize()
    return out.clone()


def main() -> None:
    args = parse_args()
    if args.repeats <= 0:
        raise ValueError("--repeats must be positive")
    if args.direct_max_size_mib <= 0:
        raise ValueError("--direct-max-size-mib must be positive")
    if args.direct_max_size_kib is not None and args.direct_max_size_kib <= 0:
        raise ValueError("--direct-max-size-kib must be positive")

    rank = int(os.environ["RANK"])
    local_rank = int(os.environ["LOCAL_RANK"])
    world_size = int(os.environ["WORLD_SIZE"])
    print(
        f"STAGE rank={rank} custom_ar_module={custom_ar_module.__file__}",
        flush=True,
    )
    if world_size not in (2, 4, 6, 8, 16, 32, 40):
        raise RuntimeError(f"custom allreduce does not support world_size={world_size}")
    if args.expect_world_size is not None and world_size != args.expect_world_size:
        raise RuntimeError(
            f"expected world_size={args.expect_world_size}, got {world_size}"
        )

    os.environ["AITER_AR_TRANSPORT"] = args.transport
    if args.direct_custom_ar:
        os.environ["AITER_AR_DEBUG_STAGES"] = "1"
    # Fabric graph mode intentionally uses the pre-registered copy-in buffer.
    os.environ["AITER_AR_ENABLE_REG_CAPTURE"] = "0"
    torch.cuda.set_device(local_rank)
    set_custom_all_reduce(True)

    initialized = False
    direct_ca = None
    try:
        print(
            f"STAGE rank={rank} distributed_init_begin backend={args.dist_backend}",
            flush=True,
        )
        if args.direct_custom_ar:
            if args.with_graph:
                raise ValueError("--direct-custom-ar does not support --with-graph")
            dist.init_process_group(
                backend=args.dist_backend,
                init_method="env://",
                world_size=world_size,
                rank=rank,
            )
            initialized = True
            print(f"STAGE rank={rank} distributed_init_done", flush=True)
            direct_ca = CustomAllreduce(
                group=dist.group.WORLD,
                device=torch.device(f"cuda:{local_rank}"),
                max_size=(
                    args.direct_max_size_kib * 1024
                    if args.direct_max_size_kib is not None
                    else args.direct_max_size_mib * 1024 * 1024
                ),
                enable_register_for_capturing=False,
            )
            ca = direct_ca
            communicator = None
            barrier_group = dist.group.WORLD
        else:
            init_distributed_environment(
                world_size=world_size,
                rank=rank,
                local_rank=local_rank,
                distributed_init_method="env://",
                backend=args.dist_backend,
            )
            initialized = True
            print(f"STAGE rank={rank} distributed_init_done", flush=True)
            ensure_model_parallel_initialized(world_size, 1, backend=args.dist_backend)
            print(f"STAGE rank={rank} model_parallel_init_done", flush=True)

            tp = get_tp_group()
            communicator = tp.device_communicator
            if communicator is None or communicator.ca_comm is None:
                raise RuntimeError("CustomAllreduce communicator was not created")
            ca = communicator.ca_comm
            barrier_group = tp.cpu_group
        if ca.disabled:
            raise RuntimeError("CustomAllreduce communicator is disabled")
        expected_transport = args.expect_transport or (
            "ipc" if args.transport == "ipc" else "fabric"
        )
        if ca.transport != expected_transport:
            raise RuntimeError(
                f"expected selected transport={expected_transport}, got {ca.transport!r} "
                f"(requested={ca.requested_transport!r})"
            )
        print(
            f"STAGE rank={rank} custom_ar_ready transport={ca.transport}",
            flush=True,
        )

        # Prevent a high-level call from passing through QuickAllReduce first.
        if communicator is not None and communicator.qr_comm is not None:
            communicator.qr_comm.disabled = True

        shapes = args.shape or [(2, 7168), (128, 8192)]
        dtypes = [DTYPES[x] for x in (args.dtype or ["fp16", "bf16"])]
        expected_value = world_size * (world_size + 1) / 2

        for dtype in dtypes:
            for shape in shapes:
                for repeat in range(args.repeats):
                    print(
                        f"STAGE rank={rank} allreduce_begin repeat={repeat} "
                        f"dtype={dtype} shape={shape}",
                        flush=True,
                    )
                    inp = torch.full(
                        shape,
                        float(rank + 1),
                        dtype=dtype,
                        device=f"cuda:{local_rank}",
                    )
                    out = (
                        ca.custom_all_reduce(inp)
                        if args.direct_custom_ar
                        else tensor_model_parallel_all_reduce(inp)
                    )
                    if out is None:
                        raise RuntimeError("CustomAllreduce did not accept the test tensor")
                    torch.cuda.synchronize()
                    expected = torch.full_like(out, expected_value)
                    assert_close(
                        out,
                        expected,
                        f"eager rank={rank} dtype={dtype} shape={shape} repeat={repeat}",
                    )

                if args.with_graph:
                    graph_inp = torch.full(
                        shape,
                        float(rank + 1),
                        dtype=dtype,
                        device=f"cuda:{local_rank}",
                    )
                    graph_out = run_graph_case(graph_inp)
                    expected = torch.full_like(graph_out, expected_value)
                    assert_close(
                        graph_out,
                        expected,
                        f"graph rank={rank} dtype={dtype} shape={shape}",
                    )

                print(
                    f"rank={rank} transport={ca.transport} dtype={dtype} "
                    f"shape={shape} repeats={args.repeats} graph={args.with_graph} PASS",
                    flush=True,
                )

        dist.barrier(group=barrier_group)
        if rank == 0:
            print(
                "SUPERNODE_CUSTOM_AR_PASS "
                f"world_size={world_size} transport={ca.transport}",
                flush=True,
            )
    finally:
        if initialized and dist.is_initialized():
            if args.direct_custom_ar:
                if direct_ca is not None:
                    direct_ca.close()
                dist.destroy_process_group()
            else:
                destroy_model_parallel()
                destroy_distributed_environment()


if __name__ == "__main__":
    main()
