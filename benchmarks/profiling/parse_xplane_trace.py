#!/usr/bin/env python3
# Copyright 2026 BrainX Ecosystem Limited. All Rights Reserved.
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
# ==============================================================================

"""Summarize BrainCell JAX scopes from an XPlane profiler trace."""

from __future__ import annotations

import argparse
from collections import defaultdict
from dataclasses import dataclass
import json
import os
from pathlib import Path
import re
import sys


BRAINCELL_PREFIX = "braincell:"
PS_PER_MS = 1_000_000_000.0
PS_PER_US = 1_000_000.0


@dataclass(frozen=True)
class ScopeSummary:
    """Aggregated duration for one BrainCell trace scope.

    Parameters
    ----------
    scope : str
        Named JAX scope, for example ``braincell:cell_update:solver``.
    calls : int
        Number of GPU events attributed to this scope.
    total_ps : int
        Sum of attributed event durations in picoseconds.
    """

    scope: str
    calls: int
    total_ps: int
    grid: str | None = None
    block: str | None = None
    occ_pct_sum: float = 0.0
    occ_pct_count: int = 0

    @property
    def mean_occ_pct(self) -> float | None:
        """Return mean occupancy percentage parsed from kernel metadata."""
        if self.occ_pct_count == 0:
            return None
        return self.occ_pct_sum / self.occ_pct_count


@dataclass(frozen=True)
class KernelSummary:
    """Aggregated GPU events for one kernel/HLO/launch-geometry tuple."""

    name: str
    hlo_op: str | None
    calls: int
    total_ps: int
    grid: str | None = None
    block: str | None = None
    occ_pct_sum: float = 0.0
    occ_pct_count: int = 0

    @property
    def mean_occ_pct(self) -> float | None:
        """Return mean occupancy percentage parsed from kernel metadata."""
        if self.occ_pct_count == 0:
            return None
        return self.occ_pct_sum / self.occ_pct_count


@dataclass(frozen=True)
class TraceSummary:
    """Aggregated BrainCell GPU trace attribution."""

    mode: str
    xplane_path: Path
    device_planes: tuple[str, ...]
    total_gpu_events: int
    total_gpu_time_ps: int
    matched_gpu_events: int
    matched_gpu_time_ps: int
    scopes: tuple[ScopeSummary, ...]
    kernels: tuple[KernelSummary, ...]


@dataclass(frozen=True)
class DHSLevelSummary:
    """Aggregated duration for one toy DHS level scope.

    Parameters
    ----------
    phase : str
        DHS toy phase, for example ``'forward'`` or ``'backward'``.
    level : int
        Static tree level encoded in the profiler scope.
    width : int
        Number of independent tree nodes in the level.
    popsize : int or None
        Batched cell count encoded in the scope or supplied by the caller.
    calls : int
        Number of GPU events attributed to the level.
    total_ps : int
        Sum of attributed event durations in picoseconds.
    """

    phase: str
    level: int
    width: int
    popsize: int | None
    calls: int
    total_ps: int
    grid: str | None = None
    block: str | None = None
    occ_pct: float | None = None

    @property
    def work_items(self) -> int | None:
        """Return ``width * popsize`` when the population size is known."""
        if self.popsize is None:
            return None
        return self.width * self.popsize


DHS_TOY_LEVEL_RE = re.compile(
    r"^braincell:dhs_toy:"
    r"(?P<phase>[^:]+):"
    r"level=(?P<level>\d+):"
    r"width=(?P<width>\d+)"
    r"(?::pop=(?P<popsize>\d+))?"
)
DHS_REAL_LEVEL_RE = re.compile(
    r"^braincell:dhs:"
    r"(?P<phase>forward_level):"
    r"i=(?P<level>\d+):"
    r"edges=(?P<width>\d+)"
    r"(?::batch=(?P<popsize>\d+))?"
)


