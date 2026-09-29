# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""Direct native collective graph replay with registration disabled.

Example for the four-rank TP group in a Fabric supernode:
    AITER_AR_TRANSPORT=fabric torchrun --standalone --nproc-per-node=4 \
      op_tests/multigpu_tests/super_node/test_custom_allreduce_graph_copyin.py

Also accepts multi-node torchrun launches with a total of 2, 4 or 8 ranks.
No high-level communicator fallback is used.
"""

import argparse
from datetime import timedelta
import hashlib
import os
from pathlib import Path

import torch
import torch.distributed as dist

import aiter as ops
import aiter.dist.device_communicators.custom_all_reduce as custom_ar


def run_case(ca, rank, world_size, dtype, repeats):
    device = ca.device
    # The fused RMSNorm kernel requires at least 64 packs: 512 FP16/BF16 values.
    shape = (2 * world_size, 512)
    base = (torch.arange(shape[-1], device=device, dtype=torch.float32) % 8) / 8
    base = base.expand(shape).contiguous()
    inp = torch.empty(shape, dtype=dtype, device=device)
    residual = torch.empty_like(inp)
    weight = torch.linspace(0.5, 1.5, shape[-1], device=device, dtype=dtype)
    rs_out = torch.empty((2, shape[-1]), dtype=dtype, device=device)
    eps = 1e-6

    def collectives():
        ar_out = ca.custom_all_reduce(inp)
        ag_first = ca.custom_all_gather(inp, dim=0)
        ag_last = ca.custom_all_gather(inp, dim=-1)
        # reduce_scatter fills its supplied output and returns None.
        ca.custom_reduce_scatter(inp, rs_out)
        return (
            ar_out, ag_first, ag_last, rs_out,
            ca.custom_fused_ar_rms(inp, residual, weight, eps),
        )

    inp.copy_((base + rank + 1).to(dtype))
    residual.fill_(0.25)
    print(f"GRAPH_COPYIN_EAGER rank={rank} dtype={dtype} shape={shape}", flush=True)
    collectives()  # Initialize native paths outside capture.
    torch.cuda.synchronize()
    dist.barrier()
    graph = torch.cuda.CUDAGraph()
    with ca.capture():
        # Exercise the graph-context warmup contract as well as capture.
        assert ca.custom_all_gather(inp, dim=0).shape == (shape[0] * world_size, shape[1])
        assert ca.custom_all_gather(inp, dim=-1).shape == (shape[0], shape[1] * world_size)
        with torch.cuda.graph(graph):
            ar_out, ag_first, ag_last, rs_out, (norm_out, res_out) = collectives()
        pending = ops.get_graph_buffer_count(ca._ptr)
        if pending != 0:
            raise AssertionError(
                f"rank={rank}: copy-in capture queued {pending} graph addresses"
            )
    print(
        f"GRAPH_COPYIN_CAPTURE rank={rank} dtype={dtype} "
        f"shape={shape} pending={pending}",
        flush=True,
    )

    for repeat in range(repeats):
        # References use the same per-rank low-precision inputs. Changing the
        # inputs on every replay also detects captured/stale staging contents.
        inputs = [
            (base + (r + 1) * (repeat + 1)).to(dtype) for r in range(world_size)
        ]
        inp.copy_(inputs[rank])
        residual.fill_((rank + repeat + 1) / 4)
        dist.barrier()
        graph.replay()
        torch.cuda.synchronize()

        reduced = torch.stack([x.float() for x in inputs]).sum(dim=0)
        summed = reduced + residual.float()
        norm = summed * torch.rsqrt(summed.square().mean(dim=-1, keepdim=True) + eps)
        norm = norm * weight.float()
        expected = (
            ("all_reduce", ar_out, reduced.to(dtype)),
            ("all_gather_dim0", ag_first, torch.cat(inputs, dim=0)),
            ("all_gather_dim_last", ag_last, torch.cat(inputs, dim=-1)),
            (
                "reduce_scatter", rs_out,
                reduced.chunk(world_size, dim=0)[rank].to(dtype),
            ),
            ("fused_rmsnorm", norm_out, norm.to(dtype)),
            ("fused_residual", res_out, summed.to(dtype)),
        )
        tolerance = 1e-2 if dtype == torch.bfloat16 else 1e-3
        for name, actual, reference in expected:
            torch.testing.assert_close(
                actual, reference,
                rtol=tolerance, atol=tolerance,
                msg=f"rank={rank} dtype={dtype} repeat={repeat} op={name}",
            )
    dist.barrier()
    print(
        f"GRAPH_COPYIN_PASS rank={rank} transport={ca.transport} "
        f"dtype={dtype} replays={repeats}",
        flush=True,
    )


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument(
        "--transport", choices=("ipc", "fabric"),
        default=os.environ.get("AITER_AR_TRANSPORT", "fabric"),
    )
    parser.add_argument("--repeats", type=int, default=3)
    args = parser.parse_args()
    if args.repeats < 2:
        parser.error("--repeats must be at least 2 to check changing inputs")
    os.environ["AITER_AR_TRANSPORT"] = args.transport
    rank, local_rank, world_size = (
        int(os.environ[k]) for k in ("RANK", "LOCAL_RANK", "WORLD_SIZE")
    )
    if world_size not in (2, 4, 8):
        raise ValueError("combined all-gather/reduce-scatter test requires 2, 4 or 8 ranks")
    torch.cuda.set_device(local_rank)
    source = Path(custom_ar.__file__).resolve()
    print(
        f"GRAPH_COPYIN_SOURCE rank={rank} path={source} "
        f"sha256={hashlib.sha256(source.read_bytes()).hexdigest()}",
        flush=True,
    )
    dist.init_process_group("gloo", timeout=timedelta(seconds=120))
    ca = None
    try:
        ca = custom_ar.CustomAllreduce(
            group=dist.group.WORLD,
            device=torch.device(f"cuda:{local_rank}"),
            max_size=1024 * 1024,
            enable_register_for_capturing=False,
        )
        if ca.disabled or ca.transport != args.transport:
            raise RuntimeError(
                f"expected active {args.transport}, got disabled={ca.disabled} "
                f"transport={ca.transport}"
            )
        assert not ca.enable_register_for_capturing
        for dtype in (torch.float16, torch.bfloat16):
            run_case(ca, rank, world_size, dtype, args.repeats)
        if rank == 0:
            print(
                f"CUSTOM_AR_GRAPH_COPYIN_PASS world_size={world_size} "
                f"transport={ca.transport}",
                flush=True,
            )
    finally:
        if ca is not None:
            ca.close()
        dist.destroy_process_group()


if __name__ == "__main__":
    main()
