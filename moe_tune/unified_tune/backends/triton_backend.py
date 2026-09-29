# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""系统 BoltOPs Triton 调优能力的适配器。

复用原生候选生成、autotuner 与日志解析，兼容已安装版本的接口差异；
保留原始日志和候选统计，生成 top/bottom 两阶段 JSON。"""
import contextlib
import json
import math
import re
from pathlib import Path
from unittest.mock import patch

from ..tune_spec import QUANTS, log_shape_progress


def timing_summary(log):
    """Keep native attempts/failures separate from the successful perf table."""
    values = [float(value) for value in re.findall(r':\s*times\([^)]+\):\s*([\d.eE+\-]+|inf|nan)\s*ms', log)]
    return dict(attempted=len(re.findall(r'^Autotuning kernel ', log, re.MULTILINE)),
                autotune_failed=len(re.findall(r'^Autotuning failed', log, re.MULTILINE)),
                reported=len(values), finite=sum(math.isfinite(value) and value > 0 for value in values),
                failed_timing_entries=sum(not math.isfinite(value) or value <= 0 for value in values))


def parser_log(log):
    # Installed parsers recognize the generic performance-table heading only.
    # Keep the raw log unchanged; normalize only known INT4 table headings.
    return re.sub(r'^fused_moe_kernel_gptq_awq(?:_w4a8(?:_channelwise)?)?:\s*$',
                  'fused_moe_kernel:', log, flags=re.MULTILINE)


def compatible_autotune(decorator, kernel):
    wrapped = decorator(kernel)
    class Invocation:
        def __getitem__(self, grid):
            launch = wrapped[grid]
            def call(*args, **kwargs):
                # Older installed W4A8 kernels have 32-bit B offsets and no
                # corresponding constexpr; the installed tuner still passes it.
                flag = 'USE_ADDR_OFFSET_INT64_B'
                if flag in kwargs and flag not in kernel.arg_names:
                    if kwargs.pop(flag):
                        raise RuntimeError('installed W4A8 kernel does not support 64-bit weight offsets')
                return launch(*args, **kwargs)
            return call
    return Invocation()


def tune(spec, workdir, options, runtime):
    import torch
    from .common import make_data, quant_flags, torch_dtype, packed_zero_points
    from boltops.tools.fused_moe_triton_tune import autotune_patches as ap
    from boltops.tools.fused_moe_triton_tune.moe_log_parser import parse_log_file, save_results_to_json
    from boltops.utility.triton_capability import get_triton_capabilities, get_triton_config_dir
    if not ap.mode_autotune or ap.test_type != QUANTS[spec.quant_type][0]:
        raise RuntimeError("BoltOPs tuning environment was initialized before its quant/training flags")
    workdir = Path(workdir)
    directory = get_triton_config_dir(workdir, get_triton_capabilities())
    directory.mkdir(parents=True, exist_ok=True)
    top, bottom = (directory / n for n in spec.triton_filenames(runtime["arch"]))
    parsed_all, counts, cases = [], [], []
    original = ap.generate_config2_lists
    original_autotune = ap.dynamic_autotune

    def candidates(*args, **kwargs):
        configs = original(*args, **kwargs)
        chosen = configs
        if options["search"] == "smoke":
            chosen = [c for c in configs if not c.kwargs.get("USE_MLS_LOAD", False) and c.num_warps in (4, 8)][:4]
        if not chosen:
            raise RuntimeError("Triton generated no candidate")
        counts.append(dict(generated=len(configs), selected=len(chosen)))
        return chosen

    for m in spec.tokens:
        log_shape_progress(spec, m, "triton", options.get("progress"))
        print(f"Triton tune M={m}, dtype={spec.dtype}, search={options['search']}", flush=True)
        data = make_data(spec, m)
        logpath = workdir / f"training_{m}.log"
        before = len(counts)
        with logpath.open("w", encoding="utf-8") as stream, contextlib.redirect_stdout(stream):
            print(f"Test: m={m}, n={spec.inter_dim}, k={spec.model_dim}, e={spec.experts}, topk={spec.topk}", flush=True)
            with contextlib.ExitStack() as stack:
                stack.enter_context(patch.object(ap, "generate_config2_lists", candidates))
                stack.enter_context(patch.object(ap, 'dynamic_autotune',
                    lambda kernel: compatible_autotune(original_autotune, kernel)))
                if options["search"] == "smoke":
                    block_m = 16 if m < 2048 else 128
                    outer = {"BLOCK_SIZE_M": block_m}
                    # Older installed tuners pass this flag separately and only
                    # enumerate BLOCK_SIZE_M outside. Preserve that native ABI.
                    if any('bottom_a_use_mls_load' in c for c in ap.k100_ai_config_lists):
                        outer['bottom_a_use_mls_load'] = False
                    stack.enter_context(patch.object(ap, "k100_ai_config_lists", [outer]))
                stack.enter_context(ap.patched_environment())
                # Direct tensor API honors fp16/bf16. No pytest dtype decorators or fixed script constants.
                ap.fused_experts_impl(data["x"], data["w1"], data["w2"], data["weights"], data["ids"],
                    output_dtype=torch_dtype(spec), activation=spec.activation,
                    global_num_experts=spec.experts, w1_scale=data["s1"], w2_scale=data["s2"],
                    block_shape=spec.block_shape, **packed_zero_points(data, 'triton'), **quant_flags(spec))
        log = logpath.read_text(encoding="utf-8")
        parsed = parse_log_file(parser_log(log))
        if len(parsed) != 1 or len(parsed[0]) != 8 or parsed[0][-1] != m:
            raise RuntimeError(f"expected one complete two-GEMM result with M={m} in {logpath}")
        if not math.isfinite(float(parsed[0][4])) or float(parsed[0][4]) <= 0:
            raise RuntimeError(f"invalid Triton best timing for M={m}")
        parsed_all.extend(parsed)
        cases.append(dict(token=m, candidate_groups=counts[before:],
                          gemm_sum_ms=float(parsed[0][4]), timing_summary=timing_summary(log),
                          log=str(logpath.resolve())))
        del data
        torch.cuda.empty_cache()
    save_results_to_json(parsed_all, str(top), str(bottom))
    return dict(files=[str(top.resolve()), str(bottom.resolve())], cases=cases)