def main(argv: list[str] | None = None) -> int:
    """Run the XPlane trace parser command."""
    args = _parse_args(argv)
    xplane_path = args.xplane or _latest_xplane(Path(args.trace_dir))
    summary = summarize_xplane(
        xplane_path,
        mode=args.mode,
        scope_prefix=args.scope_prefix,
        device_filter=args.device_filter,
    )
    _print_summary(summary, limit=args.limit)
    if args.kernel_table:
        _print_kernel_table(summary, limit=args.limit)
    dhs_levels = None
    if args.dhs_level_table:
        dhs_levels = summarize_dhs_level_scopes(
            summary,
            popsize=args.dhs_popsize,
        )
        _print_dhs_level_table(summary, dhs_levels)
    if args.out:
        out_path = Path(args.out)
        out_path.parent.mkdir(parents=True, exist_ok=True)
        out_path.write_text(json.dumps(_summary_to_json(summary, dhs_levels=dhs_levels), indent=2) + "\n")
        print(f"\nWrote {out_path}")
    return 0


def summarize_xplane(
    xplane_path: str | Path,
    *,
    mode: str = "leaf",
    scope_prefix: str = BRAINCELL_PREFIX,
    device_filter: str = "/device:GPU:",
) -> TraceSummary:
    """Aggregate BrainCell scope timings from a JAX XPlane trace.

    Parameters
    ----------
    xplane_path : str or pathlib.Path
        Path to a ``*.xplane.pb`` generated by ``jax.profiler.trace``.
    mode : {'leaf', 'inclusive'}
        Attribution mode. ``'leaf'`` charges each event to the deepest matching
        scope. ``'inclusive'`` charges it to every matching scope in the HLO
        path.
    scope_prefix : str
        Prefix used to identify BrainCell scopes in XPlane metadata.
    device_filter : str
        Plane-name prefix to include. The default keeps GPU event timelines.

    Returns
    -------
    TraceSummary
        Aggregated event counts and durations by scope.
    """
    if mode not in {"leaf", "inclusive"}:
        raise ValueError("mode must be 'leaf' or 'inclusive'.")

    path = Path(xplane_path)
    xplane_pb2 = _import_xplane_pb2()
    if xplane_pb2 is None:
        return _summarize_xplane_trace_viewer_json(
            path,
            mode=mode,
            scope_prefix=scope_prefix,
            device_filter=device_filter,
        )

    xspace = xplane_pb2.XSpace()
    xspace.ParseFromString(path.read_bytes())

    scope_calls: dict[str, int] = defaultdict(int)
    scope_time: dict[str, int] = defaultdict(int)
    scope_grid: dict[str, str] = {}
    scope_block: dict[str, str] = {}
    scope_occ_sum: dict[str, float] = defaultdict(float)
    scope_occ_count: dict[str, int] = defaultdict(int)
    kernel_calls: dict[tuple[str, str | None, str | None, str | None], int] = defaultdict(int)
    kernel_time: dict[tuple[str, str | None, str | None, str | None], int] = defaultdict(int)
    kernel_occ_sum: dict[tuple[str, str | None, str | None, str | None], float] = defaultdict(float)
    kernel_occ_count: dict[tuple[str, str | None, str | None, str | None], int] = defaultdict(int)
    matched_events = 0
    matched_time = 0
    total_events = 0
    total_time = 0
    device_planes: list[str] = []

    for plane in xspace.planes:
        if device_filter and not plane.name.startswith(device_filter):
            continue
        if not plane.lines:
            continue
        device_planes.append(plane.name)
        stat_names = {key: value.name for key, value in plane.stat_metadata.items()}
        ref_names = {key: value.name for key, value in plane.stat_metadata.items()}
        event_names = {key: value.name for key, value in plane.event_metadata.items()}
        name_stat_ids = {key for key, name in stat_names.items() if name in {"name", "hlo_op"}}
        for line in plane.lines:
            for event in line.events:
                total_events += 1
                total_time += int(event.duration_ps)
                details = _parse_kernel_details(_event_kernel_details(event))
                kernel_name = event_names.get(event.metadata_id, f"metadata:{event.metadata_id}")
                hlo_op = _protobuf_event_hlo_op(event, stat_names=stat_names, ref_names=ref_names)
                kernel_key = (
                    kernel_name,
                    hlo_op,
                    _optional_string(details.get("grid")),
                    _optional_string(details.get("block")),
                )
                kernel_calls[kernel_key] += 1
                kernel_time[kernel_key] += int(event.duration_ps)
                if details.get("occ_pct") is not None:
                    kernel_occ_sum[kernel_key] += float(details["occ_pct"])
                    kernel_occ_count[kernel_key] += 1
                scopes = _event_scopes(
                    event,
                    name_stat_ids=name_stat_ids,
                    ref_names=ref_names,
                    scope_prefix=scope_prefix,
                )
                if not scopes:
                    continue
                attributed = scopes[-1:] if mode == "leaf" else scopes
                duration_ps = int(event.duration_ps)
                matched_events += 1
                matched_time += duration_ps
                for scope in attributed:
                    scope_calls[scope] += 1
                    scope_time[scope] += duration_ps
                    if details.get("grid") and scope not in scope_grid:
                        scope_grid[scope] = str(details["grid"])
                    if details.get("block") and scope not in scope_block:
                        scope_block[scope] = str(details["block"])
                    if details.get("occ_pct") is not None:
                        scope_occ_sum[scope] += float(details["occ_pct"])
                        scope_occ_count[scope] += 1

    scopes = tuple(
        ScopeSummary(
            scope=scope,
            calls=scope_calls[scope],
            total_ps=total_ps,
            grid=scope_grid.get(scope),
            block=scope_block.get(scope),
            occ_pct_sum=scope_occ_sum[scope],
            occ_pct_count=scope_occ_count[scope],
        )
        for scope, total_ps in sorted(
            scope_time.items(),
            key=lambda item: (-item[1], item[0]),
        )
    )
    return TraceSummary(
        mode=mode,
        xplane_path=path,
        device_planes=tuple(device_planes),
        total_gpu_events=total_events,
        total_gpu_time_ps=total_time,
        matched_gpu_events=matched_events,
        matched_gpu_time_ps=matched_time,
        scopes=scopes,
        kernels=_kernel_summaries(
            kernel_calls,
            kernel_time,
            kernel_occ_sum,
            kernel_occ_count,
        ),
    )


