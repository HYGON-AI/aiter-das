# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Small, staged tests of the four framework-used AITER IPC collectives.

Run from an installed/source AITER environment; no scratch helpers are imported.
PMD setup (before starting Python, each GPU's XCD count is independent of TP):
  export ROCM_PATH=/opt/rocm PMD_PATH=/opt/rocm/pmd GPU_ARCHS=gfx946
  export AITER_ENABLE_SUPERNODE_AR=0  # IPC only; this PMD SDK lacks Fabric headers
  export LD_LIBRARY_PATH=/opt/rocm/lib:/opt/rocm/pmd:${LD_LIBRARY_PATH:-}
  export GPU_CHIP=sb GPU_ARGS="['--num-gpu=2']"
  unset HIP_VISIBLE_DEVICES ROCR_VISIBLE_DEVICES CUDA_VISIBLE_DEVICES
  mkdir -p aiter/jit/build  # Normal JIT output directory in a source checkout
  python op_tests/gfx946_tests/normal_communication/test_normal_communication.py --stage build --timeout 900
  python op_tests/gfx946_tests/normal_communication/test_normal_communication.py --stage devices
  python op_tests/gfx946_tests/normal_communication/test_normal_communication.py --stage ipc
  python op_tests/gfx946_tests/normal_communication/test_normal_communication.py --stage init
  python op_tests/gfx946_tests/normal_communication/test_normal_communication.py --stage collectives

Repeat devices/ipc/init/collectives with GPU_CHIP=sbx2 (and optionally sbx4),
--expect-xcds 2 (or 4). Do not run dependent stages after a failed prerequisite.
For route evidence, set GPU_DFLAGS="['StatLog']" and AITER_COMM_LOG_LAUNCH=1,
then use --suite route --dtypes bf16 --ops <one API> --die-mode linear.
Inspect per-XCD completedWGs/TG counters: numerical PASS alone is insufficient.
The same suite supports --require-arch gfx938/gfx936 for physical-GPU regression.
Gloo exchanges only CPU control metadata; every numerical result is from AITER.
No RCCL/CPU numerical fallback, warmup, benchmark loop, or Graph claim is made.
Exit codes: 0 PASS, 1 failure, 2 communicator unavailable, 124 wall-clock timeout.
"""

import argparse
import ctypes as C
import hashlib
import json
import math
import multiprocessing as mp
import os
from pathlib import Path
import socket
import time
import traceback
from datetime import timedelta


OPS = ("all_gather_reg", "all_gather_unreg", "custom_all_reduce", "reduce_scatter")


def report(event, **fields):
    print(json.dumps(dict(event=event, **fields), sort_keys=True), flush=True)


def hip_runtime():
    hip = C.CDLL("libamdhip64.so")
    hip.hipGetErrorString.argtypes = [C.c_int]
    hip.hipGetErrorString.restype = C.c_char_p
    hip.hipSetDevice.argtypes = [C.c_int]
    hip.hipMalloc.argtypes = [C.POINTER(C.c_void_p), C.c_size_t]
    hip.hipFree.argtypes = [C.c_void_p]
    hip.hipIpcGetMemHandle.argtypes = [C.c_void_p, C.c_void_p]
    # hipIpcMemHandle_t is passed by value, not as a pointer.
    class Handle(C.Structure):
        _fields_ = [("reserved", C.c_char * 64)]
    hip.hipIpcOpenMemHandle.argtypes = [C.POINTER(C.c_void_p), Handle, C.c_uint]
    hip.hipIpcCloseMemHandle.argtypes = [C.c_void_p]
    hip.hipMemcpy.argtypes = [C.c_void_p, C.c_void_p, C.c_size_t, C.c_int]
    return hip, Handle


def hip_check(hip, code, operation):
    if code:
        raise RuntimeError(f"{operation}: HIP {code} {hip.hipGetErrorString(code).decode()}")


def query_xcds():
    class Agent(C.Structure):
        _fields_ = [("handle", C.c_uint64)]
    hsa = C.CDLL("libhsa-runtime64.so.1")
    callback = C.CFUNCTYPE(C.c_uint32, Agent, C.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, C.c_int, C.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback, C.c_void_p]
    records = []

    @callback
    def visit(agent, _):
        device, count = C.c_uint32(), C.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, C.byref(device))
        if status or device.value != 1:
            return status
        status = hsa.hsa_agent_get_info(agent, 0xA111, C.byref(count))
        if not status:
            records.append(count.value)
        return status

    if hsa.hsa_init():
        raise RuntimeError("hsa_init failed")
    try:
        if hsa.hsa_iterate_agents(visit, None):
            raise RuntimeError("HSA numXcc query failed")
    finally:
        hsa.hsa_shut_down()
    return records


def check_device(args, rank):
    import torch
    if torch.cuda.device_count() < args.world_size:
        raise RuntimeError(f"need {args.world_size} GPUs, found {torch.cuda.device_count()}")
    torch.cuda.set_device(rank)
    prop = torch.cuda.get_device_properties(rank)
    arch = prop.gcnArchName.split(":")[0]
    if arch != args.require_arch:
        raise RuntimeError(f"expected {args.require_arch}, got {arch}")
    if args.expect_xcds is not None:
        counts = query_xcds()
        if len(counts) < args.world_size or any(n != args.expect_xcds for n in counts):
            raise RuntimeError(f"expected {args.expect_xcds} XCDs per GPU, got {counts}")
        report("xcds", rank=rank, counts=counts)
    report("device", rank=rank, arch=arch, cu=prop.multi_processor_count,
           count=torch.cuda.device_count(), torch=torch.__version__, hip=torch.version.hip)


def ipc_worker(args, rank, pipe):
    hip, Handle = hip_runtime()
    hip_check(hip, hip.hipSetDevice(rank), "hipSetDevice")
    pointer = C.c_void_p()
    if rank == 0:
        hip_check(hip, hip.hipMalloc(C.byref(pointer), 4096), "hipMalloc")
        try:
            handle = Handle()
            hip_check(hip, hip.hipIpcGetMemHandle(C.byref(handle), pointer), "hipIpcGetMemHandle")
            report("ipc_export", rank=rank)
            pipe.send(bytes(handle))
            # Keep the allocation alive until the peer has closed its mapping.
            if not pipe.poll(args.timeout):
                raise TimeoutError("IPC peer did not finish")
            if pipe.recv() != "PASS":
                raise RuntimeError("peer IPC import/readback failed")
            # Verify sharing from the owner too: reading back only through the
            # imported pointer could miss a mapping to an unrelated allocation.
            readback = C.c_int()
            hip_check(hip, hip.hipMemcpy(C.byref(readback), pointer, 4, 2), "owner D2H")
            if readback.value != 1234567:
                raise AssertionError(f"owner IPC readback {readback.value}")
            report("ipc_owner_readback_pass", rank=rank, value=readback.value)
        finally:
            hip_check(hip, hip.hipFree(pointer), "hipFree")
    else:
        if not pipe.poll(args.timeout):
            raise TimeoutError("IPC owner did not export")
        try:
            handle = Handle.from_buffer_copy(pipe.recv())
            report("ipc_import_begin", rank=rank)
            hip_check(hip, hip.hipIpcOpenMemHandle(C.byref(pointer), handle, 1), "hipIpcOpenMemHandle")
            try:
                value, readback = C.c_int(1234567), C.c_int()
                hip_check(hip, hip.hipMemcpy(pointer, C.byref(value), 4, 1), "IPC H2D")
                hip_check(hip, hip.hipMemcpy(C.byref(readback), pointer, 4, 2), "IPC D2H")
                if readback.value != value.value:
                    raise AssertionError(f"IPC readback {readback.value}")
                report("ipc_readback_pass", rank=rank, value=readback.value)
            finally:
                hip_check(hip, hip.hipIpcCloseMemHandle(pointer), "hipIpcCloseMemHandle")
            pipe.send("PASS")
        except BaseException:
            pipe.send("FAIL")
            raise


def cpu_input(shape, dtype, rank):
    import torch
    # Exactly representable values, nonconstant by rank AND element.
    return ((torch.arange(math.prod(shape), dtype=torch.float32) % 17 - 8) / 8
            + rank).reshape(shape).to(dtype)


def collective_cases(args, rank, ca):
    import torch
    import torch.distributed as dist
    for dtype_name in args.dtypes:
        dtype = {"fp32": torch.float32, "fp16": torch.float16, "bf16": torch.bfloat16}[dtype_name]
        for op in args.ops:
            shapes_dims = [((16, 1024), 0)] if args.suite == "route" else [((4, 16), 0)]
            if args.suite == "quick" and op.startswith("all_gather"):
                shapes_dims += [((4, 16), 1)]
            if args.suite == "quick" and op == "reduce_scatter":
                shapes_dims += [((4, 16), 1), ((2, 4, 8), 1), ((4, 6), 1)]
            for shape, dim in shapes_dims:
                inputs = [cpu_input(shape, dtype, r) for r in range(args.world_size)]
                inp = inputs[rank].to(f"cuda:{rank}")
                if op.startswith("all_gather"):
                    reference = torch.cat(inputs, dim=dim)
                    if op == "all_gather_reg":
                        import aiter
                        if not aiter.ag_rs_requires_copy_in():
                            ca.register_input_buffer(inp)
                    invoke = lambda: getattr(ca, op)(inp, dim=dim)
                else:
                    reference = sum(x.float() for x in inputs).to(dtype)
                    if op == "reduce_scatter":
                        reference = reference.chunk(args.world_size, dim=dim)[rank].contiguous()
                        out = torch.empty_like(reference, device=f"cuda:{rank}")
                        def invoke():
                            ca.reduce_scatter(inp, out, dim=dim)
                            return out
                    else:
                        invoke = lambda: ca.custom_all_reduce(inp)
                dist.barrier()
                report("call", rank=rank, op=op, dtype=dtype_name, shape=shape, dim=dim)
                out = invoke()
                if out is None:
                    raise AssertionError(f"{op} returned None; AITER did not execute")
                actual = out.cpu()
                torch.testing.assert_close(actual, reference, rtol=0, atol=0)
                report("case_pass", rank=rank, op=op, dtype=dtype_name, shape=shape, dim=dim,
                       output_shape=list(actual.shape))
                dist.barrier()


def distributed_worker(args, rank):
    import torch
    import torch.distributed as dist
    from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
    check_device(args, rank)
    # PMD consumes GPU_CHIP at initialization; launcher must rely on numXcc.
    os.environ.pop("GPU_CHIP", None)
    dist.init_process_group("gloo", init_method=args.init_method,
                            rank=rank, world_size=args.world_size,
                            timeout=timedelta(seconds=args.timeout))
    ca = None
    try:
        report("communicator_begin", rank=rank)
        ca = CustomAllreduce(dist.group.WORLD, torch.device(f"cuda:{rank}"),
                             max_size=512 * 1024, enable_register_for_capturing=False)
        if ca.disabled or not ca._ptr:
            report("communicator_unavailable", rank=rank)
            raise SystemExit(2)
        import aiter
        report("communicator_pass", rank=rank, transport=ca.transport,
               ag_reg_copy_in=bool(aiter.ag_rs_requires_copy_in()))
        if args.stage == "collectives":
            collective_cases(args, rank, ca)
    finally:
        if ca is not None:
            ca.close()
        dist.destroy_process_group()


def worker(args, rank, pipe=None):
    try:
        # PMD writes fixed-name statistics/configuration files in cwd. Keep
        # rank outputs separate; these directories are outputs, never imports.
        directory = Path.cwd() / f"{args.stage}_rank{rank}"
        directory.mkdir(exist_ok=True)
        os.chdir(directory)
        if args.stage == "build":
            import aiter
            from aiter.jit.core import get_module
            size = aiter.meta_size()
            module = get_module("module_custom_all_reduce")
            path = Path(module.__file__).resolve()
            report("build_pass", aiter=str(Path(aiter.__file__).resolve()),
                   module=str(path), sha256=hashlib.sha256(path.read_bytes()).hexdigest(),
                   meta_bytes=size, copy_in=bool(aiter.ag_rs_requires_copy_in()))
        elif args.stage == "devices":
            for device in range(args.world_size):
                check_device(args, device)
        elif args.stage == "ipc":
            ipc_worker(args, rank, pipe)
        else:
            distributed_worker(args, rank)
    except Exception:
        traceback.print_exc()
        raise SystemExit(1)


def main():
    parser = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    parser.add_argument("--stage", choices=("build", "devices", "ipc", "init", "collectives"), required=True)
    parser.add_argument("--require-arch", default="gfx946")
    parser.add_argument("--expect-xcds", type=int)
    parser.add_argument("--world-size", type=int, choices=(2,), default=2)
    parser.add_argument("--timeout", type=int, default=90)
    parser.add_argument("--suite", choices=("quick", "route"), default="quick")
    parser.add_argument("--dtypes", nargs="+", choices=("fp32", "fp16", "bf16"), default=["fp32", "fp16", "bf16"])
    parser.add_argument("--ops", nargs="+", choices=OPS, default=list(OPS))
    parser.add_argument("--die-mode", choices=("auto", "off", "linear"), default="auto")
    args = parser.parse_args()
    if args.timeout <= 0:
        parser.error("--timeout must be positive")
    os.environ["AITER_COMM_DIE_MODE"] = args.die_mode
    os.environ["AITER_AR_TRANSPORT"] = "ipc"
    os.environ["AITER_AR_SMALL_MESSAGE"] = "off"
    os.environ["AITER_AR_DEBUG_STAGES"] = "1"
    with socket.socket() as sock:
        sock.bind(("127.0.0.1", 0))
        args.init_method = f"tcp://127.0.0.1:{sock.getsockname()[1]}"
    ctx = mp.get_context("spawn")
    pipes = ctx.Pipe()
    count = 1 if args.stage in ("build", "devices") else args.world_size
    children = [ctx.Process(target=worker, args=(args, rank, pipes[rank])) for rank in range(count)]
    for child in children:
        child.start()
    deadline = time.monotonic() + args.timeout
    timed_out = False
    while any(p.is_alive() for p in children):
        if time.monotonic() >= deadline:
            timed_out = True
            break
        if any(p.exitcode not in (None, 0) for p in children):
            break
        time.sleep(0.1)
    # Only stop processes owned by this invocation.
    for child in children:
        if child.is_alive():
            child.terminate()
    for child in children:
        child.join(3)
        if child.is_alive():
            child.kill()
            child.join()
    codes = [p.exitcode for p in children]
    result = 124 if timed_out else (0 if all(c == 0 for c in codes) else (2 if 2 in codes else 1))
    report("stage_result", stage=args.stage, exit_code=result, worker_exit_codes=codes)
    return result


if __name__ == "__main__":
    raise SystemExit(main())
