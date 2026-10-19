# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""MOE_C timing adapter for cross-backend route selection.

moe_c is a fixed backend here: unlike asm (solution sweep -> CSV) and triton
(config sweep -> JSON), tune_moe never writes or changes moe_c tuned configs.
For each token the adapter gets the config from
`get_aiter_moe_config(spec_sol_type=MOE_C)` (the same call common.get_config
uses), runs it through public_call (which applies aiter_moe_shfl_weight when
cfg.need_shuffle), checks accuracy and benchmarks.

Outcome per token:
  * accuracy pass + timing -> case recorded as eligible for route recommendation
  * accuracy failure       -> numerically_failed case (kept in the report, never
                              recommended in the route table; the pipeline
                              filters these out)
  * no tuned moe_c config  -> skipped (backend cannot serve this shape)
Returns dict(files=[], timing-cases=...). files stays empty because moe_c has
no tuned files to validate or install.
"""
import json
from pathlib import Path

from .common import (benchmark, check, get_config, make_data, public_call,
                     reference, torch_dtype)
from ..tune_spec import log_shape_progress


def _adapt_scales(spec, data):
    """common.make_data produces fp32 weight scales, but the moe_c w8a16 marlin
    kernel needs them in the activation dtype. w8a8 channel fp8/int8 accept
    fp32, so only int8_w8a16 is cast."""
    if spec.quant_type == "int8_w8a16":
        dt = torch_dtype(spec)
        for key in ("s1", "s2"):
            if data[key] is not None and data[key].dtype != dt:
                data[key] = data[key].to(dt)
    return data


def tune(spec, workdir, options, runtime):
    import torch

    workdir = Path(workdir)
    cases = []
    for m in spec.tokens:
        log_shape_progress(spec, m, "moe_c", options.get("progress"))
        print(f"MOE_C timing M={m} quant={spec.quant_type}", flush=True)
        data = _adapt_scales(spec, make_data(spec, m))
        ref = reference(spec, data)
        try:
            cfg = get_config(spec, m, "moe_c")
        except RuntimeError as exc:  # no tuned moe_c config for this shape
            cases.append(dict(token=m, status="no_config", error=str(exc)))
            del data, ref
            torch.cuda.empty_cache()
            continue
        call = public_call(spec, data, cfg)
        try:
            accuracy = check(call(), ref)
        except Exception as exc:
            if any(x in str(exc).lower() for x in ("illegal memory", "memory access fault",
                                                    "device-side assert")):
                raise  # poisoned device: abort loudly, never keep timing
            # Numeric failures (including the known moe_c w8a8 error) are recorded, not raised.
            cases.append(dict(token=m, status="numerically_failed", error=str(exc)))
            del data, ref
            torch.cuda.empty_cache()
            continue
        timing = benchmark(call, options["warmup"], options["iterations"], use_graph=True)
        after = check(call(), ref)
        cases.append(dict(token=m, status="ok", accuracy=accuracy,
                          accuracy_after_timing=after, **timing))
        del data, ref, call, cfg
        torch.cuda.empty_cache()
    (workdir / "moe_c_timing.json").write_text(
        json.dumps(dict(cases=cases), indent=2), encoding="utf-8")
    ok = [c for c in cases if c["status"] == "ok"]
    if not ok:
        statuses = {c["token"]: c["status"] for c in cases}
        raise RuntimeError(f"moe_c produced no numerically-valid timing for any token: {statuses}")
    return dict(files=[], cases=cases,
                timings={c["token"]: c["median_us"] for c in ok})