def summarize_trace_viewer_json(
    trace_path: str | Path,
    *,
    mode: str = "leaf",
    scope_prefix: str = BRAINCELL_PREFIX,
    device_filter: str = "/device:GPU:",
) -> TraceSummary:
    """Aggregate BrainCell scope timings from trace viewer JSON.

    Parameters
    ----------
    trace_path : str or pathlib.Path
        Path to a trace viewer JSON file produced by XProf.
    mode : {'leaf', 'inclusive'}
        Attribution mode. ``'leaf'`` charges each event to the deepest matching
        scope. ``'inclusive'`` charges it to every matching scope in the HLO
        path.
    scope_prefix : str
        Prefix used to identify BrainCell scopes in trace metadata.
    device_filter : str
        Process-name prefix to include. The default keeps GPU event timelines.

    Returns
    -------
    TraceSummary
        Aggregated event counts and durations by scope.
    """
    path = Path(trace_path)
    return _summarize_trace_viewer_events(
        path,
        json.loads(path.read_text()),
        mode=mode,
        scope_prefix=scope_prefix,
        device_filter=device_filter,
    )


def summarize_dhs_level_scopes(
    summary: TraceSummary,
    *,
    popsize: int | None = None,
) -> tuple[DHSLevelSummary, ...]:
    """Extract level-wise toy DHS rows from a trace summary.

    Parameters
    ----------
    summary : TraceSummary
        Parsed trace summary containing ``braincell:dhs_toy`` scopes.
    popsize : int or None
        Optional batched cell count used when the scope name does not encode
        one.

    Returns
    -------
    tuple of DHSLevelSummary
        Rows sorted by phase and level.
    """
    rows: list[DHSLevelSummary] = []
    for scope in summary.scopes:
        match = DHS_TOY_LEVEL_RE.match(scope.scope)
        if match is None:
            match = DHS_REAL_LEVEL_RE.match(scope.scope)
        if match is None:
            continue
        encoded_popsize = match.group("popsize")
        row_popsize = int(encoded_popsize) if encoded_popsize is not None else popsize
        rows.append(
            DHSLevelSummary(
                phase=match.group("phase"),
                level=int(match.group("level")),
                width=int(match.group("width")),
                popsize=row_popsize,
                calls=scope.calls,
                total_ps=scope.total_ps,
                grid=scope.grid,
                block=scope.block,
                occ_pct=scope.mean_occ_pct,
            )
        )
    phase_order = {"forward": 0, "forward_level": 0, "root": 1, "backward": 2}
    return tuple(
        sorted(
            rows,
            key=lambda row: (phase_order.get(row.phase, 99), row.level, row.width),
        )
    )


