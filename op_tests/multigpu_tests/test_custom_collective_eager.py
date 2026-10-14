# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

"""AG/RS eager binding contracts: live storage, streams, compile and fallback.

Run with torchrun --nproc_per_node=2 (also supports TP4/TP8).
The exhaustive numeric and Graph-reuse tests remain in the AG/RS test scripts.
"""
import argparse
from datetime import timedelta
import hashlib
import json
import os
from pathlib import Path
import sys

import torch
import torch.distributed as dist

from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
from aiter.jit import core
from aiter.ops import custom_all_reduce as ops
from aiter.utility.dtypes import FP8_DTYPES


NAMES = ("all_gather_unreg", "all_gather_reg", "reduce_scatter_dim", "reduce_scatter_8bit")


def exact(actual, expected):
    assert torch.equal(actual.view(torch.uint8).cpu(), expected.view(torch.uint8))


def expect_error(fn):
    try:
        fn()
    except (ValueError, TypeError, RuntimeError, AssertionError):
        return
    raise AssertionError("expected rejection before collective launch")


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--output", required=True)
    args = parser.parse_args()
    rank, local, world = (int(os.environ[k]) for k in ("RANK", "LOCAL_RANK", "WORLD_SIZE"))
    torch.cuda.set_device(local)
    device = torch.device("cuda", local)
    dist.init_process_group("gloo", timeout=timedelta(seconds=180))
    ca = CustomAllreduce(dist.group.WORLD, local, max_size=64 << 20,
                         enable_register_for_capturing=True)
    assert not ca.disabled
    native = core.get_module("module_custom_all_reduce")
    guard = sys.modules[core.torch_compile_guard.__module__]
    saved_direct = guard.EAGER_DIRECT_OP.copy()
    bindings = {name: getattr(native, name + "_tensor") for name in NAMES}
    saved_stream = native._set_current_hip_stream
    stream_seen = []

    def record_stream(value):
        stream_seen.append(value)
        saved_stream(value)

    def wrap(binding):
        def call(*args, **kwargs):
            stream_seen.append(kwargs["stream_ptr"])
            return binding(*args, **kwargs)
        return call

    def select(mode):
        guard.EAGER_DIRECT_OP.clear()
        guard.EAGER_DIRECT_OP.update(saved_direct)
        if mode == "baseline":
            guard.EAGER_DIRECT_OP.difference_update(NAMES)
        for name, binding in bindings.items():
            setattr(native, name + "_tensor", wrap(binding) if mode == "final" else None)
        native._set_current_hip_stream = record_stream

    report = dict(rank=rank, world=world, arch=torch.cuda.get_device_properties(local).gcnArchName,
                  cases=0, compiled=[], modes=[], effective_registered=ca.enable_register_for_capturing)
    try:
        streams = [torch.cuda.Stream(device=device), torch.cuda.Stream(device=device)]
        for mode in ("baseline", "quick", "final"):
            select(mode)
            for op in ("ag", "rs"):
                for dtype in (torch.int8, *FP8_DTYPES, torch.float16, torch.bfloat16, torch.float32):
                    inp = torch.empty(0, dtype=dtype, device=device)
                    out = torch.empty_like(inp)
                    for dim in (0, 1):
                        for iteration, shape in enumerate(((16, 512), (8, 1024), (16, 256), (8, 512))):
                            outshape = list(shape)
                            outshape[dim] = outshape[dim] * world if op == "ag" else outshape[dim] // world
                            # Same Tensor objects, different backing storage, offset and shape.
                            backing = torch.empty(shape[0] * shape[1] + 64, dtype=dtype, device=device)
                            output_backing = torch.empty(outshape[0] * outshape[1] + 64, dtype=dtype, device=device)
                            inp.set_(backing.untyped_storage(), 1, shape, (shape[1], 1))
                            out.set_(output_backing.untyped_storage(), 16, outshape, (outshape[1], 1))
                            values = [torch.full(shape, (r + iteration) % 7 - 3, dtype=torch.float32).to(dtype)
                                      for r in range(world)]
                            want = (torch.cat([v.view(torch.uint8) for v in values], dim).view(dtype)
                                    if op == "ag" else
                                    sum(v.float() for v in values).chunk(world, dim)[rank].contiguous().to(dtype))
                            stream = streams[iteration % 2]
                            stream.wait_stream(torch.cuda.current_stream())
                            with torch.cuda.stream(stream):
                                inp.copy_(values[rank])
                                stream_seen.clear()
                                if op == "ag":
                                    ca.all_gather_unreg(inp, out, dim)
                                else:
                                    ca.reduce_scatter(inp, out, dim)
                                assert stream_seen[-1] == stream.cuda_stream, stream_seen
                                inp.view(torch.uint8).fill_(0xA5)
                            stream.synchronize()
                            exact(out, want)
                            report["cases"] += 1
            report["modes"].append(mode)

        # Final bindings retain the registered opaque op under fullgraph tracing.
        select("final")
        reg, capacity, handle = ca._pool["input"].data_ptr, ca._pool["input"].max_size, ca._ptr

        def ag(inp, out):
            ops.all_gather_unreg(_fa=handle, inp=inp, reg_buffer=reg, out=out, reg_bytes=capacity, dim=0)
            return out

        def rs8(inp, out):
            ops.reduce_scatter_8bit(handle, inp, out, 0, 0, inp.numel(), 0, reg, capacity, 0)
            return out

        def rs_float(inp, out):
            ops.reduce_scatter_dim(handle, inp, out, 0, 0, inp.numel(), 0, reg, capacity)
            return out

        def ag_registered(inp, out):
            ops.all_gather_reg(handle, inp, out, 0)
            return out

        for name, fn, dtype in (("all_gather_unreg", ag, torch.uint8),
                                ("reduce_scatter_8bit", rs8, torch.uint8),
                                ("reduce_scatter_dim", rs_float, torch.float32)):
            graphs = []

            def backend(gm, inputs):
                graphs.append(str(gm.graph))
                assert any(name in str(node.target) for node in gm.graph.nodes)
                return gm.forward

            for compiler in (backend, "inductor"):
                compiled = torch.compile(fn, backend=compiler, fullgraph=True)
                for iteration in range(3):
                    inp = torch.full((256,), rank + iteration, dtype=dtype, device=device)
                    out = torch.empty((256 * world if name == "all_gather_unreg" else 256 // world,),
                                      dtype=dtype, device=device)
                    compiled(inp, out)
                    want = (torch.cat([torch.full((256,), r + iteration, dtype=dtype) for r in range(world)])
                            if name == "all_gather_unreg" else
                            torch.full(out.shape, sum(r + iteration for r in range(world)), dtype=dtype))
                    exact(out, want)
            assert graphs
            report["compiled"].append(name)

        # DTK must use copy-in: inspect the registered API's graph without running
        # an unsafe direct peer read. The public all_gather_reg redirect is covered
        # by test_custom_allgather.py on both architectures.
        inp = torch.empty(256, dtype=torch.uint8, device=device)
        out = torch.empty(256 * world, dtype=torch.uint8, device=device)
        exported = torch._dynamo.export(ag_registered)(inp, out)
        assert "all_gather_reg" in str(exported.graph_module.graph)
        report["registered_export"] = True

        # Rejections from the new metadata bridge happen before it reads a handle.
        for bad in (object(), torch.empty((1,) * 9), torch.empty(16, dtype=torch.float64)):
            expect_error(lambda: bindings["all_gather_unreg"](0, bad, 0, out, 0, 0, 0))
        for dtype in (torch.float8_e4m3fnuz, torch.float8_e5m2fnuz):
            bad = torch.empty(16, dtype=dtype, device=device)
            expect_error(lambda: bindings["all_gather_unreg"](0, bad, 0, out, 0, 0, 0))
        bad = torch.empty(256, dtype=torch.float8_e5m2, device=device)
        bad_out = torch.empty(256 // world, dtype=bad.dtype, device=device)
        bad_out.view(torch.uint8).fill_(0xA5)
        for mode in ('baseline', 'final'):
            select(mode)
            expect_error(lambda: ops.reduce_scatter_dim(handle, bad, bad_out, 0, 0, bad.numel(), 0, reg, capacity))
            assert (bad_out.view(torch.uint8) == 0xA5).all().item()
        report["bridge_rejections"] = 7
    finally:
        guard.EAGER_DIRECT_OP.clear()
        guard.EAGER_DIRECT_OP.update(saved_direct)
        for name, binding in bindings.items():
            setattr(native, name + "_tensor", binding)
        native._set_current_hip_stream = saved_stream
        ca.close()
    report["native"] = {native.__file__: hashlib.sha256(Path(native.__file__).read_bytes()).hexdigest()}
    report["status"] = "passed"
    directory = Path(args.output)
    directory.mkdir(parents=True, exist_ok=True)
    (directory / f"rank{rank}.json").write_text(json.dumps(report, indent=2) + "\n")
    dist.barrier()
    dist.destroy_process_group()
    print("EAGER_CONTRACT_PASS", json.dumps(report), flush=True)


if __name__ == "__main__":
    main()
