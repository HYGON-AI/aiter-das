# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""PMD-friendly S1 regression for the public API and gfx946 IDs4/5.

Host preparation/reference keeps unrelated Torch/Triton compute kernels off PMD.
TestPagedMQAHCU in the main test covers gfx936/gfx938 ID6/7 and S64 paths.
"""

import importlib
import json
from pathlib import Path

import torch

from op_tests.test_paged_mqa_logits import make_case, reference, check_output


def run_cpu_reference(report_path, kernel_id=None, *, test_graph=False):
    from aiter import paged_mqa_logits
    module = importlib.import_module("aiter.ops.opus.paged_mqa_logits")
    torch.set_num_threads(1)
    arch = torch.cuda.get_device_properties(0).gcnArchName.split(":")[0]
    assert arch in ("gfx938", "gfx946"), arch
    cases = [(f"r{r}_h{h}", (1, r, h, 67), None, False)
             for r in (1, 2, 4) for h in (32, 64)]
    cases += [
        ("min", (1, 1, 32, 1), [1], True),
        ("min_mtp", (1, 4, 64, 4), [4], True),
        ("n63", (1, 2, 32, 63), [63], False),
        ("n64", (1, 4, 64, 64), [64], False),
        ("n65", (2, 2, 32, 65), [63, 65], False),
        ("n128", (2, 4, 64, 128), [65, 128], False),
        ("n257", (2, 4, 64, 257), [129, 257], True),
        ("far_tail", (2, 2, 32, 1025), [2, 67], False),
        ("short_table", (1, 2, 64, 257), [73], False),
        ("scales", (2, 2, 32, 129), [67, 129], False),
        ("zero_weights", (1, 4, 64, 67), None, False),
        ("fp8_limits", (1, 2, 32, 65), None, False),
        ("repeat_pages", (2, 4, 64, 129), [73, 129], True),
        ("stream", (1, 2, 32, 65), None, True),
        ("fp8_subnormals", (2, 1, 32, 129), [67, 129], False),
        ("offset_storage", (2, 2, 64, 65), [63, 65], False),
    ]
    if test_graph:
        # Some PMD releases abort even on a copy-only HIP Graph. Keep this
        # explicit so eager correctness does not imply model Graph support.
        cases.append(("graph_mutation", (2, 2, 32, 129), [73, 129], False))
    records = []
    report_path = Path(report_path)
    report_path.parent.mkdir(parents=True, exist_ok=True)

    def save():
        report_path.write_text(json.dumps({"arch": arch, "torch": torch.__version__,
            "kernel_id": kernel_id, "reference": "CPU FP32",
            "graph_requested": test_graph, "cases": records}, indent=2))

    for index, (name, shape, lengths, structured) in enumerate(cases):
        args = list(make_case(*shape, seed=946+index, lengths=lengths,
                              structured=structured, independent_cache=True, device="cpu"))
        q, cache, weights, context, table, n = args
        if name == "short_table":
            args[4] = table[:, :73].contiguous()
        if name == "scales":
            scales = 2.0 ** torch.linspace(-8, 8, cache.shape[0])
            cache.view(-1, 132)[:, 128:].copy_(scales[:, None].view(torch.uint8))
        if name == "zero_weights":
            weights.zero_()
        if name == "fp8_limits":
            args[0] = torch.full(shape[:3]+(128,), 448.0).to(torch.float8_e4m3fn)
            cache.view(-1, 132)[:, :128].copy_(torch.full((cache.shape[0], 128), 448.0)
                                             .to(torch.float8_e4m3fn).view(torch.uint8))
        if name == "repeat_pages":
            table[:, ::2] = table[:, :1]
        if name == "fp8_subnormals":
            # Every finite E4M3FN encoding, including signed zero/subnormals.
            codes = torch.arange(256, dtype=torch.int16).to(torch.uint8)
            codes[0x7f] = 0
            codes[0xff] = 0x80
            q.view(torch.uint8).flatten().copy_(codes.repeat((q.numel()+255)//256)[:q.numel()])
            keys = cache.view(-1, 132)[:, :128]
            keys.copy_(codes.repeat((keys.numel()+255)//256)[:keys.numel()].view_as(keys))
            cache.view(-1, 132)[:, 128:].copy_(torch.ones((cache.shape[0], 1)).view(torch.uint8))
        ref, valid = reference(args)
        dev = [t.to("cuda") for t in args[:5]] + [n]
        if name == "offset_storage":
            for i in (0, 1):
                raw = args[i].view(torch.uint8)
                storage = torch.empty(raw.numel()+4, dtype=torch.uint8, device="cuda")
                storage[4:].view_as(raw).copy_(raw)
                dev[i] = storage[4:].view(args[i].dtype).view_as(args[i])
                assert dev[i].data_ptr() % 16 == 4
        # Canary surrounds a contiguous output view; all writes are checked on CPU.
        backing_cpu = torch.full((shape[0]*shape[1]*n+32,), -1234567.0)
        backing = backing_cpu.to("cuda")
        out = backing[16:-16].view(shape[0]*shape[1], n)
        stream = torch.cuda.Stream() if name == "stream" else torch.cuda.current_stream()
        stream.wait_stream(torch.cuda.current_stream())
        with torch.cuda.stream(stream):
            returned = paged_mqa_logits(*dev, out=out, kernelId=kernel_id)
        stream.synchronize()
        assert returned is out
        host = out.cpu()
        error = check_output(host, ref, valid, structured)
        whole = backing.cpu()
        assert torch.equal(whole[:16], backing_cpu[:16])
        assert torch.equal(whole[-16:], backing_cpu[-16:])
        assert not (host == -1234567.0).any(), "output sentinel survived"
        for cpu, gpu in zip(args[:5], dev[:5]):
            assert torch.equal(cpu.view(torch.uint8), gpu.cpu().view(torch.uint8)), "input mutated"
        resolved = module._resolve_paged_mqa_kernel(kernel_id, rows=shape[0]*shape[1],
                                                   max_len=n, arch=arch)
        if arch == "gfx946":
            assert resolved == (4 if kernel_id is None else kernel_id)
        if name in ("min", "n65", "stream"):
            paged_mqa_logits(*dev, out=out, clean_logits=False, kernelId=kernel_id)
            torch.cuda.synchronize()
            assert torch.equal(out.cpu(), host), "repeat/clean=False changed the result"
        graph_checked = name == "graph_mutation"
        if graph_checked:
            capture_stream = torch.cuda.Stream()
            capture_stream.wait_stream(torch.cuda.current_stream())
            graph = torch.cuda.CUDAGraph()
            with torch.cuda.graph(graph, stream=capture_stream):
                paged_mqa_logits(*dev, out=out, kernelId=kernel_id)
            graph.replay()
            torch.cuda.synchronize()
            check_output(out.cpu(), ref, valid)
            # Replay must read current device data, not host-cached page IDs,
            # context lengths, weights or FP8 input values from capture time.
            context[0] -= 9
            table[:, 1] = table[:, -1]
            weights.mul_(-0.5)
            q.view(torch.uint8).bitwise_xor_(0x80)
            cache.view(-1, 132)[0, :128].fill_(1)
            for src, dst in zip(args[:5], dev[:5]):
                dst.copy_(src)
            out.copy_(torch.full_like(ref, float("nan")))
            ref, valid = reference(args)
            graph.replay()
            torch.cuda.synchronize()
            error = check_output(out.cpu(), ref, valid)
            whole = backing.cpu()
            assert torch.equal(whole[:16], backing_cpu[:16])
            assert torch.equal(whole[-16:], backing_cpu[-16:])
        records.append({"name": name, "shape": list(shape), "lengths": context.tolist(),
                        "resolved_id": resolved, "structured": structured, "seed": 946+index,
                        "graph_metadata_replay": graph_checked, "status": "PASS", **error})
        save()
        print(f"CPU_REF_PASS {name} id={resolved} max_abs={error['max_abs']}", flush=True)

    # Host metadata errors must be rejected before entering the JIT/DUT.
    checks = 0
    def rejects(call):
        nonlocal checks
        try:
            call()
        except (ValueError, NotImplementedError, RuntimeError):
            checks += 1
        else:
            raise AssertionError("invalid API call was accepted")
    rejects(lambda: paged_mqa_logits(*dev, kernelId=True))
    rejects(lambda: paged_mqa_logits(*dev, kernelId=99))
    rejects(lambda: paged_mqa_logits(*dev, kernelId=0 if arch == "gfx946" else 4))
    rejects(lambda: paged_mqa_logits(*dev, clean_logits=1))
    rejects(lambda: paged_mqa_logits(*dev[:-1], 0))
    rejects(lambda: paged_mqa_logits(dev[0].view(torch.uint8), *dev[1:]))
    rejects(lambda: paged_mqa_logits(dev[0], dev[1], dev[2][:, ::2], *dev[3:]))
    rejects(lambda: paged_mqa_logits(*dev, out=out[:, ::2]))
    rejects(lambda: paged_mqa_logits(args[0], *dev[1:]))
    # Direct pybind bypass must still enforce architecture/ID pairing.
    rejects(lambda: module._paged_mqa_logits_opus(*dev[:5], out, n,
                                                 0 if arch == "gfx946" else 4))
    if arch == "gfx946":
        for unsupported_id in (6, 7):
            rejects(lambda: paged_mqa_logits(*dev, kernelId=unsupported_id))
            rejects(lambda: module._paged_mqa_logits_opus(*dev[:5], out, n, unsupported_id))
        # S64 remains outside the gfx946 contract, even when its shape is valid.
        s64 = torch.zeros((1, 64, 1, 132), dtype=torch.uint8).to("cuda")
        rejects(lambda: paged_mqa_logits(dev[0], s64, *dev[2:]))
    records.append({"api_rejections": checks, "status": "PASS"})
    save()
    print(f"CPU_REFERENCE_PASS cases={len(cases)} rejections={checks}", flush=True)