def _event_scopes(
    event,
    *,
    name_stat_ids: set[int],
    ref_names: dict[int, str],
    scope_prefix: str,
) -> tuple[str, ...]:
    for stat in event.stats:
        if stat.metadata_id not in name_stat_ids:
            continue
        value = _stat_string(stat, ref_names)
        if value and scope_prefix in value:
            return _scopes_from_path(value, scope_prefix=scope_prefix)
    return ()


def _stat_string(stat, ref_names: dict[int, str]) -> str | None:
    if stat.HasField("str_value"):
        return stat.str_value
    if stat.HasField("bytes_value"):
        return stat.bytes_value.decode("utf-8", errors="replace")
    if stat.HasField("ref_value"):
        return ref_names.get(stat.ref_value)
    return None


def _scopes_from_path(path: str, *, scope_prefix: str) -> tuple[str, ...]:
    scopes: list[str] = []
    for part in path.split("/"):
        if part.startswith(scope_prefix):
            scopes.append(part)
    return tuple(scopes)


def _summarize_xplane_trace_viewer_json(
    xplane_path: Path,
    *,
    mode: str,
    scope_prefix: str,
    device_filter: str,
) -> TraceSummary:
    os.environ.setdefault("TF_CPP_MIN_LOG_LEVEL", "2")
    try:
        from xprof.convert import raw_to_tool_data
    except Exception as exc:  # pragma: no cover - depends on local install
        raise RuntimeError(
            "Parsing XPlane traces requires either TensorFlow's XPlane protobuf module or xprof."
        ) from exc

    data, _content_type = raw_to_tool_data.xspace_to_tool_data(
        [str(xplane_path)],
        "trace_viewer",
        {"use_saved_result": False},
    )
    if isinstance(data, bytes):
        data = data.decode("utf-8")
    return _summarize_trace_viewer_events(
        xplane_path,
        json.loads(data),
        mode=mode,
        scope_prefix=scope_prefix,
        device_filter=device_filter,
    )


