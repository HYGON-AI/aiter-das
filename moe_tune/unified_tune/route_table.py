# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Backend-selection ("route") table for fused_moe.

One row per tuned shape group + token: which backend tune_moe measured fastest
while passing the numeric check. Only the backend choice is recorded; the
solution/config stays in each backend's own table, and the router's
BACKEND_LAYOUTS check still decides whether a backend can use the weights.

Format (fixed header, plain csv module, so the router can read it with the
standard library only):

    arch,quant_type,indtype,inter_dim,model_dim,expert,topk,q_size_n,q_size_k,token,backend,time_us

``quant_type`` uses the tune_spec.QUANTS vocabulary restricted to the routed
families (ROUTE_QUANT_TYPES below). ``token`` is part of the row because a
lookup uses the nearest tuned token; on a tie the smaller token wins.
"""

import csv
import io
from bisect import bisect_left
from pathlib import Path

ROUTE_COLUMNS = ("arch", "quant_type", "indtype", "inter_dim", "model_dim",
                 "expert", "topk", "q_size_n", "q_size_k", "token",
                 "backend", "time_us")
GROUP_KEY = ROUTE_COLUMNS[:9]          # shape identity, excludes token/backend/time
BACKEND_COL = "backend"
TIME_COL = "time_us"
ROUTE_FILENAME = "tuned_fused_moe_route.csv"

# Valid quant_type values: tune_spec.QUANTS without the int4 families, which
# fused_moe does not route, so no route rows are written for them.
ROUTE_QUANT_TYPES = ("int8_w8a8_channel", "f8_w8a8_channel", "int8_w8a8_block",
                     "f8_w8a8_block", "no_quant", "int8_w8a16")

# ck is accepted on the write side; fused_moe_router keeps it out of
# _CANDIDATE_ORDER and selects it only via an explicit route row.
VALID_BACKENDS = ("asm", "triton", "moe_c", "ck")


def write_route_csv(rows):
    """Serialize route rows (dicts with ROUTE_COLUMNS keys) -> utf-8 bytes."""
    out = io.StringIO(newline="")
    writer = csv.DictWriter(out, fieldnames=list(ROUTE_COLUMNS), lineterminator="\n")
    writer.writeheader()
    for row in rows:
        writer.writerow({c: row.get(c, "") for c in ROUTE_COLUMNS})
    return out.getvalue().encode("utf-8")


def parse_route_csv(csv_bytes):
    """Bytes -> list[dict] with normalized values; malformed rows are skipped."""
    if not csv_bytes:
        return []
    rows = []
    for raw in csv.DictReader(io.StringIO(csv_bytes.decode("utf-8-sig"))):
        try:
            row = {c: (raw.get(c) or "").strip() for c in ROUTE_COLUMNS}
            row["token"] = int(row["token"])
        except (KeyError, TypeError, ValueError):
            continue
        if not row["arch"] or not row["backend"]:
            continue
        if row["quant_type"] and row["quant_type"] not in ROUTE_QUANT_TYPES:
            continue
        if row["backend"] not in VALID_BACKENDS:
            continue
        rows.append(row)
    return rows


def build_index(rows):
    """rows -> {group9: (ascending tokens, backends, times)}. Later rows win
    within an identical (group, token) (merge guarantees no old duplicates)."""
    groups = {}
    for row in rows:
        key = tuple(row[c] for c in GROUP_KEY)
        tokens, backends, times = groups.setdefault(key, ([], [], []))
        token = row["token"]
        for i, existing in enumerate(tokens):
            if existing == token:
                tokens[i], backends[i], times[i] = token, row["backend"], row["time_us"]
                break
        else:
            tokens.append(token)
            backends.append(row["backend"])
            times.append(row["time_us"])
    for key, (tokens, backends, times) in groups.items():
        order = sorted(range(len(tokens)), key=lambda i: tokens[i])
        groups[key] = ([tokens[i] for i in order],
                       [backends[i] for i in order], [times[i] for i in order])
    return groups


def load_route_table(path):
    """Read a route CSV from disk; missing file -> None (router falls back to
    the static _CANDIDATE_ORDER, zero impact on untuned environments)."""
    path = Path(path)
    if not path.is_file():
        return None
    return build_index(parse_route_csv(path.read_bytes()))


def route_group_key(values):
    """Normalize the GROUP_KEY values of a row to a tuple of strings."""
    return tuple(str(v) for v in values)


def lookup_route(index, key, token):
    """(backend, time_us) for group key + nearest token (ties LEFT), else None."""
    entry = index.get(route_group_key(key)) if index else None
    if not entry:
        return None
    tokens, backends, times = entry
    token = int(token)
    if token <= tokens[0]:
        return backends[0], times[0]
    if token >= tokens[-1]:
        return backends[-1], times[-1]
    idx = bisect_left(tokens, token)
    if tokens[idx] == token:
        return backends[idx], times[idx]
    left, right = idx - 1, idx
    if token - tokens[left] <= tokens[right] - token:  # ties to the left
        return backends[left], times[left]
    return backends[right], times[right]


def merge_route_csv(old_bytes, new_bytes):
    """Merge installed (old) with freshly tuned (new) route rows.

    Group identity is the full 9-column key (arch, quant_type, indtype,
    inter_dim, model_dim, expert, topk, q_size_n, q_size_k), so unlike the
    asm base table there is no dtype/group-size ambiguity the native key
    cannot distinguish -- the only collision class left is duplicate
    (group, token) rows in OLD (corruption: refuse, mirror merge_csv), while
    new rows overwrite same-key old rows and untouched old rows are kept.
    """
    old = parse_route_csv(old_bytes)
    new = parse_route_csv(new_bytes)
    seen = set()
    rows = {}
    for r in old:
        k = (route_group_key(r[c] for c in GROUP_KEY), r["token"])
        if k in seen:
            raise ValueError("existing route CSV contains duplicate runtime "
                             "keys; resolve them before installation")
        seen.add(k)
        rows[k] = r
    for r in new:
        rows[(route_group_key(r[c] for c in GROUP_KEY), r["token"])] = r
    out = io.StringIO(newline="")
    writer = csv.DictWriter(out, fieldnames=list(ROUTE_COLUMNS), lineterminator="\n")
    writer.writeheader()
    for k in sorted(rows):
        row = dict(rows[k])
        row["token"] = k[1]
        writer.writerow({c: row.get(c, "") for c in ROUTE_COLUMNS})
    return out.getvalue().encode("utf-8")


def install_route(files, runtime):
    """Transactionally merge+install route CSVs into runtime['route_config_dir'].

    Mirrors tune_artifacts.install(): exclusive lock + journal through
    transactional_replace; refuses targets outside the config directory.
    """
    from .tune_artifacts import exclusive_lock, transactional_replace

    directory = Path(runtime["route_config_dir"]).resolve()
    directory.mkdir(parents=True, exist_ok=True)
    with exclusive_lock(directory / ".moe_tune_route_install.lock"):
        replacements = {}
        for source in map(Path, files):
            target = directory / source.name
            new = source.read_bytes()
            old = target.read_bytes() if target.exists() else None
            replacements[target] = merge_route_csv(old, new)
        return transactional_replace(directory, replacements)
