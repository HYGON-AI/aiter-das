# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Dense dtype/layout/stride, pure C ABI and CK selection contract regressions.

python op_tests/test_ck_grouped_gemm_contracts.py --output results.json
Use --dispatch-only for the variable-M/K selection regressions.
"""
import argparse
import ctypes as ct
import json
import os
from pathlib import Path
import re
import tempfile
from unittest.mock import patch

import torch
import aiter
from aiter.jit.core import get_module


class Descriptor(ct.Structure):
    _fields_ = [("a", ct.c_void_p), ("b", ct.c_void_p), ("c", ct.c_void_p),
                ("k_batch", ct.c_int), ("m", ct.c_int), ("n", ct.c_int), ("k", ct.c_int),
                ("sa", ct.c_int), ("sb", ct.c_int), ("sc", ct.c_int),
                ("num_d", ct.c_int), ("d", ct.c_void_p), ("sd", ct.c_void_p)]


DTYPES = {"fp16": torch.float16, "bf16": torch.bfloat16,
          "fp8": torch.float8_e4m3fn, "bf8": torch.float8_e5m2,
          "int8": torch.int8, "int4": torch.uint8}
CK_DTYPES = {"fp16": 0, "bf16": 4, "fp8": 1, "bf8": 3, "int8": 2, "int4": 5}


def pack_int4(x):
    # Raw HCU i4 MMAC consumes signed two's-complement, low nibble first.
    codes = (x.to(torch.int16) & 15).to(torch.uint8)
    return (codes[:, 0::2] | (codes[:, 1::2] << 4)).contiguous()


def inputs(name, layout, shapes, strided=False):
    dtype = DTYPES[name]
    padding = 1 if strided == "odd" else 16
    a, b, refs, c = [], [], [], []
    for m, n, k in shapes:
        av = torch.randint(-3, 4, (m, k), device="cuda").float()
        bv = torch.randint(-3, 4, (k, n), device="cuda").float()
        if name in ("fp16", "bf16"):
            av *= .125
            bv *= .125
        refs.append(av @ bv)
        if name == "int4":
            av, bv = pack_int4(av), pack_int4(bv.T.contiguous())
            av = av.T.contiguous() if layout[0] == "T" else av
        else:
            av = av.T.contiguous() if layout[0] == "T" else av
            bv = bv.T.contiguous() if layout[1] == "T" else bv
            av, bv = av.to(dtype), bv.to(dtype)
        if strided:
            def padded(t):
                buf = torch.empty((t.shape[0], t.shape[1] + padding), dtype=t.dtype, device="cuda")
                view = buf[:, :t.shape[1]]
                view.copy_(t)
                return view
            av, bv = padded(av), padded(bv)
        out_dtype = torch.int32 if name in ("int8", "int4") else torch.float32 if name in ("fp8", "bf8") else dtype
        cv = torch.empty((m, n + (padding if strided else 0)), dtype=out_dtype, device="cuda")[:, :n]
        a.append(av); b.append(bv); c.append(cv)
    return a, b, c, refs


def c_call(lib, name, layout, shapes, a, b, c):
    desc = (Descriptor * len(a))(*[
        Descriptor(ai.data_ptr(), bi.data_ptr(), ci.data_ptr(), 1, m, n, k,
                   ai.stride(0), bi.stride(0), ci.stride(0), 0, None, None)
        for (m, n, k), ai, bi, ci in zip(shapes, a, b, c)])
    size = lib.ck_tile_hcu_grouped_gemm_workspace_size(len(a), 0)
    workspace = torch.empty(size, dtype=torch.uint8, device="cuda")
    al = b"C" if layout[0] == "T" else b"R"
    bl = b"C" if layout[1] == "T" else b"R"
    stream = torch.cuda.current_stream().cuda_stream
    def call(_a=a, _b=b):
        status = lib.ck_tile_hcu_grouped_gemm_run(desc, len(a), CK_DTYPES[name], al, bl,
                                                workspace.data_ptr(), stream)
        if status != 0:
            raise RuntimeError(f"C ABI returned {status}")
        return c
    # The closure retains all input tensors, metadata and workspace.
    return call


def check(outputs, refs, name):
    rtol, atol = (0, 0) if name in ("int8", "int4") else (.02, .03) if name == "bf16" else (.003, .003)
    errors = []
    for out, ref in zip(outputs, refs):
        torch.testing.assert_close(out.float(), ref, rtol=rtol, atol=atol)
        errors.append((out.float() - ref).abs().max().item())
    return max(errors)


def run_dispatch_cases(lib, arch, results):
    # The capacity is the sum of host-known group lengths, not max(lengths).
    # NT/NN cross the BW/MLS threshold with the correct sum; TN and uniform
    # cases retain their existing selection and check numerical compatibility.
    for name in ("fp16", "bf16"):
        large_id = 1000 if arch == "gfx936" else 3000
        tn_id = 1004 if name == "bf16" else 2001 if arch == "gfx936" else 3000
        cases = [
            ("NT", [(2048, 2048, 2048), (2304, 2048, 2048)], large_id),
            ("NN", [(2048, 2048, 2048), (2304, 2048, 2048)], large_id),
            ("TN", [(2048, 2048, 2048), (2048, 2048, 2304)], tn_id),
            ("NT", [(1024, 1024, 1024)] * 3, 4000 if arch == "gfx936" else 3001),
        ]
        for layout, shapes, expected in cases:
            a, b, c, refs = inputs(name, layout, shapes)
            for surface in ("python_out", "c_abi"):
                call = (lambda: aiter.ck_grouped_gemm_out(a, b, c, layout)) if surface == "python_out" else c_call(lib, name, layout, shapes, a, b, c)
                row = dict(dtype=name, layout=layout, shapes=shapes, surface=surface,
                           contract="dispatch_capacity", expected_instance=expected)
                try:
                    # Capture native fprintf(stderr), without changing public APIs.
                    with tempfile.TemporaryFile() as trace, patch.dict(os.environ, {
                        "AITER_CK_GROUPED_GEMM_BACKEND": "registry",
                        "CK_TILE_HCU_GROUPED_GEMM_DISPATCH_TRACE": "1",
                    }):
                        saved = os.dup(2)
                        try:
                            os.dup2(trace.fileno(), 2)
                            out = call()
                        finally:
                            os.dup2(saved, 2)
                            os.close(saved)
                        trace.seek(0)
                        ids = re.findall(rb"AITER_CK_DISPATCH instance_id=(\d+)", trace.read())
                    assert ids == [str(expected).encode()], (expected, ids)
                    row["max_abs_error"] = check(out, refs, name)
                    row["status"] = "PASS"
                except Exception as error:
                    row.update(status="FAIL", error=str(error))
                results.append(row)
                print(json.dumps(row), flush=True)


def run(args):
    torch.manual_seed(20261012)
    arch = torch.cuda.get_device_properties(0).gcnArchName.split(":")[0]
    # Trigger the actual public Python build/load before locating its ELF.
    a = torch.ones(128, 128, dtype=torch.float16, device="cuda")
    aiter.ck_grouped_gemm([a], [a]); torch.cuda.synchronize()
    so = get_module("module_cpp_api").__file__
    lib = ct.CDLL(so)
    has_c_abi = hasattr(lib, "ck_tile_hcu_grouped_gemm_run") and hasattr(lib, "ck_tile_hcu_grouped_gemm_workspace_size")
    if has_c_abi:
        lib.ck_tile_hcu_grouped_gemm_workspace_size.argtypes = [ct.c_int, ct.c_int]
        lib.ck_tile_hcu_grouped_gemm_workspace_size.restype = ct.c_size_t
        lib.ck_tile_hcu_grouped_gemm_run.argtypes = [ct.POINTER(Descriptor), ct.c_int, ct.c_int,
                                                   ct.c_char, ct.c_char, ct.c_void_p, ct.c_void_p]
        lib.ck_tile_hcu_grouped_gemm_run.restype = ct.c_int
    else:
        raise RuntimeError("public C ABI symbols are not exported")
    result = {"arch": arch, "visible_devices": os.getenv("HIP_VISIBLE_DEVICES"),
              "torch": torch.__version__, "hip": torch.version.hip,
              "aiter": aiter.__file__, "so": so, "public_c_abi_exported": has_c_abi,
              "correctness": []}
    cases = []
    for name in ("fp16", "bf16"):
        for layout in ("NT", "NN", "TN", "TT"):
            cases.extend([
                (name, layout, [(128, 128, 128), (256, 128, 128)], False),
                (name, layout, [(17, 129, 137), (65, 129, 137)], False),
                (name, layout, [(128, 128, 128)], True),
                (name, layout, [(128, 128, 128)], "odd"),
            ])
        cases.append((name, "NT", [(128, 128, 128), (192, 256, 128)], False))
        cases.append((name, "TN", [(128, 128, 129), (128, 128, 193)], False))
    cases.extend([
        ("int8", "NT", [(32, 32, 256), (64, 64, 256)], False),
        ("int8", "NT", [(32, 32, 384)], True),
    ])
    if arch in ("gfx938", "gfx946"):
        for name in ("fp8", "bf8"):
            cases.append((name, "NT", [(17, 128, 256), (128, 256, 256)], False))
            cases.append((name, "NT", [(128, 128, 384)], True))
    for layout in ("NT", "TT"):
        cases.append(("int4", layout, [(128, 128, 512), (256, 128, 512)], False))
        cases.append(("int4", layout, [(128, 128, 512)], True))
    if args.dispatch_only:
        cases = []
    for name, layout, shapes, strided in cases:
        a, b, c, refs = inputs(name, layout, shapes, strided)
        for surface in ("python_alloc", "python_out", "c_abi"):
            row = {"dtype": name, "layout": layout, "shapes": shapes, "strided": strided, "surface": surface}
            try:
                if surface == "python_alloc": call = lambda: aiter.ck_grouped_gemm(a, b, layout)
                elif surface == "python_out": call = lambda: aiter.ck_grouped_gemm_out(a, b, c, layout)
                else: call = c_call(lib, name, layout, shapes, a, b, c)
                out = call()
                row["max_abs_error"] = check(out, refs, name)
                if surface == "python_out":
                    assert all(x.data_ptr() == y.data_ptr() for x, y in zip(out, c))
                row["status"] = "PASS"
            except Exception as error:
                row.update(status="FAIL", error=str(error))
            result["correctness"].append(row)
            print(json.dumps(row), flush=True)
    # Retained C-only Split-K and D-tensor contracts must bypass the registry.
    if not args.dispatch_only:
        for name in ("fp16", "bf16"):
            for split_k, num_d in ((2, 0), (1, 1), (1, 2)):
                a, b, c, refs = inputs(name, "NT", [(128, 128, 256)])
                ds = [torch.full_like(c[0], .125 * (i + 1)) for i in range(num_d)]
                ptrs = (ct.c_void_p * num_d)(*[d.data_ptr() for d in ds])
                strides = (ct.c_int * num_d)(*[d.stride(0) for d in ds])
                desc = Descriptor(a[0].data_ptr(), b[0].data_ptr(), c[0].data_ptr(),
                                  split_k, 128, 128, 256, 256, 256, 128, num_d,
                                  ct.cast(ptrs, ct.c_void_p), ct.cast(strides, ct.c_void_p))
                ws = torch.empty(lib.ck_tile_hcu_grouped_gemm_workspace_size(1, num_d), dtype=torch.uint8, device="cuda")
                row = {"dtype": name, "layout": "NT", "surface": "c_abi_legacy_contract",
                       "split_k": split_k, "num_d": num_d}
                try:
                    rc = lib.ck_tile_hcu_grouped_gemm_run(ct.byref(desc), 1, CK_DTYPES[name], b"R", b"C",
                                                         ws.data_ptr(), torch.cuda.current_stream().cuda_stream)
                    if split_k > 1:
                        # This V4 half-output config explicitly rejects Split-K.
                        # Verify the public adapter preserves the old rejection.
                        os.environ["AITER_CK_GROUPED_GEMM_BACKEND"] = "legacy"
                        legacy_rc = lib.ck_tile_hcu_grouped_gemm_run(ct.byref(desc), 1, CK_DTYPES[name], b"R", b"C",
                                                                   ws.data_ptr(), torch.cuda.current_stream().cuda_stream)
                        os.environ.pop("AITER_CK_GROUPED_GEMM_BACKEND", None)
                        assert rc == legacy_rc == -100, (rc, legacy_rc)
                        row.update(expected_outcome="unsupported", return_code=rc)
                    else:
                        assert rc == 0, f"C ABI returned {rc}"
                        row["max_abs_error"] = check(c, [refs[0] + sum(d.float() for d in ds)], name)
                    row["status"] = "PASS"
                except Exception as error:
                    row.update(status="FAIL", error=str(error))
                result["correctness"].append(row)
                print(json.dumps(row), flush=True)
    if arch in ("gfx936", "gfx938"):
        run_dispatch_cases(lib, arch, result["correctness"])
    Path(args.output).write_text(json.dumps(result, indent=2), encoding="utf-8")
    failures = [row for row in result["correctness"] if row["status"] == "FAIL"]
    print(f"RESULT {len(result['correctness'])-len(failures)} PASS, {len(failures)} FAIL", flush=True)
    return 1 if failures else 0


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("--dispatch-only", action="store_true")
    parser.add_argument("--output", required=True)
    raise SystemExit(run(parser.parse_args()))