def _summarize_trace_viewer_events(
    trace_path: Path,
    trace: dict,
    *,
    mode: str,
    scope_prefix: str,
    device_filter: str,
) -> TraceSummary:
    if mode not in {"leaf", "inclusive"}:
        raise ValueError("mode must be 'leaf' or 'inclusive'.")

    process_names: dict[int, str] = {}
    for event in trace.get("traceEvents", ()):
        if event.get("ph") == "M" and event.get("name") == "process_name":
            process_names[int(event["pid"])] = event.get("args", {}).get("name", "")

    scope_calls: dict[str, int] = defaultdict(int)
    scope_time: dict[str, int] = defaultdict(int)
    scope_grid: dict[str, str] = {}
    scope_block: dict[str, str] = {}
    scope_occ_sum: dict[str, float] = defaultdict(float)
    scope_occ_count: dict[str, int] = defaultdict(int)
    kernel_calls: dict[tuple[str, str | None, str | None, str | None], int] = defaultdict(int)
    kernel_time: dict[tuple[str, str | None, str | None, str | None], int] = defaultdict(int)
    kernel_occ_sum: dict[tuple[str, str | None, str | None, str | None], float] = defaultdict(float)
    kernel_occ_count: dict[tuple[str, str | None, str | None, str | None], int] = defaultdict(int)
    matched_events = 0
    matched_time = 0
    total_events = 0
    total_time = 0
    device_planes: list[str] = []
    seen_planes: set[str] = set()

    for event in trace.get("traceEvents", ()):
        if event.get("ph") != "X":
            continue
        process_name = process_names.get(int(event.get("pid", -1)), "")
        if device_filter and not process_name.startswith(device_filter):
            continue
        args = event.get("args", {})
        if "kernel_details" not in args and "hlo_op" not in args:
            continue
        duration_ps = int(round(float(event.get("dur", 0.0)) * PS_PER_US))
        total_events += 1
        total_time += duration_ps
        details = _parse_kernel_details(_event_kernel_details(event))
        event_args = event.get("args", {})
        kernel_key = (
            str(event.get("name", "<unknown>")),
            _optional_string(event_args.get("hlo_op") or event_args.get("name")),
            _optional_string(details.get("grid")),
            _optional_string(details.get("block")),
        )
        kernel_calls[kernel_key] += 1
        kernel_time[kernel_key] += duration_ps
        if details.get("occ_pct") is not None:
            kernel_occ_sum[kernel_key] += float(details["occ_pct"])
            kernel_occ_count[kernel_key] += 1
        scopes = _trace_viewer_event_scopes(
            event,
            scope_prefix=scope_prefix,
        )
        if not scopes:
            continue
        if process_name not in seen_planes:
            seen_planes.add(process_name)
            device_planes.append(process_name)
        attributed = scopes[-1:] if mode == "leaf" else scopes
        matched_events += 1
        matched_time += duration_ps
        for scope in attributed:
            scope_calls[scope] += 1
            scope_time[scope] += duration_ps
            if details.get("grid") and scope not in scope_grid:
                scope_grid[scope] = str(details["grid"])
            if details.get("block") and scope not in scope_block:
                scope_block[scope] = str(details["block"])
            if details.get("occ_pct") is not None:
                scope_occ_sum[scope] += float(details["occ_pct"])
                scope_occ_count[scope] += 1

    scopes = tuple(
        ScopeSummary(
            scope=scope,
            calls=scope_calls[scope],
            total_ps=total_ps,
            grid=scope_grid.get(scope),
            block=scope_block.get(scope),
            occ_pct_sum=scope_occ_sum[scope],
            occ_pct_count=scope_occ_count[scope],
        )
        for scope, total_ps in sorted(
            scope_time.items(),
            key=lambda item: (-item[1], item[0]),
        )
    )
    return TraceSummary(
        mode=mode,
        xplane_path=trace_path,
        device_planes=tuple(device_planes),
        total_gpu_events=total_events,
        total_gpu_time_ps=total_time,
        matched_gpu_events=matched_events,
        matched_gpu_time_ps=matched_time,
        scopes=scopes,
        kernels=_kernel_summaries(
            kernel_calls,
            kernel_time,
            kernel_occ_sum,
            kernel_occ_count,
        ),
    )


