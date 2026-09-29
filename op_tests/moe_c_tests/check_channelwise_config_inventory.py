#!/usr/bin/env python3
"""Validate literal config pairs, including defaults and shadowed legacy files."""

import argparse
import csv
import gc
import hashlib
import importlib
import inspect
import json
import os
import sys
import traceback
from pathlib import Path


QUANTS = ("fp8_w8a8", "int8_w8a8", "int8_w4a8")


def check_unpaired(root, files, out):
    """Use the independent GEMM reference for files without a stage pair."""
    sys.path.insert(0, str(root / "3rdparty/moe_c"))
    import torch
    from tune.tune_moe_hipc import Shape, _make_w8a8_inputs, _bench_w8a8_stage

    rows = []
    for filename in files:
        path = Path(filename)
        fields = dict(part.split("=", 1) for part in path.stem.split(","))
        quant = fields["dtype"]
        stage = "gemm2" if "is_bottom=True" in filename else "gemm1"
        for m, config in sorted(json.loads(path.read_text()).items(), key=lambda item: int(item[0])):
            shape = Shape(int(fields.get("E", 257)), int(fields["N"]),
                          int(fields.get("K", 7168)), int(fields.get("topk", 8)),
                          int(m), "bf16", "gfx938", 72)
            data = None
            row = dict(config=filename, stage=stage, M=int(m), mode=config["MODE"],
                       status="", error="", max_delta=None)
            print("UNPAIRED CASE", row, flush=True)
            try:
                data = _make_w8a8_inputs(int(m), shape, quant)
                result = _bench_w8a8_stage(shape, data, config, stage, quant, 0, 1)
                row.update(status="passed" if result.ok else "failed",
                           error=result.error, max_delta=result.max_delta)
            except Exception as exc:
                row.update(status="oom" if "out of memory" in str(exc).lower() else "failed",
                           error=repr(exc))
                traceback.print_exc()
            finally:
                data = None
                gc.collect()
                torch.cuda.empty_cache()
            rows.append(row)
            (out / "unpaired_stage_results.json").write_text(json.dumps(rows, indent=2))
            print("UNPAIRED RESULT", row, flush=True)
    return int(any(row["status"] == "failed" for row in rows))


