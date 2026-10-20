#!/usr/bin/env python3
# Modified by Hygon Information Technology Co., Ltd.: quality and safety fixes.
# SPDX-License-Identifier: Apache-2.0

import argparse
import csv
import gc
import os
import re
import sys
import time
from pathlib import Path


NORMAL_M_LIST = [
    1, 2, 3, 4, 5, 6, 7, 8,
    9, 10, 11, 12, 13, 14, 15, 16,
    32, 64, 128, 256, 512, 1024, 2048,
    4096, 6144, 8192, 16384, 32768,
]

K1280_M_LIST = [
    56, 112, 1400, 2240, 2800, 4480, 5712,
    6552, 8960, 11424, 13104, 14336, 28672, 57344,
]


CSV_FIELDS = [
    "config",
    "E",
    "N",
    "K",
    "M",
    "status",
    "error_ratio",
    "mode",
    "bm",
    "backend",
    "error",
    "elapsed_s",
]


def parse_args():
    parser = argparse.ArgumentParser(
        description="Validate every gfx fp8_w8a8 MoE-C config over the full M list."
    )
    parser.add_argument("--arch", default="gfx938")
    parser.add_argument("--config-dir", default=None)
    parser.add_argument(
        "--out-csv",
        default="w8a8_fp8_moec_all_config_correctness_gfx938_latest560.csv",
    )
    parser.add_argument("--device", default=None, help="Set HIP_VISIBLE_DEVICES before importing torch.")
    parser.add_argument("--resume", action="store_true", help="Keep passed CSV cases and retry remaining cases, including OOM.")
    parser.add_argument("--topk", type=int, default=8)
    parser.add_argument("--rtol", type=float, default=0.01)
    parser.add_argument("--atol", type=float, default=0.5)
    parser.add_argument("--max-error-ratio", type=float, default=0.03)
    parser.add_argument(
        "--keep-going-on-oom",
        action="store_true",
        default=True,
        help="Keep running after OOM and print OOM cases at the end. Enabled by default.",
    )
    parser.add_argument(
        "--fail-on-accuracy",
        action="store_true",
        help="Exit non-zero when non-OOM accuracy/config failures are found.",
    )
    parser.add_argument(
        "--fail-on-oom",
        action="store_true",
        help="Exit non-zero when OOM cases are found.",
    )
    return parser.parse_args()


def is_oom_error(exc):
    text = repr(exc).lower()
    return "outofmemory" in text or "out of memory" in text or "hip out of memory" in text


def discover_configs(config_dir):
    configs = []
    for path in sorted(config_dir.glob("*.json")):
        if "is_bottom=True" in path.name:
            continue
        match = re.search(r"E=(\d+),N=(\d+)(?:,K=(\d+))?,dtype=fp8_w8a8", path.name)
        if not match:
            continue
        e = int(match.group(1))
        n = int(match.group(2))
        k = int(match.group(3) or 7168)
        configs.append((e, n, k, path.name))
    return configs


def build_cases(configs):
    cases = []
    for e, n, k, cfg_name in configs:
        m_list = K1280_M_LIST if k == 1280 else NORMAL_M_LIST
        for m in m_list:
            cases.append((e, n, k, m, cfg_name))
    return cases


def write_rows(out_csv, rows):
    with open(out_csv, "w", newline="") as f:
        writer = csv.DictWriter(f, fieldnames=CSV_FIELDS)
        writer.writeheader()
        writer.writerows(rows)


def print_case_list(title, rows):
    if not rows:
        return
    print(f"\n[{title}] count={len(rows)}", flush=True)
    for row in rows:
        print(
            "  "
            f"E={row['E']} N={row['N']} K={row['K']} M={row['M']} "
            f"config={row['config']} mode={row.get('mode', '')} bm={row.get('bm', '')} "
            f"error={row.get('error', '')}",
            flush=True,
        )