def _kernel_summaries(calls, total_time, occ_sum, occ_count) -> tuple[KernelSummary, ...]:
    rows = []
    for (name, hlo_op, grid, block), count in calls.items():
        key = (name, hlo_op, grid, block)
        rows.append(
            KernelSummary(
                name=name,
                hlo_op=hlo_op,
                calls=count,
                total_ps=total_time[key],
                grid=grid,
                block=block,
                occ_pct_sum=occ_sum[key],
                occ_pct_count=occ_count[key],
            )
        )
    return tuple(sorted(rows, key=lambda row: (-row.total_ps, row.name, row.hlo_op or "")))


def _protobuf_event_hlo_op(event, *, stat_names: dict[int, str], ref_names: dict[int, str]) -> str | None:
    fallback = None
    for stat in event.stats:
        name = stat_names.get(stat.metadata_id)
        if name not in {"hlo_op", "name"}:
            continue
        value = _stat_string(stat, ref_names)
        if not value:
            continue
        if name == "hlo_op":
            return value
        fallback = value
    return fallback


def _optional_string(value) -> str | None:
    return value if isinstance(value, str) and value else None


def _trace_viewer_event_scopes(
    event: dict,
    *,
    scope_prefix: str,
) -> tuple[str, ...]:
    args = event.get("args", {})
    for value in (args.get("name"), event.get("name"), args.get("hlo_op")):
        if isinstance(value, str) and scope_prefix in value:
            return _scopes_from_path(value, scope_prefix=scope_prefix)
    return ()


def _event_kernel_details(event) -> str | None:
    if isinstance(event, dict):
        value = event.get("args", {}).get("kernel_details")
        return value if isinstance(value, str) else None
    for stat in getattr(event, "stats", ()):
        value = _protobuf_stat_raw_string(stat)
        if value and ("grid:" in value or "block:" in value or "occ_pct:" in value):
            return value
    return None


def _protobuf_stat_raw_string(stat) -> str | None:
    if stat.HasField("str_value"):
        return stat.str_value
    if stat.HasField("bytes_value"):
        return stat.bytes_value.decode("utf-8", errors="replace")
    return None


def _parse_kernel_details(details: str | None) -> dict[str, str | float | None]:
    parsed: dict[str, str | float | None] = {
        "grid": None,
        "block": None,
        "occ_pct": None,
    }
    if not details:
        return parsed
    for key in ("grid", "block"):
        match = re.search(rf"(?:^|\s){key}:([^ ]+)", details)
        if match is not None:
            parsed[key] = match.group(1)
    occ_match = re.search(r"(?:^|\s)occ_pct:([0-9.]+)", details)
    if occ_match is not None:
        parsed["occ_pct"] = float(occ_match.group(1))
    return parsed


def _latest_xplane(trace_dir: Path) -> Path:
    matches = sorted(
        trace_dir.rglob("*.xplane.pb"),
        key=lambda path: path.stat().st_mtime,
        reverse=True,
    )
    if not matches:
        raise FileNotFoundError(f"No *.xplane.pb files found under {trace_dir}.")
    return matches[0]


def _print_summary(summary: TraceSummary, *, limit: int) -> None:
    print(f"xplane: {summary.xplane_path}")
    print(f"mode: {summary.mode}")
    print(f"device_planes: {', '.join(summary.device_planes) or '<none>'}")
    print(f"total_gpu_events: {summary.total_gpu_events}")
    print(f"total_gpu_time_ms: {summary.total_gpu_time_ps / PS_PER_MS:.6f}")
    print(f"matched_gpu_events: {summary.matched_gpu_events}")
    print(f"matched_gpu_time_ms: {summary.matched_gpu_time_ps / PS_PER_MS:.6f}")
    print(f"\n{'scope':<64} {'calls':>10} {'total_ms':>12} {'mean_us':>12} {'percent':>9}")
    print("-" * 112)
    rows = summary.scopes if limit <= 0 else summary.scopes[:limit]
    for row in rows:
        total_ms = row.total_ps / PS_PER_MS
        mean_us = row.total_ps / row.calls / PS_PER_US if row.calls else 0.0
        percent = row.total_ps / summary.matched_gpu_time_ps * 100.0 if summary.matched_gpu_time_ps else 0.0
        print(f"{row.scope:<64} {row.calls:>10} {total_ms:>12.6f} {mean_us:>12.3f} {percent:>8.2f}%")


