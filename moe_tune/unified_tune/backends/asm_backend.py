# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""ASM 原生 MoE 候选调优适配器。

查询并执行 ASM solution，逐候选检查精度与计时；
处理 shuffle 和量化布局，筛选可用结果并生成原生 CSV。"""
import csv
import json
from pathlib import Path

from .common import benchmark, check, make_data, quant_flags, reference, torch_dtype, packed_zero_points
from ..tune_spec import log_shape_progress


def tune(spec, workdir, options, runtime):
    import aiter
    import aiter.fused_moe_asm_wna16 as asm
    from aiter.ops.shuffle import asm_shuffle_weight_b8
    import torch

    workdir = Path(workdir)
    if spec.quant_type == 'int4_w4a8':
        binaries = Path(runtime['asm_config_dir']).parents[1] / 'hsa' / runtime['arch'] / 'w4a8'
        if not binaries.is_dir() or not any(binaries.rglob('*.co')):
            raise RuntimeError(f'ASM W4A8 code objects are unavailable for {runtime["arch"]}: {binaries}')
    rows, cases = [], []
    for m in spec.tokens:
        log_shape_progress(spec, m, "asm", options.get("progress"))
        print(f"ASM tune M={m}, shuffle={spec.shuffle}", flush=True)
        data = make_data(spec, m)
        ref = reference(spec, data)
        flags = quant_flags(spec)
        zeros = packed_zero_points(data, 'asm')
        solutions = aiter.asm_moe_get_solutions(data["x"], data["w1"], data["w2"], data["weights"],
            data["ids"], w1_scale=data["s1"], w2_scale=data["s2"], block_shape_n=spec.q_size_n, block_shape_k=spec.q_size_k,
            block_m=16, **zeros, **flags)
        if not solutions:
            raise RuntimeError(f"ASM has no candidate for M={m}, quant={spec.quant_type}")
        selected = list(solutions)[:4] if options["search"] == "smoke" else list(solutions)
        w1, w2 = data["w1"], data["w2"]
        if spec.shuffle:
            w1, w2 = asm_shuffle_weight_b8(w1, 1), asm_shuffle_weight_b8(w2, 2)
        good, failures = [], []
        for index, sid in enumerate(selected):
            def call():
                return asm.fused_experts_asm_impl(data["x"], w1, w2, data["weights"], data["ids"],
                    dtype=torch_dtype(spec), activation=spec.activation, global_num_experts=spec.experts,
                    w1_scale=data["s1"], w2_scale=data["s2"], use_shuffle=spec.shuffle,
                    solution_id=str(sid), block_shape=spec.block_shape, **zeros, **quant_flags(spec, 'asm'))
            try:
                accuracy = check(call(), ref)
                # Rank kernels by device execution, without Python launch gaps.
                timing = benchmark(call, options["warmup"], options["iterations"], use_graph=True)
                after_timing = check(call(), ref)
                good.append(dict(sol_id=str(sid), **timing, accuracy=accuracy, accuracy_after_timing=after_timing))
            except Exception as exc:
                # A poisoned device cannot safely continue running other candidates.
                if any(x in str(exc).lower() for x in ("illegal memory", "memory access fault", "device-side assert")):
                    raise
                failures.append(dict(sol_id=str(sid), error=str(exc)))
            if (index + 1) % 25 == 0:
                print(f"ASM M={m}: {index + 1}/{len(selected)} candidates", flush=True)
        record = dict(token=m, enumerated=len(solutions), measured=len(selected), valid=good, failures=failures)
        (workdir / f"candidates_{m}.json").write_text(json.dumps(record, indent=2), encoding="utf-8")
        if not good:
            hint = "; the smoke subset is not exhaustive, retry --search full" if options['search'] == 'smoke' else ''
            raise RuntimeError(f"all measured ASM candidates failed for M={m}; see candidates_{m}.json{hint}")
        best = min(good, key=lambda item: item["median_us"])
        rows.append(dict(arch=runtime["arch"], quant_type=spec.quant_type,
            indtype=str(torch_dtype(spec)), token=m, inter_dim=spec.inter_dim, model_dim=spec.model_dim,
            expert=spec.experts, topk=spec.topk, q_size_n=spec.q_size_n, q_size_k=spec.q_size_k,
            sol_type="asm", sol_id=best["sol_id"], time_us=best["median_us"]))
        cases.append(dict(token=m, enumerated=len(solutions), measured=len(selected),
                          failed=len(failures), best=best))
        del data, ref, w1, w2
        torch.cuda.empty_cache()
    target = workdir / spec.asm_filename()
    with target.open("w", newline="", encoding="utf-8") as stream:
        writer = csv.DictWriter(stream, fieldnames=list(rows[0]))
        writer.writeheader(); writer.writerows(rows)
    return dict(files=[str(target.resolve())], cases=cases)