def main():
    args = parse_args()
    if args.device is not None:
        os.environ["HIP_VISIBLE_DEVICES"] = str(args.device)

    import torch

    from aiter import dtypes
    from aiter.moe import (
        MoeQuantType,
        MoeSolutionType,
        aiter_moe,
        aiter_moe_shfl_weight,
        get_aiter_moe_config,
    )
    from aiter.moe_c_golden import run_fp8_channelwise_golden
    from aiter.test_common import checkAllclose
    from op_tests.ci_tests.test_aiter_moe_with_config_w8a8_channelwise import (
        prepare_w8a8_channelwise_inputs,
    )

    repo_root = Path.cwd()
    config_dir = Path(args.config_dir) if args.config_dir else repo_root / "aiter" / "moe_c_configs" / args.arch / "fp8_w8a8"
    configs = discover_configs(config_dir)
    cases = build_cases(configs)
    rows = []
    if args.resume and Path(args.out_csv).exists():
        with open(args.out_csv, newline="") as f:
            rows = [row for row in csv.DictReader(f) if row["status"] == "passed"]
        completed = {(row["config"], int(row["M"])) for row in rows}
        cases = [case for case in cases if (case[4], case[3]) not in completed]
    start = time.time()

    print(
        f"[moe-c-fp8-w8a8-all-configs] arch={args.arch} "
        f"configs={len(configs)} total_cases={len(cases)} out={args.out_csv}",
        flush=True,
    )
    print(f"[config-dir] {config_dir}", flush=True)

    for idx, (e, n, k, m, cfg_name) in enumerate(cases, 1):
        row = {key: "" for key in CSV_FIELDS}
        row.update({"config": cfg_name, "E": e, "N": n, "K": k, "M": m})
        t0 = time.time()
        print(f"[case {idx}/{len(cases)}] E={e} N={n} K={k} M={m}", flush=True)
        try:
            status, moe_cfg = get_aiter_moe_config(
                M=m,
                E=e,
                N1=2 * n,
                N2=k,
                K=k,
                top_k=args.topk,
                block_size=0,
                dtype=dtypes.fp8,
                quant_type=MoeQuantType.FP8_W8A8,
                use_shuffle=0,
                spec_sol_type=MoeSolutionType.MOE_C,
            )
            if not status:
                raise RuntimeError("no moe_c config found")

            row["backend"] = str(moe_cfg.solution_type)
            row["mode"] = str(moe_cfg.config.get("MODE", "")) if moe_cfg.config else ""
            row["bm"] = str(moe_cfg.config.get("BLOCK_SIZE_M", "")) if moe_cfg.config else ""

            data = prepare_w8a8_channelwise_inputs(
                m, k, n, e, args.topk, dtypes.fp8, MoeQuantType.FP8_W8A8
            )
            ref_out = run_fp8_channelwise_golden(
                data["input"],
                data["w1_qweight"],
                data["w2_qweight"],
                data["topk_weights"],
                data["topk_ids"],
                dtypes.bf16,
                data["w1_scales"],
                data["w2_scales"],
                data["a1_scales"],
                e,
            )

            w1_input, w2_input = data["w1_qweight"], data["w2_qweight"]
            if moe_cfg.need_shuffle:
                w1_input, w2_input = aiter_moe_shfl_weight(w1_input, w2_input, moe_cfg)

            aiter_out = aiter_moe(
                hidden_states=data["input"],
                w1=w1_input,
                w2=w2_input,
                topk_weights=data["topk_weights"],
                topk_ids=data["topk_ids"],
                moe_config=moe_cfg,
                inplace=False,
                activation="silu",
                w1_scale=data["w1_scales"],
                w2_scale=data["w2_scales"],
                w1_zp=None,
                w2_zp=None,
                a1_scale=data["a1_scales"],
                a2_scale=None,
                block_shape=None,
                global_num_experts=e,
                expert_map=None,
                output_dtype=dtypes.bf16,
                use_weight_shuffle=moe_cfg.need_shuffle,
            )
            torch.cuda.synchronize()
            if not torch.isfinite(aiter_out).all():
                raise AssertionError("non-finite output")

            err = checkAllclose(
                ref_out.to(aiter_out.dtype),
                aiter_out,
                rtol=args.rtol,
                atol=args.atol,
                msg=f"[moe_c fp8 direct] E={e} N={n} K={k} M={m}",
            )
            row["error_ratio"] = f"{float(err):.6f}"
            if err <= args.max_error_ratio:
                row["status"] = "passed"
                print(
                    f"[PASS] E={e} N={n} K={k} M={m} mode={row['mode']} "
                    f"bm={row['bm']} err={err:.6f}",
                    flush=True,
                )
            else:
                row["status"] = "failed"
                row["error"] = f"error_ratio {err:.6f} > {args.max_error_ratio}"
                print(
                    f"[FAIL] E={e} N={n} K={k} M={m} mode={row['mode']} "
                    f"bm={row['bm']} err={err:.6f}",
                    flush=True,
                )
        except BaseException as exc:
            row["status"] = "oom" if is_oom_error(exc) else "failed"
            row["error"] = repr(exc)
            print(f"[{row['status'].upper()}] E={e} N={n} K={k} M={m}: {exc!r}", flush=True)
            if row["status"] == "oom" and not args.keep_going_on_oom:
                raise
        finally:
            row["elapsed_s"] = f"{time.time() - t0:.3f}"
            rows.append(row)
            write_rows(args.out_csv, rows)

            data = ref_out = w1_input = w2_input = aiter_out = None
            try:
                torch.cuda.empty_cache()
                torch.cuda.synchronize()
            except Exception:
                pass
            gc.collect()

    passed = [row for row in rows if row["status"] == "passed"]
    oom_rows = [row for row in rows if row["status"] == "oom"]
    failed_rows = [row for row in rows if row["status"] == "failed"]

    print(
        f"\n[done] elapsed_s={time.time() - start:.1f} total={len(rows)} "
        f"passed={len(passed)} failed={len(failed_rows)} oom={len(oom_rows)} "
        f"out={args.out_csv}",
        flush=True,
    )
    print_case_list("OOM cases", oom_rows)
    print_case_list("FAILED cases", failed_rows)

    if (args.fail_on_accuracy and failed_rows) or (args.fail_on_oom and oom_rows):
        return 1
    return 0


if __name__ == "__main__":
    sys.exit(main())