def _print_kernel_table(summary: TraceSummary, *, limit: int) -> None:
    print(
        "\n"
        f"{'kernel':<36} {'calls':>8} {'total_ms':>12} {'mean_us':>12} "
        f"{'pct':>8} {'occ%':>8} {'grid':>12} {'block':>12} {'hlo_op':<48}"
    )
    print("-" * 168)
    rows = summary.kernels if limit <= 0 else summary.kernels[:limit]
    for row in rows:
        mean_us = row.total_ps / row.calls / PS_PER_US if row.calls else 0.0
        percent = row.total_ps / summary.total_gpu_time_ps * 100.0 if summary.total_gpu_time_ps else 0.0
        occ_text = f"{row.mean_occ_pct:.2f}" if row.mean_occ_pct is not None else "<none>"
        print(
            f"{row.name[:36]:<36} {row.calls:>8} {row.total_ps / PS_PER_MS:>12.6f} "
            f"{mean_us:>12.3f} {percent:>7.2f}% {occ_text:>8} "
            f"{(row.grid or '<none>'):>12} {(row.block or '<none>'):>12} "
            f"{(row.hlo_op or '<none>')[:48]:<48}"
        )


def _print_dhs_level_table(
    summary: TraceSummary,
    rows: tuple[DHSLevelSummary, ...],
) -> None:
    if not rows:
        print("\nNo DHS level scopes matched.")
        return
    print(
        "\n"
        f"{'phase':<14} {'level':>5} {'items':>8} {'work':>12} "
        f"{'calls':>8} {'total_ms':>12} {'pct':>8} {'us/work':>10} "
        f"{'occ%':>8} {'grid':>12} {'block':>12}"
    )
    print("-" * 120)
    for row in rows:
        total_ms = row.total_ps / PS_PER_MS
        percent = row.total_ps / summary.matched_gpu_time_ps * 100.0 if summary.matched_gpu_time_ps else 0.0
        work_items = row.work_items
        us_per_work = row.total_ps / PS_PER_US / work_items if work_items else 0.0
        work_text = str(work_items) if work_items is not None else "<unknown>"
        occ_text = f"{row.occ_pct:.2f}" if row.occ_pct is not None else "<none>"
        print(
            f"{row.phase:<14} {row.level:>5} {row.width:>8} {work_text:>12} "
            f"{row.calls:>8} {total_ms:>12.6f} {percent:>7.2f}% "
            f"{us_per_work:>10.6f} {occ_text:>8} "
            f"{(row.grid or '<none>'):>12} {(row.block or '<none>'):>12}"
        )
    _print_dhs_phase_summary(summary, rows)


def _print_dhs_phase_summary(
    summary: TraceSummary,
    rows: tuple[DHSLevelSummary, ...],
) -> None:
    phases = sorted({row.phase for row in rows})
    print("\nDHS level phase summary")
    print(f"{'phase':<10} {'levels':>8} {'total_ms':>12} {'pct':>8}")
    print("-" * 42)
    for phase in phases:
        phase_rows = [row for row in rows if row.phase == phase]
        total_ps = sum(row.total_ps for row in phase_rows)
        percent = total_ps / summary.matched_gpu_time_ps * 100.0 if summary.matched_gpu_time_ps else 0.0
        print(f"{phase:<10} {len(phase_rows):>8} {total_ps / PS_PER_MS:>12.6f} {percent:>7.2f}%")