def inventory(root):
    groups, orphans = {}, []
    for quant in QUANTS:
        for up in sorted(root.glob("*/" + quant + "/*.json")):
            if "is_bottom=True" in up.name:
                top = up.with_name(up.name.replace(",is_bottom=True", ""))
                if not top.exists():
                    orphans.append(str(up))
                continue
            down = up.with_name(up.stem + ",is_bottom=True.json")
            if not down.exists():
                orphans.append(str(up))
                continue
            fields = dict(part.split("=", 1) for part in up.stem.split(","))
            shape = [int(fields.get(key, default)) for key, default in
                     (("E", 257), ("N", 0), ("K", 7168), ("topk", 8))]
            # Identical architecture copies run once on the available hardware.
            digest = hashlib.sha256(up.read_bytes() + down.read_bytes()).hexdigest()
            key = (quant, tuple(shape), digest)
            if key not in groups:
                groups[key] = dict(quant=quant, shape=shape, up=str(up),
                                   down=str(down), copies=[])
            groups[key]["copies"].append([str(up), str(down)])
    return list(groups.values()), orphans


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--config-root", default="aiter/moe_c_configs")
    parser.add_argument("--output-dir", required=True)
    parser.add_argument("--shard-index", type=int, default=0)
    parser.add_argument("--shard-count", type=int, default=1)
    parser.add_argument("--device", required=True)
    parser.add_argument("--quant", nargs="+", choices=QUANTS, default=list(QUANTS))
    parser.add_argument("--inventory-only", action="store_true")
    parser.add_argument("--unpaired-only", action="store_true")
    parser.add_argument("--config-files", nargs="+", help="Restrict a retry to literal GEMM1 paths")
    args = parser.parse_args()
    if args.shard_count < 1 or not 0 <= args.shard_index < args.shard_count:
        parser.error("shard-index must be within shard-count")
    if args.device == "3":
        parser.error("physical GPU 3 is reserved")
    os.environ["HIP_VISIBLE_DEVICES"] = args.device
    root = Path(__file__).resolve().parents[2]
    sys.path.insert(0, str(root))
    groups, orphans = inventory(Path(args.config_root).resolve())
    groups = [group for group in groups if group["quant"] in args.quant]
    orphans = [path for path in orphans if Path(path).parent.name in args.quant]
    if args.config_files:
        selected = {str(Path(path).resolve()) for path in args.config_files}
        filtered, found = [], set()
        for group in groups:
            matches = [(up, down) for up, down in group["copies"] if up in selected]
            if matches:
                group.update(up=matches[0][0], down=matches[0][1])
                filtered.append(group)
                found.update(up for up, _ in matches)
        if selected - found:
            parser.error("requested config has no paired inventory entry: %s" % sorted(selected - found))
        groups = filtered
    out = Path(args.output_dir).resolve()
    out.mkdir(parents=True, exist_ok=True)
    if args.shard_index == 0:
        (out / "inventory.json").write_text(json.dumps(
            dict(groups=groups, unpaired_files=orphans), indent=2))
    if args.inventory_only:
        print("pairs", len(groups), "unpaired", orphans)
        return
    if args.unpaired_only:
        return check_unpaired(root, orphans, out)

    import torch
    from aiter import dtypes
    from aiter.fused_moe import torch_moe
    from aiter.moe import (MoeQuantType, MoeSolutionType, aiter_moe,
                           aiter_moe_shfl_weight, get_aiter_moe_config)
    from aiter.moe_c_golden import run_fp8_channelwise_golden, run_w4a8_perchannel_golden
    from aiter.test_common import checkAllclose
    from op_tests.ci_tests.test_aiter_moe_with_config_w8a8_channelwise import prepare_w8a8_channelwise_inputs
    from op_tests.ci_tests.test_aiter_moe_with_config_w4a8_perchannel import prepare_w4a8_inputs

    fused = importlib.import_module("aiter.fused_moe_c")
    original_find = fused._find_moe_c_config_file
    active = {}

    def find_literal(filename, quant, block_shape, arch=None):
        if quant == active.get("quant"):
            return active["down" if "is_bottom=True" in filename else "up"]
        return original_find(filename, quant, block_shape, arch)

    fused._find_moe_c_config_file = find_literal
    # Shape-only caching must not hide another literal file for the same shape.
    fused.get_moe_configs_marlin = inspect.unwrap(fused.get_moe_configs_marlin)
    rows = []
    quant_types = dict(fp8_w8a8=MoeQuantType.FP8_W8A8,
                       int8_w8a8=MoeQuantType.W8A8, int8_w4a8=MoeQuantType.W4A8)
    for index, group in enumerate(groups):
        if index % args.shard_count != args.shard_index:
            continue
        active.update(group)
        up, down = (json.loads(Path(group[key]).read_text()) for key in ("up", "down"))
        for m in sorted(set(map(int, up)) | set(map(int, down))):
            e, n, k, topk = group["shape"]
            quant = group["quant"]
            row = dict(quant=quant, E=e, N=n, K=k, topk=topk, M=m,
                       config=group["up"], mode_up="", mode_down="", BM="",
                       status="", error="", error_ratio="")
            print("CASE", row, flush=True)
            data = ref = result = weights = None
            try:
                torch.manual_seed(123)
                qt = quant_types[quant]
                ok, cfg = get_aiter_moe_config(
                    M=m, E=e, N1=2*n, N2=k, K=k, top_k=topk,
                    block_size=0, dtype=dtypes.fp8 if quant == "fp8_w8a8" else dtypes.bf16, quant_type=qt,
                    use_shuffle=0, spec_sol_type=MoeSolutionType.MOE_C)
                if not ok or cfg.solution_type != MoeSolutionType.MOE_C:
                    raise RuntimeError("MoE-C config was not selected")
                row["mode_up"] = cfg.config["MODE"]
                row["BM"] = cfg.config["BLOCK_SIZE_M"]
                up_key = min(up, key=lambda key: abs(int(key) - m))
                if cfg.config["MODE"] != up[up_key]["MODE"]:
                    raise AssertionError("config lookup selected another file")
                down_key = min(down, key=lambda key: abs(int(key) - m))
                row["mode_down"] = down[down_key]["MODE"]
                is_w4 = quant == "int8_w4a8"
                if is_w4:
                    data = prepare_w4a8_inputs(m, k, n, e, topk, dtypes.bf16)
                    ref = run_w4a8_perchannel_golden(
                        data["input"], data["w1_ref"], data["w2_ref"],
                        data["topk_weights"], data["topk_ids"], dtypes.bf16,
                        data["w1_scales"], data["w2_scales"])
                else:
                    dtype = dtypes.fp8 if quant == "fp8_w8a8" else dtypes.bf16
                    data = prepare_w8a8_channelwise_inputs(m, k, n, e, topk, dtype, qt)
                    if quant == "fp8_w8a8":
                        ref = run_fp8_channelwise_golden(
                            data["input"], data["w1_qweight"], data["w2_qweight"],
                            data["topk_weights"], data["topk_ids"], dtypes.bf16,
                            data["w1_scales"], data["w2_scales"], data["a1_scales"], e)
                    else:
                        ref = torch_moe(data["input_ref"], data["w1_ref"],
                                        data["w2_ref"], data["topk_weights"], data["topk_ids"])
                weights = (data["w1_qweight"], data["w2_qweight"])
                if cfg.need_shuffle:
                    weights = aiter_moe_shfl_weight(*weights, cfg)
                result = aiter_moe(
                    hidden_states=data["input"], w1=weights[0], w2=weights[1],
                    topk_weights=data["topk_weights"], topk_ids=data["topk_ids"],
                    moe_config=cfg, inplace=False, activation="silu",
                    w1_scale=data["w1_scales"] / 16 if is_w4 else data["w1_scales"],
                    w2_scale=data["w2_scales"] / 16 if is_w4 else data["w2_scales"],
                    w1_zp=None, w2_zp=None,
                    a1_scale=None if is_w4 else data["a1_scales"], a2_scale=None,
                    block_shape=None, global_num_experts=e, expert_map=None,
                    output_dtype=dtypes.bf16, use_weight_shuffle=cfg.need_shuffle)
                torch.cuda.synchronize()
                if not torch.isfinite(result).all():
                    raise AssertionError("non-finite output")
                ratio = float(checkAllclose(ref.to(result.dtype), result, atol=.5, rtol=.01))
                row["error_ratio"] = ratio
                if ratio > .03:
                    raise AssertionError("error ratio exceeds 3%: %s" % ratio)
                row["status"] = "passed"
            except Exception as exc:
                row["status"] = "oom" if "out of memory" in str(exc).lower() else "failed"
                row["error"] = repr(exc)
                traceback.print_exc()
            finally:
                data = ref = result = weights = None
                gc.collect()
                torch.cuda.empty_cache()
            rows.append(row)
            with (out / ("shard%d.csv" % args.shard_index)).open("w", newline="") as handle:
                writer = csv.DictWriter(handle, fieldnames=list(row))
                writer.writeheader()
                writer.writerows(rows)
            print("RESULT", row, flush=True)
    print("SUMMARY", {s: sum(r["status"] == s for r in rows)
                      for s in ("passed", "failed", "oom")}, flush=True)
    print("NON_PASSING", [r for r in rows if r["status"] != "passed"], flush=True)
    return int(any(r["status"] == "failed" for r in rows))


if __name__ == "__main__":
    sys.exit(main())