def _summary_to_json(
    summary: TraceSummary,
    *,
    dhs_levels: tuple[DHSLevelSummary, ...] | None = None,
) -> dict:
    return {
        "mode": summary.mode,
        "xplane_path": str(summary.xplane_path),
        "device_planes": list(summary.device_planes),
        "total_gpu_events": summary.total_gpu_events,
        "total_gpu_time_ms": summary.total_gpu_time_ps / PS_PER_MS,
        "matched_gpu_events": summary.matched_gpu_events,
        "matched_gpu_time_ms": summary.matched_gpu_time_ps / PS_PER_MS,
        "scopes": [
            {
                "scope": row.scope,
                "calls": row.calls,
                "total_ms": row.total_ps / PS_PER_MS,
                "mean_us": row.total_ps / row.calls / PS_PER_US if row.calls else 0.0,
                "grid": row.grid,
                "block": row.block,
                "occ_pct": row.mean_occ_pct,
                "percent_of_matched": (
                    row.total_ps / summary.matched_gpu_time_ps * 100.0 if summary.matched_gpu_time_ps else 0.0
                ),
            }
            for row in summary.scopes
        ],
        "kernels": [
            {
                "name": row.name,
                "hlo_op": row.hlo_op,
                "calls": row.calls,
                "total_ms": row.total_ps / PS_PER_MS,
                "mean_us": row.total_ps / row.calls / PS_PER_US if row.calls else 0.0,
                "grid": row.grid,
                "block": row.block,
                "occ_pct": row.mean_occ_pct,
                "percent_of_gpu_time": (
                    row.total_ps / summary.total_gpu_time_ps * 100.0 if summary.total_gpu_time_ps else 0.0
                ),
            }
            for row in summary.kernels
        ],
        "dhs_levels": [
            {
                "phase": row.phase,
                "level": row.level,
                "width": row.width,
                "popsize": row.popsize,
                "work_items": row.work_items,
                "calls": row.calls,
                "total_ms": row.total_ps / PS_PER_MS,
                "grid": row.grid,
                "block": row.block,
                "occ_pct": row.occ_pct,
                "percent_of_matched": (
                    row.total_ps / summary.matched_gpu_time_ps * 100.0 if summary.matched_gpu_time_ps else 0.0
                ),
                "us_per_work_item": (row.total_ps / PS_PER_US / row.work_items if row.work_items else None),
            }
            for row in (dhs_levels or ())
        ],
    }


def _parse_args(argv: list[str] | None) -> argparse.Namespace:
    parser = argparse.ArgumentParser(
        description=__doc__,
        formatter_class=argparse.ArgumentDefaultsHelpFormatter,
    )
    source = parser.add_mutually_exclusive_group(required=True)
    source.add_argument("--xplane", type=Path, default=None)
    source.add_argument("--trace-dir", type=Path, default=None)
    parser.add_argument("--mode", choices=("leaf", "inclusive"), default="leaf")
    parser.add_argument("--scope-prefix", "--prefix", default=BRAINCELL_PREFIX)
    parser.add_argument("--device-filter", default="/device:GPU:")
    parser.add_argument("--limit", type=int, default=40)
    parser.add_argument(
        "--kernel-table",
        action="store_true",
        help="Print GPU kernels grouped by HLO operation and launch geometry.",
    )
    parser.add_argument(
        "--dhs-level-table",
        action="store_true",
        help="Print a level-wise table for braincell:dhs_toy scopes.",
    )
    parser.add_argument(
        "--dhs-popsize",
        type=int,
        default=None,
        help="Population size for DHS toy scopes that do not encode pop=.",
    )
    parser.add_argument("--out", default=None)
    return parser.parse_args(argv)


def _import_xplane_pb2():
    os.environ.setdefault("TF_CPP_MIN_LOG_LEVEL", "2")
    try:
        from tensorflow.tsl.profiler.protobuf import xplane_pb2
    except Exception:  # pragma: no cover - depends on local install
        return None
    return xplane_pb2


if __name__ == "__main__":
    sys.exit(main())
