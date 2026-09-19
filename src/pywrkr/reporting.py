"""Output formatting, reporting, and observability exports for pywrkr."""

import csv
import importlib.resources
import importlib.util
import json
import logging
import math
import re
import statistics
import sys
from collections import defaultdict
from string import Template
from typing import TYPE_CHECKING, NamedTuple, Sequence, TextIO
from urllib.parse import urlparse

from pywrkr.compare import (
    EXIT_USAGE,
    SCHEMA_VERSION,
    ResultsError,
    compare_results,
    load_baseline,
    render_report,
)
from pywrkr.config import (
    BenchmarkConfig,
    LatencyBreakdown,
    StepResult,
    Threshold,
    WorkerStats,
)
from pywrkr.traffic_profiles import RateLimiter

if TYPE_CHECKING:  # pragma: no cover - typing only
    from pywrkr.config import WsStats

_logger = logging.getLogger(__name__)

# Optional third-party availability flags
RICH_AVAILABLE = importlib.util.find_spec("rich") is not None

try:
    from opentelemetry.exporter.otlp.proto.http.metric_exporter import OTLPMetricExporter
    from opentelemetry.sdk.metrics import MeterProvider
    from opentelemetry.sdk.metrics.export import PeriodicExportingMetricReader
    from opentelemetry.sdk.resources import Resource

    OTEL_AVAILABLE = True
except ImportError:
    OTEL_AVAILABLE = False

# ---------------------------------------------------------------------------
# Chart color constants
# ---------------------------------------------------------------------------

COLOR_GREEN = "rgba(76, 175, 80, 0.8)"
COLOR_YELLOW = "rgba(255, 193, 7, 0.8)"
COLOR_RED = "rgba(244, 67, 54, 0.8)"
COLOR_BLUE = "rgba(33, 150, 243, 0.8)"
COLOR_ORANGE = "rgba(255, 152, 0, 0.8)"
COLOR_PURPLE = "rgba(156, 39, 176, 0.8)"
COLOR_CYAN = "rgba(0, 188, 212, 0.8)"

# Status code colors (slightly higher opacity for pie chart)
STATUS_COLOR_2XX = "rgba(76, 175, 80, 0.85)"
STATUS_COLOR_3XX = "rgba(33, 150, 243, 0.85)"
STATUS_COLOR_4XX = "rgba(255, 152, 0, 0.85)"
STATUS_COLOR_5XX = "rgba(244, 67, 54, 0.85)"

# ---------------------------------------------------------------------------
# Latency breakdown aggregation
# ---------------------------------------------------------------------------


def aggregate_breakdowns(breakdowns: list[LatencyBreakdown]) -> dict:
    """Compute aggregate statistics for a list of LatencyBreakdown objects.

    Returns a dict with keys: dns, connect, tls, ttfb, transfer, total.
    Each has: avg, min, max, p50, p95, count.
    Also includes: new_connections, reused_connections.
    """
    if not breakdowns:
        return {}

    # Only report phases every sample actually measured. The httpx backend has
    # no hooks for DNS/TCP/TLS, and averaging in zeros for those would invent a
    # suspiciously fast connection phase rather than admitting it is unknown.
    measurable = set(getattr(breakdowns[0], "available", None) or ())
    for b in breakdowns[1:]:
        measurable &= set(getattr(b, "available", None) or ())

    phases = {
        "dns": [b.dns for b in breakdowns],
        "connect": [b.connect for b in breakdowns],
        "tls": [b.tls for b in breakdowns],
        "ttfb": [b.ttfb for b in breakdowns],
        "transfer": [b.transfer for b in breakdowns],
        "total": [b.dns + b.connect + b.tls + b.ttfb + b.transfer for b in breakdowns],
    }
    phases = {name: values for name, values in phases.items() if name in measurable}

    result: dict = {}
    # Connection reuse is only knowable from the connection-level hooks. Under
    # HTTP/2 in particular, "200 new connections" would be flatly wrong: that is
    # one connection carrying 200 streams.
    if "connect" in measurable:
        result["new_connections"] = sum(1 for b in breakdowns if not b.is_reused)
        result["reused_connections"] = sum(1 for b in breakdowns if b.is_reused)

    for name, values in phases.items():
        if not values:
            continue
        sorted_vals = sorted(values)
        n = len(sorted_vals)
        result[name] = {
            "avg": statistics.mean(values),
            "min": min(values),
            "max": max(values),
            "p50": sorted_vals[_nearest_rank_idx(50, n)],
            "p95": sorted_vals[_nearest_rank_idx(95, n)],
            "count": n,
        }

    return result


# ---------------------------------------------------------------------------
# Template loader
# ---------------------------------------------------------------------------


def _load_template(name: str) -> Template:
    """Load an HTML template from the templates package."""
    ref = importlib.resources.files("pywrkr.templates").joinpath(name)
    return Template(ref.read_text(encoding="utf-8"))


# ---------------------------------------------------------------------------
# Formatting helpers
# ---------------------------------------------------------------------------


def format_bytes(n: float) -> str:
    """Format byte count to human-readable string (B/KB/MB/GB/TB)."""
    for unit in ("B", "KB", "MB", "GB"):
        if abs(n) < 1024:
            return f"{n:.2f}{unit}"
        n /= 1024
    return f"{n:.2f}TB"


def format_duration(secs: float) -> str:
    """Format seconds to human-readable duration string (us/ms/s)."""
    if secs < 0.001:
        return f"{secs * 1_000_000:.2f}us"
    if secs < 1:
        return f"{secs * 1000:.2f}ms"
    return f"{secs:.2f}s"


def describe_session_mode(config: BenchmarkConfig) -> str:
    """Describe how cookies are scoped for this run, for banners and summaries."""
    if not config.session_cookies:
        return "off (static -C cookies only)"
    if config.scenario is not None and config.scenario.session == "fresh_per_iteration":
        return "cookie jar per user, cleared each iteration"
    return "cookie jar per user"


# ---------------------------------------------------------------------------
# Report printers
# ---------------------------------------------------------------------------


def print_latency_histogram(
    latencies: list[float], buckets: int = 20, file: TextIO = sys.stdout
) -> None:
    """Print an ASCII histogram of latency distribution."""
    # Drop non-finite samples (inf/NaN) so width math and int() bucketing
    # cannot crash or silently corrupt the histogram.
    latencies = [x for x in latencies if math.isfinite(x)]
    if not latencies:
        return
    mn, mx = min(latencies), max(latencies)
    if mn == mx:
        print(f"  All requests: {format_duration(mn)}", file=file)
        return
    width = (mx - mn) / buckets
    if not math.isfinite(width) or width <= 0:
        return
    counts = [0] * buckets
    for lat in latencies:
        idx = min(int((lat - mn) / width), buckets - 1)
        counts[idx] += 1
    max_count = max(counts)
    bar_max = 40
    print("  Latency Distribution (histogram):", file=file)
    for i, count in enumerate(counts):
        lo = mn + i * width
        hi = lo + width
        bar_len = int(count / max_count * bar_max) if max_count else 0
        bar = "#" * bar_len
        pct = count / len(latencies) * 100
        print(
            f"    {format_duration(lo):>10} - {format_duration(hi):>10} "
            f"| {bar:<{bar_max}} | {count:>6} ({pct:5.1f}%)",
            file=file,
        )


def _nearest_rank_idx(percentile: float, n: int) -> int:
    """Return the nearest-rank index for *percentile* in a sorted list of length *n*."""
    return min(int(math.ceil(percentile / 100 * n)) - 1, n - 1)


def compute_percentiles(latencies: list[float]) -> list[tuple[float, float]]:
    """Return list of (percentile, value) pairs.

    Non-finite samples (inf/NaN) are dropped before sorting so they cannot
    poison the nearest-rank result. High tail percentiles are only reported
    when the sample size can actually resolve them: p99.9 requires n >= 1000
    and p99.99 requires n >= 10000. For smaller samples these collapse to the
    max (and to each other / p99), so they are omitted rather than implying
    tail resolution the data does not support.
    """
    finite = [x for x in latencies if math.isfinite(x)]
    if not finite:
        return []
    sorted_lat = sorted(finite)
    n = len(sorted_lat)
    percentiles = [50, 75, 90, 95, 99]
    if n >= 1000:
        percentiles.append(99.9)
    if n >= 10000:
        percentiles.append(99.99)
    result = []
    for p in percentiles:
        result.append((p, sorted_lat[_nearest_rank_idx(p, n)]))
    return result


# ---------------------------------------------------------------------------
# Threshold support (SLO pass/fail)
# ---------------------------------------------------------------------------

#: The metrics a threshold can name, aggregate or per step.
_THRESHOLD_METRICS = "p50|p75|p90|p95|p99|avg_latency|max_latency|min_latency|error_rate|rps"

_THRESHOLD_PATTERN = re.compile(
    rf"^\s*({_THRESHOLD_METRICS})"
    r"\s*(<=?|>=?)\s*"
    r"([0-9]*\.?[0-9]+)\s*(ms|s|us|%)?\s*$"
)

#: ``step:<name> <metric> <op> <value>``. The step name is non-greedy and the
#: metric alternation anchors where it ends, so a name containing spaces --
#: which the default `METHOD /path` naming produces -- still parses.
_STEP_THRESHOLD_PATTERN = re.compile(
    rf"^\s*step:\s*(?P<step>.+?)\s+(?P<metric>{_THRESHOLD_METRICS})"
    r"\s*(?P<op><=?|>=?)\s*"
    r"(?P<value>[0-9]*\.?[0-9]+)\s*(?P<unit>ms|s|us|%)?\s*$"
)

_LATENCY_METRICS = {"p50", "p75", "p90", "p95", "p99", "avg_latency", "max_latency", "min_latency"}

_PERCENTILE_MAP = {"p50": 50, "p75": 75, "p90": 90, "p95": 95, "p99": 99}


def parse_threshold(expr: str) -> "Threshold":
    """Parse a threshold expression into a Threshold.

    Accepts an aggregate form, ``p95 < 300ms``, and a per-step form,
    ``step:checkout p95 < 800ms``. For a scenario the aggregate is a blend of
    every step, so adding fast steps improves it while the step that matters
    stays out of budget; the per-step form is the one that expresses the SLO.
    """
    step: "str | None" = None
    m = _STEP_THRESHOLD_PATTERN.match(expr)
    if m:
        step = m.group("step").strip()
        if not step:
            raise ValueError(f"Invalid threshold expression, empty step name: {expr!r}")
        metric = m.group("metric")
        operator = m.group("op")
        raw_value = m.group("value")
        unit = m.group("unit")
        return _finish_threshold(expr, metric, operator, raw_value, unit, step)

    m = _THRESHOLD_PATTERN.match(expr)
    if not m:
        raise ValueError(f"Invalid threshold expression: {expr!r}")
    metric, operator, raw_value, unit = m.groups()
    value = float(raw_value)

    # Convert time units to seconds for latency metrics
    if metric in _LATENCY_METRICS:
        if unit == "ms":
            value /= 1000.0
        elif unit == "us":
            value /= 1_000_000.0
        elif unit == "%":
            raise ValueError(f"Invalid unit '%' for latency metric {metric!r} in: {expr!r}")
        elif unit is None:
            # A bare latency number is interpreted as seconds, which silently
            # turns a misremembered 'p99<5' (meant as 5ms) into a green gate.
            # Keep the seconds semantics for backward compatibility, but warn.
            _logger.warning(
                "Threshold %r has no time unit; interpreting %s as %s seconds. "
                "Add an explicit unit (e.g. '%sms') to avoid silently gating in seconds.",
                expr.strip(),
                raw_value,
                raw_value,
                raw_value,
            )
        # else: unit == "s" -> already in seconds, nothing to convert
    elif metric == "error_rate":
        # '%' is optional; value is always a percentage number
        if unit in ("ms", "s", "us"):
            raise ValueError(f"Invalid unit {unit!r} for error_rate in: {expr!r}")
    elif metric == "rps":
        if unit in ("ms", "s", "us", "%"):
            raise ValueError(f"Invalid unit {unit!r} for rps in: {expr!r}")

    return Threshold(metric=metric, operator=operator, value=value, raw_expr=expr.strip())


def _finish_threshold(expr, metric, operator, raw_value, unit, step):
    """Convert units and build a Threshold, sharing the aggregate form's rules."""
    parsed = parse_threshold(f"{metric} {operator} {raw_value}{unit or ''}")
    return Threshold(
        metric=metric,
        operator=operator,
        value=parsed.value,
        raw_expr=expr.strip(),
        step=step,
    )


def evaluate_thresholds(
    thresholds: "list[Threshold]",
    stats: "WorkerStats",
    duration: float,
) -> "list[tuple[Threshold, float | None, bool]]":
    """Evaluate thresholds against benchmark results.

    Returns a list of ``(threshold, actual_value, passed)`` tuples, where
    *actual_value* is None for a metric this run could not produce.

    A metric that could not be measured **fails** its threshold. It used to be
    substituted with 0.0, which made ``p95 < 500ms`` pass on a run that never
    recorded a latency -- a gate reporting success on a run where the service
    was never exercised. A gate that is silent and a gate that is satisfied
    must not look the same. This matches
    :func:`pywrkr.ci.evaluate_from_results`, which reads the same metrics out
    of a results file.

    A genuine zero is still a zero: a run with requests and no failures really
    does have ``error_rate == 0.0`` and keeps passing ``error_rate < 1%``.
    """
    # Pre-compute percentiles from latencies
    pct_map: dict[float, float] = {}
    if stats.latencies:
        for p, v in compute_percentiles(stats.latencies):
            pct_map[p] = v

    results: list[tuple[Threshold, "float | None", bool]] = []
    for th in thresholds:
        if th.step is not None:
            actual = _get_step_metric_value(th, stats, duration)
        else:
            actual = _get_metric_value(th.metric, stats, duration, pct_map)
        passed = actual is not None and compare_threshold(actual, th.operator, th.value)
        results.append((th, actual, passed))
    return results


def _get_step_metric_value(
    threshold: "Threshold", stats: "WorkerStats", duration: float
) -> "float | None":
    """One step's own metric, or None when that step produced nothing.

    None rather than a zero for the same reason as the aggregate path: a typo in
    the step name, or a step that never ran because an earlier one aborted the
    iteration, must not read as a satisfied threshold.
    """
    step = threshold.step or ""
    samples = stats.step_latencies.get(step)
    errors = stats.step_errors.get(step, 0)

    if threshold.metric == "error_rate":
        attempts = (len(samples) if samples else 0) + errors
        return (errors / attempts * 100) if attempts else None
    if threshold.metric == "rps":
        count = (len(samples) if samples else 0) + errors
        return count / duration if duration > 0 and count else None
    if not samples:
        return None

    pct_map = dict(compute_percentiles(list(samples)))
    return _get_metric_value(
        threshold.metric,
        _StepStatsView(samples),
        duration,
        pct_map,
    )


class _StepStatsView:
    """Just enough of a WorkerStats for the shared metric reader.

    Reusing :func:`_get_metric_value` rather than reimplementing avg/min/max is
    what keeps a per-step p95 and an aggregate p95 meaning the same thing.
    """

    __slots__ = ("latencies", "total_requests", "errors")

    def __init__(self, samples) -> None:
        self.latencies = list(samples)
        self.total_requests = len(self.latencies)
        self.errors = 0


def _get_metric_value(
    metric: str,
    stats: "WorkerStats",
    duration: float,
    pct_map: dict[float, float],
) -> "float | None":
    """Extract the actual metric value from stats, or None if unmeasurable."""
    if metric in _PERCENTILE_MAP:
        # Absent rather than zero: no samples means no percentile exists.
        return pct_map.get(_PERCENTILE_MAP[metric])
    if metric in ("avg_latency", "max_latency", "min_latency"):
        if not stats.latencies:
            return None
        if metric == "avg_latency":
            return sum(stats.latencies) / len(stats.latencies)
        return max(stats.latencies) if metric == "max_latency" else min(stats.latencies)
    if metric == "error_rate":
        # A rate over no requests is undefined, not zero.
        if stats.total_requests == 0:
            return None
        return stats.errors / stats.total_requests * 100
    if metric == "rps":
        return stats.total_requests / duration if duration > 0 else None
    return None


def compare_threshold(actual: float, operator: str, threshold: float) -> bool:
    """Compare actual value against threshold using the given operator."""
    if operator == "<":
        return actual < threshold
    if operator == ">":
        return actual > threshold
    if operator == "<=":
        return actual <= threshold
    if operator == ">=":
        return actual >= threshold
    return False


def format_threshold_actual(metric: str, actual: "float | None") -> str:
    """Render a measured threshold value in its metric's own unit.

    None prints as ``not measured`` rather than as a zero: the number does not
    exist, and printing one would be the same lie the gate used to tell.
    """
    if actual is None:
        return "not measured"
    if metric in _LATENCY_METRICS:
        return format_duration(actual)
    if metric == "error_rate":
        return f"{actual:.2f}%"
    if metric == "rps":
        return f"{actual:.2f}"
    return f"{actual:.4f}"


def print_threshold_results(
    results: "list[tuple[Threshold, float | None, bool]]",
    file: TextIO = sys.stdout,
) -> None:
    """Print a summary table of threshold evaluation results."""
    if not results:
        return
    print(file=file)
    print("  SLO Threshold Results:", file=file)
    width = max(30, max(len(th.raw_expr) for th, _, _ in results))
    print(f"  {'Expression':<{width}} {'Actual':>12}   {'Status':>6}", file=file)
    print(f"  {'-' * width} {'-' * 12}   {'-' * 6}", file=file)
    for th, actual, passed in results:
        status = "PASS" if passed else "FAIL"
        actual_str = format_threshold_actual(th.metric, actual)
        print(f"  {th.raw_expr:<{width}} {actual_str:>12}   {status:>6}", file=file)

    all_passed = all(passed for _, _, passed in results)
    summary = "ALL PASSED" if all_passed else "SOME FAILED"
    print(f"\n  Thresholds: {summary}", file=file)


def print_percentiles(latencies: list[float], file: TextIO = sys.stdout) -> None:
    """Print latency percentiles table."""
    pairs = compute_percentiles(latencies)
    if not pairs:
        return
    print("  Latency Percentiles:", file=file)
    for p, val in pairs:
        print(f"    p{p:<6} {format_duration(val):>12}", file=file)


def _bucket_timeline(timeline: list[tuple[float, int]], bucket_size: int) -> dict[int, int]:
    """Bucket an rps_timeline into ``{bucket_index: summed_count}``.

    Timestamps are bucketed relative to the timeline's own earliest entry, not
    an external clock. ``merge_stats`` already rebases each worker's timeline
    onto a ``[0, duration)`` axis (see ``normalize_timeline``), so subtracting a
    monotonic ``start_time`` again would push every bucket index far negative —
    which empties the console timeline and produces negative HTML x-axis labels.
    """
    buckets: dict[int, int] = defaultdict(int)
    if not timeline:
        return buckets
    origin = min(ts for ts, _ in timeline)
    for ts, count in timeline:
        buckets[int((ts - origin) / bucket_size)] += count
    return buckets


def _bucket_span(index: int, bucket_size: float, duration: float) -> float:
    """Real time covered by one timeline bucket.

    The final bucket is usually partial, so dividing by the whole bucket_size
    would understate its throughput. But workers flush their last interval
    after the stop signal, so that bucket's timestamp routinely lands at or
    past duration and the remaining span comes out zero or negative. Falling
    back to the full bucket is the only sane reading of it -- the samples did
    happen, and one bucket's width is the closest thing to a real span.

    Clamping to a tiny epsilon instead, which the HTML report used to do, turns
    the same bucket into count/1e-9: a five-billion-req/s bar that rescales the
    y-axis and flattens the entire timeline into the baseline.
    """
    span = bucket_size
    if duration > 0:
        span = min(bucket_size, duration - index * bucket_size)
    return span if span > 0 else bucket_size


def print_rps_timeline(
    timeline: list[tuple[float, int]], start: float, duration: float, file: TextIO = sys.stdout
) -> None:
    """Print requests-per-second timeline.

    ``start`` is accepted for backward compatibility; bucketing is done relative
    to the timeline's own origin via :func:`_bucket_timeline`.
    """
    if not timeline:
        return
    bucket_size = max(1, int(duration / 20))
    # A non-empty timeline always yields at least one bucket (origin -> 0).
    buckets = _bucket_timeline(timeline, bucket_size)

    def _span(i: int) -> float:
        return _bucket_span(i, bucket_size, duration)

    max_rps = max(count / _span(i) for i, count in buckets.items())
    bar_max = 40
    print(f"  Requests/sec Timeline ({bucket_size}s buckets):", file=file)
    for i in range(max(buckets.keys()) + 1):
        rps = buckets.get(i, 0) / _span(i)
        bar_len = int(rps / max_rps * bar_max) if max_rps else 0
        bar = "#" * bar_len
        t_start = i * bucket_size
        print(f"    {t_start:>4}s | {bar:<{bar_max}} | {rps:>8.1f} req/s", file=file)


def build_step_stats(stats: WorkerStats, duration: float) -> dict:
    """Summarize each scenario step on its own.

    A scenario's aggregate p95 blends every step together: if login is 40ms and
    checkout is 2s, the headline number describes neither. This reuses the same
    percentile machinery as the top-level block so the two never disagree.
    """
    step_stats: dict[str, dict] = {}
    for step_name, lats in stats.step_latencies.items():
        if not lats:
            continue
        finite = [x for x in lats if math.isfinite(x)]
        if not finite:
            continue
        pct_map = dict(compute_percentiles(finite))
        block = {
            "count": len(finite),
            "errors": int(stats.step_errors.get(step_name, 0)),
            "requests_per_sec": round(len(finite) / duration, 2) if duration > 0 else 0.0,
            "min": round(min(finite), 6),
            "max": round(max(finite), 6),
            "mean": round(statistics.mean(finite), 6),
            "median": round(pct_map.get(50, statistics.median(finite)), 6),
        }
        for pct in (50, 95, 99):
            if pct in pct_map:
                block[f"p{pct}"] = round(pct_map[pct], 6)
        if len(finite) > 1:
            block["stdev"] = round(statistics.stdev(finite), 6)
        step_stats[step_name] = block
    return step_stats


def print_step_table(step_stats: dict, file: TextIO = sys.stdout) -> None:
    """Print the per-step table used by scenario runs."""
    if not step_stats:
        return
    name_width = max(len("Step"), max(len(name) for name in step_stats))
    header = (
        f"    {'Step'.ljust(name_width)}  {'Count':>8}  {'Errors':>7}  "
        f"{'Req/s':>9}  {'p50':>10}  {'p95':>10}  {'p99':>10}  {'Max':>10}"
    )
    print(header, file=file)
    print(
        f"    {'-' * name_width}  {'-' * 8}  {'-' * 7}  {'-' * 9}  " + "  ".join(["-" * 10] * 4),
        file=file,
    )
    for name, block in step_stats.items():
        print(
            f"    {name.ljust(name_width)}  {block['count']:>8,}  {block['errors']:>7,}  "
            f"{block['requests_per_sec']:>9,.1f}  "
            f"{format_duration(block.get('p50', block['median'])):>10}  "
            f"{format_duration(block.get('p95', block['max'])):>10}  "
            f"{format_duration(block.get('p99', block['max'])):>10}  "
            f"{format_duration(block['max']):>10}",
            file=file,
        )


def _config_snapshot(config: BenchmarkConfig, connections: int) -> dict:
    """Capture the load shape a run was asked for.

    Only the fields that make two runs comparable — comparing a 10-user run to a
    1000-user baseline is arithmetically fine and completely meaningless. The
    host is recorded but not the full URL, so query-string noise does not make
    every run look incomparable.
    """
    if config.users is not None:
        mode = "users"
    elif config.num_requests is not None:
        mode = "requests"
    else:
        mode = "duration"
    if config.scenario is not None:
        mode = f"scenario:{mode}"
    return {
        "mode": mode,
        "connections": connections,
        "users": config.users,
        "duration": config.duration,
        "num_requests": config.num_requests,
        "rate": config.rate,
        "url_host": urlparse(config.url).netloc or None,
        # Whether bodies were read. Two runs that differ here are not measuring
        # the same thing -- total_bytes counts only what was read, and the
        # latency of a released response excludes receiving it -- so `compare`
        # warns rather than reporting a spectacular transfer-rate change.
        "read_body": config.read_body,
    }


def build_results_dict(
    stats: WorkerStats,
    duration: float,
    connections: int,
    config: BenchmarkConfig | None = None,
    rate_limiter: RateLimiter | None = None,
) -> dict:
    """Build a structured results dict for JSON/HTML/programmatic use."""
    rps = stats.total_requests / duration if duration > 0 else 0
    transfer_rate = stats.total_bytes / duration if duration > 0 else 0
    result: dict = {
        # Lets `pywrkr compare` reject files it cannot read. Files written before
        # this key existed have the same shape and are read as version 1.
        "schema_version": SCHEMA_VERSION,
        "duration_sec": round(duration, 3),
        "connections": connections,
        "total_requests": stats.total_requests,
        "total_errors": stats.errors,
        "requests_per_sec": round(rps, 2),
        "transfer_per_sec_bytes": round(transfer_rate, 2),
        "total_bytes": stats.total_bytes,
        "content_length_errors": stats.content_length_errors,
        # Scenario correlation counters (always present so CI consumers can rely
        # on the key; 0 for non-scenario runs).
        "extract_failures": stats.extract_failures,
        "template_errors": stats.template_errors,
        "status_codes": dict(stats.status_codes),
        # Negotiated protocol per response. With --http2 this is what shows a
        # server that only offered HTTP/1.1, rather than the run silently
        # claiming to be an HTTP/2 test.
        "http_versions": dict(stats.http_versions),
        "error_types": dict(stats.error_types),
        # Throughput timeline as [seconds_from_start, requests_in_interval] pairs.
        # Always present (empty list when not collected) so JSON/CI consumers can
        # rely on the key. Timestamps are already rebased to a [0, duration) axis
        # by merge_stats(); see normalize_timeline.
        "rps_timeline": [[round(ts, 3), count] for ts, count in stats.rps_timeline],
    }
    if config is not None:
        # Snapshot of what was asked for, so `pywrkr compare` can tell whether
        # two runs are even comparable.
        result["config"] = _config_snapshot(config, connections)
    if config is not None and config.tags:
        result["tags"] = dict(config.tags)
    if config is not None and config.rate is not None:
        result["target_rps"] = config.rate
        if config.rate_ramp is not None:
            result["ramp_target_rps"] = config.rate_ramp
        if config.traffic_profile is not None:
            result["traffic_profile"] = config.traffic_profile.describe()
        if rate_limiter is not None:
            result["rate_limit_waits"] = rate_limiter.waits
    if stats.ws is not None:
        result["websocket"] = ws_results_section(stats.ws, duration)
    finite_latencies = [x for x in stats.latencies if math.isfinite(x)]
    if finite_latencies:
        pct_pairs = compute_percentiles(finite_latencies)
        pct_map = dict(pct_pairs)
        # Use the nearest-rank p50 as the median so latency.median and
        # percentiles.p50 agree (the ab-style table and print_percentiles
        # also use nearest-rank).
        median = pct_map.get(50, statistics.median(finite_latencies))
        result["latency"] = {
            "min": round(min(finite_latencies), 6),
            "max": round(max(finite_latencies), 6),
            "mean": round(statistics.mean(finite_latencies), 6),
            "median": round(median, 6),
            "stdev": (
                round(statistics.stdev(finite_latencies), 6) if len(finite_latencies) > 1 else 0
            ),
        }
        result["percentiles"] = {f"p{p}": round(v, 6) for p, v in pct_pairs}
    # Per-step latency stats for scenario mode
    if stats.step_latencies:
        # Kept under the existing "step_stats" key rather than renamed, so JSON
        # consumers written against earlier releases keep working; the block
        # gained errors and percentiles.
        result["step_stats"] = build_step_stats(stats, duration)
    # Latency breakdown
    if stats.breakdowns:
        agg = aggregate_breakdowns(stats.breakdowns)
        bd_json: dict = {}
        # Omitted entirely when the backend cannot observe connection reuse,
        # rather than reported as zero.
        for key in ("new_connections", "reused_connections"):
            if key in agg:
                bd_json[key] = agg[key]
        for phase in ("dns", "connect", "tls", "ttfb", "transfer", "total"):
            if phase in agg:
                bd_json[phase] = {k: round(v, 6) for k, v in agg[phase].items()}
        result["latency_breakdown"] = bd_json
    return result


def write_csv_output(path: str, stats: WorkerStats) -> None:
    """Write ab-style CSV with percentile served times.

    Non-finite samples are dropped here too: writing ``inf`` into a CSV of
    millisecond timings produces a column no spreadsheet or plotting tool
    reads back as a number.
    """
    sorted_lat = sorted(x for x in stats.latencies if math.isfinite(x))
    if not sorted_lat:
        return
    n = len(sorted_lat)
    with open(path, "w", newline="") as f:
        writer = csv.writer(f)
        writer.writerow(["Percentage", "Time (ms)"])
        for pct in range(1, 101):
            writer.writerow([pct, round(sorted_lat[_nearest_rank_idx(pct, n)] * 1000, 3)])


def write_json_output(path: str, results: dict) -> None:
    """Write benchmark results as JSON to a file.

    Uses ``allow_nan=False`` so a non-finite float (inf/NaN) fails loudly with
    a ``ValueError`` instead of silently writing the non-standard
    ``Infinity``/``NaN`` tokens that strict JSON parsers reject.
    """
    with open(path, "w") as f:
        json.dump(results, f, indent=2, allow_nan=False)


def generate_html_report(stats: WorkerStats, duration: float, connections: int) -> str:
    """Generate an ab-style HTML table report.

    Everything interpolated here is escaped. Plenty of it comes from the far
    end of the wire rather than from us: error_types keys carry server reason
    phrases, and scenario data reaches the same table through step names,
    tags and the host. A target that returns a reason phrase containing markup
    would otherwise have it rendered when someone opens the report.

    The Gatling report was hardened in #109; this one was left as it was, so
    the two disagreed about whether report data is trusted.
    """
    results = build_results_dict(stats, duration, connections)

    def cell(value: object) -> str:
        # Nested dicts used to render as a Python repr, which is unreadable
        # and, unescaped, just as injectable.
        text = json.dumps(value, sort_keys=True) if isinstance(value, (dict, list)) else str(value)
        return _html_escape(text)

    rows = []
    for key, val in results.items():
        if isinstance(val, dict):
            for k2, v2 in val.items():
                rows.append(f"<tr><td>{cell(key)}.{cell(k2)}</td><td>{cell(v2)}</td></tr>")
        else:
            rows.append(f"<tr><td>{cell(key)}</td><td>{cell(val)}</td></tr>")
    return (
        "<html><head><title>pywrkr benchmark results</title></head><body>\n"
        "<h1>pywrkr Benchmark Results</h1>\n"
        "<table border='1' cellpadding='4'>\n"
        "<tr><th>Metric</th><th>Value</th></tr>\n" + "\n".join(rows) + "\n</table></body></html>"
    )


def generate_gatling_html_report(
    stats: WorkerStats,
    duration: float,
    connections: int,
    config: BenchmarkConfig | None = None,
    rate_limiter: RateLimiter | None = None,
    start_time: float = 0.0,
) -> str:
    """Generate a Gatling-style interactive HTML report with charts.

    Produces a self-contained HTML file using Chart.js (loaded from CDN)
    with:
    - Summary indicators (requests, errors, RPS, mean/p95/p99 latency)
    - Response time distribution histogram
    - Response time percentiles chart
    - Requests per second timeline
    - Status code breakdown (pie chart)
    - Latency breakdown by phase (if available)
    """
    results = build_results_dict(stats, duration, connections, config, rate_limiter)
    latency = results.get("latency", {})
    percentiles = results.get("percentiles", {})
    status_codes = results.get("status_codes", {})
    error_types = results.get("error_types", {})

    # -- Histogram buckets --
    hist_labels: list[str] = []
    hist_counts: list[int] = []
    hist_colors: list[str] = []
    # Filtered for the same reason build_results_dict, compute_percentiles and
    # print_latency_histogram filter: a single inf makes step inf, (inf - lo) /
    # inf is NaN, and int(NaN) raises -- so --html-report aborted after the run
    # had already finished and its results were otherwise fine. A NaN is worse
    # than a crash: hi > lo is False, so every request collapses into one bar
    # and the chart quietly lies.
    finite_lat = [x for x in stats.latencies if math.isfinite(x)]
    if finite_lat:
        sorted_lat = sorted(finite_lat)
        lo, hi = sorted_lat[0], sorted_lat[-1]
        if hi > lo:
            # Create ~20 buckets
            n_buckets = min(30, max(10, len(sorted_lat) // 50))
            step = (hi - lo) / n_buckets
            buckets_hist: list[int] = [0] * n_buckets
            for lat in sorted_lat:
                idx = min(int((lat - lo) / step), n_buckets - 1)
                buckets_hist[idx] += 1
            p50 = percentiles.get("p50", 0)
            p95 = percentiles.get("p95", 0)
            for i in range(n_buckets):
                edge_ms = (lo + i * step) * 1000
                hist_labels.append(f"{edge_ms:.0f}")
                hist_counts.append(buckets_hist[i])
                # Color by latency: green < p50, yellow < p95, red >= p95
                edge_s = lo + i * step
                if edge_s < p50:
                    hist_colors.append(COLOR_GREEN)
                elif edge_s < p95:
                    hist_colors.append(COLOR_YELLOW)
                else:
                    hist_colors.append(COLOR_RED)
        else:
            # Degenerate distribution: every observed latency is the same
            # value. Falling through to the bucket loop with hi == lo would
            # produce a step of 1 second and stretch the histogram across
            # an arbitrary range with all bars red. Render a single green
            # bar at the actual value instead.
            hist_labels.append(f"{lo * 1000:.0f}")
            hist_counts.append(len(sorted_lat))
            hist_colors.append(COLOR_GREEN)

    # -- Percentile curve --
    pct_labels = ["p50", "p75", "p90", "p95", "p99"]
    pct_values = [round(percentiles.get(p, 0) * 1000, 2) for p in pct_labels]

    # -- RPS timeline --
    rps_labels: list[str] = []
    rps_values: list[float] = []
    if stats.rps_timeline:
        bucket_size = max(1, int(duration / 40))
        time_buckets = _bucket_timeline(stats.rps_timeline, bucket_size)
        for b in sorted(time_buckets.keys()):
            # Same span rule as the console timeline, from the same helper,
            # so the two cannot disagree about the final bucket again.
            span = _bucket_span(b, bucket_size, duration)
            rps_labels.append(f"{b * bucket_size}s")
            rps_values.append(round(time_buckets[b] / span, 1))

    # -- Status code pie --
    sc_labels = [str(c) for c in sorted(status_codes.keys())]
    sc_values = [status_codes[int(c)] for c in sc_labels]
    sc_colors = []
    for c in sc_labels:
        code = int(c)
        if 200 <= code < 300:
            sc_colors.append(STATUS_COLOR_2XX)
        elif 300 <= code < 400:
            sc_colors.append(STATUS_COLOR_3XX)
        elif 400 <= code < 500:
            sc_colors.append(STATUS_COLOR_4XX)
        else:
            sc_colors.append(STATUS_COLOR_5XX)

    # -- Latency breakdown --
    bd = results.get("latency_breakdown", {})
    bd_phases = ["dns", "connect", "tls", "ttfb", "transfer"]
    bd_labels = ["DNS", "Connect", "TLS", "TTFB", "Transfer"]
    bd_values = [round(bd.get(p, {}).get("avg", 0) * 1000, 2) for p in bd_phases]
    has_breakdown = any(v > 0 for v in bd_values)

    # -- Error rate --
    error_rate = (stats.errors / stats.total_requests * 100) if stats.total_requests else 0

    # -- Mode description --
    mode = "Duration mode"
    if config:
        if config.users:
            mode = f"{config.users} virtual users"
        elif config.num_requests:
            mode = f"{config.num_requests:,} requests"
        elif config.rate:
            mode = f"Rate: {config.rate} req/s"

    url = config.url if config else "N/A"
    method = config.method if config else "GET"
    timestamp = __import__("datetime").datetime.now().strftime("%Y-%m-%d %H:%M:%S")

    import json as _json

    # Pre-compute conditional CSS classes and display values
    errors_class = "red" if stats.errors else "green"
    p95_class = "yellow" if percentiles.get("p95", 0) > 1 else ""
    p99_class = "red" if percentiles.get("p99", 0) > 2 else ""
    bd_card_display = "display:block" if has_breakdown else "display:none"

    # Pre-render error table HTML
    error_table_html = ""
    if error_types:
        rows = "".join(
            f"<tr><td>{_html_escape(e)}</td><td>{c:,}</td></tr>"
            for e, c in sorted(error_types.items(), key=lambda x: -x[1])
        )
        error_table_html = (
            '<div class="chart-card full" style="margin-bottom:28px">\n'
            "  <h3>Error Details</h3>\n"
            '  <table class="errors-table">\n'
            "    <tr><th>Error</th><th>Count</th></tr>\n"
            f"    {rows}\n"
            "  </table>\n"
            "</div>"
        )

    # Per-step table, for scenario runs. Prepended to the error table so the
    # report leads with which step is slow or failing.
    step_stats = results.get("step_stats") or {}
    if step_stats:
        step_rows = "".join(
            "<tr>"
            f"<td>{_html_escape(name)}</td>"
            f"<td>{block['count']:,}</td>"
            f"<td>{block['errors']:,}</td>"
            f"<td>{block['requests_per_sec']:,.1f}</td>"
            f"<td>{format_duration(block.get('p50', block['median']))}</td>"
            f"<td>{format_duration(block.get('p95', block['max']))}</td>"
            f"<td>{format_duration(block.get('p99', block['max']))}</td>"
            f"<td>{format_duration(block['max'])}</td>"
            "</tr>"
            for name, block in step_stats.items()
        )
        error_table_html = (
            '<div class="chart-card full" style="margin-bottom:28px">\n'
            "  <h3>Per-Step Breakdown</h3>\n"
            '  <table class="errors-table">\n'
            "    <tr><th>Step</th><th>Count</th><th>Errors</th><th>Req/s</th>"
            "<th>p50</th><th>p95</th><th>p99</th><th>Max</th></tr>\n"
            f"    {step_rows}\n"
            "  </table>\n"
            "</div>"
        ) + error_table_html

    # WebSocket panel, prepended so the report leads with the metrics that
    # describe the run rather than with HTTP-shaped ones that barely apply.
    websocket = results.get("websocket")
    if websocket:
        error_table_html = _websocket_html_table(websocket) + error_table_html

    # Build template context
    context = {
        "title": _html_escape(url),
        "method": _html_escape(method),
        "url_display": _html_escape(url),
        "mode": mode,
        "connections": connections,
        "timestamp": timestamp,
        "total_requests": f"{stats.total_requests:,}",
        "duration_display": f"{duration:.1f}",
        "rps_display": f"{results.get('requests_per_sec', 0):,.1f}",
        "errors_display": f"{stats.errors:,} ({error_rate:.1f}%)",
        "errors_class": errors_class,
        "mean_latency": format_duration(latency.get("mean", 0)),
        "p95_latency": format_duration(percentiles.get("p95", 0)),
        "p95_class": p95_class,
        "p99_latency": format_duration(percentiles.get("p99", 0)),
        "p99_class": p99_class,
        "transfer_rate": format_bytes(results.get("transfer_per_sec_bytes", 0)),
        "hist_labels_json": _json.dumps(hist_labels),
        "hist_counts_json": _json.dumps(hist_counts),
        "hist_colors_json": _json.dumps(hist_colors),
        "pct_labels_json": _json.dumps(pct_labels),
        "pct_values_json": _json.dumps(pct_values),
        "rps_labels_json": _json.dumps(rps_labels),
        "rps_values_json": _json.dumps(rps_values),
        "sc_labels_json": _json.dumps(sc_labels),
        "sc_values_json": _json.dumps(sc_values),
        "sc_colors_json": _json.dumps(sc_colors),
        "bd_labels_json": _json.dumps(bd_labels),
        "bd_values_json": _json.dumps(bd_values),
        "has_breakdown_json": _json.dumps(has_breakdown),
        "bd_card_display": bd_card_display,
        "bd_bar_colors_json": _json.dumps(
            [COLOR_BLUE, COLOR_GREEN, COLOR_PURPLE, COLOR_ORANGE, COLOR_CYAN]
        ),
        "error_table_html": error_table_html,
    }

    template = _load_template("gatling_report.html")
    return template.safe_substitute(context)


def _websocket_html_table(section: dict) -> str:
    """Render the WebSocket metrics as a card for the HTML report."""
    connections = section.get("connections", {})
    messages = section.get("messages", {})
    close = section.get("close", {})
    rows = [
        ("Connections opened", f"{connections.get('opened', 0):,}"),
        ("Connections failed", f"{connections.get('failed', 0):,}"),
        ("Connections dropped", f"{connections.get('dropped', 0):,}"),
        ("Reconnects", f"{connections.get('reconnects', 0):,}"),
        ("Peak concurrent", f"{connections.get('peak_concurrent', 0):,}"),
        (
            "Messages sent",
            f"{messages.get('sent', 0):,} ({messages.get('sent_per_sec', 0):,.2f}/s)",
        ),
        (
            "Messages received",
            f"{messages.get('received', 0):,} ({messages.get('received_per_sec', 0):,.2f}/s)",
        ),
        ("Bytes sent", format_bytes(messages.get("bytes_sent", 0))),
        ("Bytes received", format_bytes(messages.get("bytes_received", 0))),
        ("Reply timeouts", f"{messages.get('reply_timeouts', 0):,}"),
        ("Close frames sent", f"{close.get('frames_sent', 0):,}"),
        ("Close unacknowledged", f"{close.get('unacknowledged', 0):,}"),
    ]
    for label, key in (("Handshake", "handshake"), ("Round-trip", "rtt")):
        block = section.get(key) or {}
        if not block:
            continue
        pct = block.get("percentiles", {})
        rows.append(
            (
                f"{label} latency",
                f"mean {format_duration(block.get('mean', 0))} · "
                f"p95 {format_duration(pct.get('p95', 0))} · "
                f"p99 {format_duration(pct.get('p99', 0))}",
            )
        )
    measured = _WS_LATENCY_DESCRIPTIONS.get(
        section.get("latency_metric", ""), section.get("latency_metric", "")
    )
    body = "".join(
        f"<tr><td>{_html_escape(k)}</td><td>{_html_escape(v)}</td></tr>" for k, v in rows
    )
    return (
        '<div class="chart-card full" style="margin-bottom:28px">\n'
        "  <h3>WebSocket</h3>\n"
        f"  <p>Latency charts above measure the {_html_escape(measured)}.</p>\n"
        '  <table class="errors-table">\n'
        "    <tr><th>Metric</th><th>Value</th></tr>\n"
        f"    {body}\n"
        "  </table>\n"
        "</div>"
    )


def _html_escape(s: str) -> str:
    """Escape HTML special characters."""
    from html import escape

    return escape(s)


def write_html_report(path: str, html: str) -> None:
    """Write HTML report to a file."""
    with open(path, "w", encoding="utf-8") as f:
        f.write(html)


# ---------------------------------------------------------------------------
# Shared export metric definitions
# ---------------------------------------------------------------------------


class _MetricSpec(NamedTuple):
    """Specification for an exportable benchmark metric."""

    name_suffix: str  # used for Prometheus: "pywrkr_" + name_suffix
    otel_name: str  # explicit OTel metric name
    results_key: str
    nested_key: str | None
    multiplier: float
    metric_type: str  # "counter" or "gauge"
    description: str


_EXPORT_METRICS: list[_MetricSpec] = [
    _MetricSpec(
        "requests_total",
        "pywrkr.requests.total",
        "total_requests",
        None,
        1,
        "counter",
        "Total requests",
    ),
    _MetricSpec(
        "errors_total", "pywrkr.errors.total", "total_errors", None, 1, "counter", "Total errors"
    ),
    _MetricSpec(
        "requests_per_sec",
        "pywrkr.requests_per_sec",
        "requests_per_sec",
        None,
        1,
        "gauge",
        "Requests per second",
    ),
    _MetricSpec(
        "transfer_bytes_per_sec",
        "pywrkr.transfer_bytes_per_sec",
        "transfer_per_sec_bytes",
        None,
        1,
        "gauge",
        "Transfer bytes per second",
    ),
    _MetricSpec(
        "duration_sec",
        "pywrkr.duration_sec",
        "duration_sec",
        None,
        1,
        "gauge",
        "Benchmark duration in seconds",
    ),
    _MetricSpec(
        "latency_p50_ms",
        "pywrkr.latency.p50",
        "percentiles",
        "p50",
        1000,
        "gauge",
        "p50 latency in ms",
    ),
    _MetricSpec(
        "latency_p95_ms",
        "pywrkr.latency.p95",
        "percentiles",
        "p95",
        1000,
        "gauge",
        "p95 latency in ms",
    ),
    _MetricSpec(
        "latency_p99_ms",
        "pywrkr.latency.p99",
        "percentiles",
        "p99",
        1000,
        "gauge",
        "p99 latency in ms",
    ),
    _MetricSpec(
        "latency_mean_ms",
        "pywrkr.latency.mean",
        "latency",
        "mean",
        1000,
        "gauge",
        "Mean latency in ms",
    ),
    _MetricSpec(
        "latency_max_ms", "pywrkr.latency.max", "latency", "max", 1000, "gauge", "Max latency in ms"
    ),
]


# Valid Prometheus label name per the text exposition format spec.
_PROM_LABEL_NAME_PATTERN = re.compile(r"^[a-zA-Z_][a-zA-Z0-9_]*$")


def _escape_prom_label_value(v: str) -> str:
    """Escape a label value per the Prometheus text exposition format.

    Backslash -> double-backslash, double-quote -> escaped quote, newline -> ``\\n``.
    Order matters: backslashes must be escaped first.
    """
    return str(v).replace("\\", "\\\\").replace('"', '\\"').replace("\n", "\\n")


def _resolve_metric_value(
    results: dict, results_key: str, nested_key: str | None, multiplier: float
) -> float | None:
    """Resolve a metric value from the results dict.

    Returns ``None`` when the underlying data is absent (the parent key is
    missing, or a nested key is missing) so callers can distinguish
    "no data collected" from a real zero and skip emitting the metric.
    """
    if nested_key is not None:
        parent = results.get(results_key)
        if not isinstance(parent, dict) or nested_key not in parent:
            return None
        val = parent[nested_key]
    else:
        if results_key not in results:
            return None
        val = results[results_key]
    return val * multiplier


def export_to_otel(results: dict, endpoint: str, tags: dict[str, str]) -> bool:
    """Export benchmark metrics to an OpenTelemetry collector via OTLP/HTTP.

    Returns True on success, False on any error (including missing packages).
    """
    if not OTEL_AVAILABLE:
        _logger.error(
            "OTel export failed: opentelemetry packages not installed. "
            "Install with: pip install pywrkr[otel]"
        )
        return False

    try:
        resource_attrs = {"service.name": "pywrkr"}
        resource_attrs.update(tags)
        resource = Resource.create(resource_attrs)
        exporter = OTLPMetricExporter(endpoint=endpoint)
        reader = PeriodicExportingMetricReader(exporter, export_interval_millis=1000)
        provider = MeterProvider(resource=resource, metric_readers=[reader])
        meter = provider.get_meter("pywrkr")
        attributes = dict(tags)

        for spec in _EXPORT_METRICS:
            value = _resolve_metric_value(
                results, spec.results_key, spec.nested_key, spec.multiplier
            )
            if value is None:
                continue
            if spec.metric_type == "counter":
                counter = meter.create_counter(spec.otel_name, description=spec.description)
                counter.add(value, attributes=attributes)
            else:
                gauge = meter.create_up_down_counter(spec.otel_name, description=spec.description)
                gauge.add(value, attributes=attributes)

        provider.force_flush()
        provider.shutdown()
        return True
    except Exception as e:
        _logger.error("OTel export failed (endpoint=%s): %s", endpoint, e)
        return False


def export_to_prometheus(results: dict, endpoint: str, tags: dict[str, str]) -> bool:
    """Export benchmark metrics to a Prometheus Pushgateway-compatible endpoint.

    Returns True on success, False on any error.
    """
    import urllib.error
    import urllib.request

    try:
        lines: list[str] = []
        labels_parts = [
            f'{k}="{_escape_prom_label_value(v)}"'
            for k, v in sorted(tags.items())
            if _PROM_LABEL_NAME_PATTERN.match(k)
        ]
        labels_str = "{" + ",".join(labels_parts) + "}" if labels_parts else ""

        for spec in _EXPORT_METRICS:
            value = _resolve_metric_value(
                results, spec.results_key, spec.nested_key, spec.multiplier
            )
            if value is None:
                continue
            prom_name = "pywrkr_" + spec.name_suffix
            lines.append(f"# HELP {prom_name} {spec.description}")
            lines.append(f"# TYPE {prom_name} {spec.metric_type}")
            lines.append(f"{prom_name}{labels_str} {value}")

        body = "\n".join(lines) + "\n"
        url = endpoint.rstrip("/") + "/metrics/job/pywrkr"
        req = urllib.request.Request(
            url,
            data=body.encode("utf-8"),
            method="POST",
            headers={"Content-Type": "text/plain; version=0.0.4"},
        )
        urllib.request.urlopen(req, timeout=10)
        return True
    except Exception as e:
        _logger.error("Prometheus export failed (endpoint=%s): %s", endpoint, e)
        return False


def run_baseline_gate(
    stats: WorkerStats,
    duration: float,
    connections: int,
    config: BenchmarkConfig,
    rate_limiter: "RateLimiter | None" = None,
    file: TextIO | None = None,
) -> int:
    """Write ``--save-baseline`` and apply ``--baseline`` in one pass.

    Folding the comparison into the run turns a three-step CI recipe (run,
    dump JSON, diff it) into one command.

    Sub-runs are skipped: a distributed worker and an autofind step each see
    only part of the picture, and gating (or worse, overwriting the baseline
    file) from several of them at once would be meaningless. The master applies
    the gate to the merged result instead.

    Returns:
        An exit code: 0 when there is nothing to do or nothing regressed,
        ``EXIT_REGRESSION`` when a ``--fail-on`` rule fired, ``EXIT_USAGE``
        when the baseline could not be read or the configs differ under
        ``--strict-config``.
    """
    if not config.save_baseline and not config.baseline:
        return 0
    if getattr(config, "_quiet", False):
        return 0

    out = file if file is not None else sys.stdout
    results = build_results_dict(stats, duration, connections, config, rate_limiter)

    if config.save_baseline:
        try:
            write_json_output(config.save_baseline, results)
        except OSError as exc:
            print(f"\n  ERROR: could not write baseline: {exc}", file=sys.stderr)
            return EXIT_USAGE
        print(f"\n  Baseline written to: {config.save_baseline}", file=out)

    if not config.baseline:
        return 0

    try:
        baseline, sources = load_baseline(config.baseline)
    except ResultsError as exc:
        print(f"\n  ERROR: {exc}", file=sys.stderr)
        return EXIT_USAGE

    report = compare_results(baseline, results, config.fail_on, sources)
    render_report(report, config.compare_format, file=out)

    if report.config_warnings and config.strict_config:
        print(
            "\n  ERROR: --strict-config is set and the run configurations differ",
            file=sys.stderr,
        )
        return EXIT_USAGE
    return report.exit_code


def run_observability_exports(
    stats: WorkerStats,
    duration: float,
    connections: int,
    config: BenchmarkConfig,
    rate_limiter: "RateLimiter | None" = None,
) -> bool:
    """Run configured OTel/Prometheus exports. Returns True if all succeeded."""
    if not (config.otel_endpoint or config.prom_remote_write):
        return True
    results = build_results_dict(stats, duration, connections, config, rate_limiter)
    ok = True
    if config.otel_endpoint:
        ok = export_to_otel(results, config.otel_endpoint, config.tags) and ok
    if config.prom_remote_write:
        ok = export_to_prometheus(results, config.prom_remote_write, config.tags) and ok
    return ok


def _latency_summary(samples: "Sequence[float]") -> dict:
    """Min/mean/max plus percentiles for one WebSocket latency family."""
    finite = [x for x in samples if math.isfinite(x)]
    if not finite:
        return {}
    pct_pairs = compute_percentiles(finite)
    return {
        "count": len(finite),
        "min": round(min(finite), 6),
        "max": round(max(finite), 6),
        "mean": round(statistics.mean(finite), 6),
        "percentiles": {f"p{p}": round(v, 6) for p, v in pct_pairs},
    }


def ws_results_section(ws: "WsStats", duration: float) -> dict:
    """The ``websocket`` block of the results file.

    Documented schema (all keys always present so a CI consumer can rely on
    them; ``handshake``/``rtt`` are ``{}`` when nothing was measured)::

        websocket:
          latency_metric: "rtt" | "handshake"   # which metric percentiles/ describe
          primary_metric: "messages" | "connections"  # what total_requests counts
          connections: {opened, failed, dropped, reconnects, peak_concurrent}
          messages: {sent, received, sent_per_sec, received_per_sec,
                     bytes_sent, bytes_received, reply_timeouts,
                     unexpected_replies}
          handshake: {count, min, max, mean, percentiles: {...}}
          rtt:       {count, min, max, mean, percentiles: {...}}
          close: {frames_sent, unacknowledged, codes: {"1000": n, ...}}
    """
    per_sec = (lambda n: round(n / duration, 2)) if duration > 0 else (lambda n: 0.0)
    return {
        "latency_metric": ws.latency_metric,
        "primary_metric": ws.primary_metric,
        "connections": {
            "opened": ws.connections_opened,
            "failed": ws.connections_failed,
            "dropped": ws.connections_dropped,
            "reconnects": ws.reconnects,
            "peak_concurrent": ws.peak_concurrent,
        },
        "messages": {
            "sent": ws.messages_sent,
            "received": ws.messages_received,
            "sent_per_sec": per_sec(ws.messages_sent),
            "received_per_sec": per_sec(ws.messages_received),
            "bytes_sent": ws.bytes_sent,
            "bytes_received": ws.bytes_received,
            "reply_timeouts": ws.reply_timeouts,
            "unexpected_replies": ws.unexpected_replies,
        },
        "handshake": _latency_summary(ws.handshake_latencies),
        "rtt": _latency_summary(ws.rtt_latencies),
        "close": {
            "frames_sent": ws.close_frames_sent,
            "unacknowledged": ws.close_unacked,
            "codes": dict(ws.close_codes),
        },
    }


#: What ``WorkerStats.latencies`` holds in each WebSocket shape, spelled out
#: rather than left for the reader to infer from the flags.
_WS_LATENCY_DESCRIPTIONS = {
    "rtt": "message round-trip time",
    "handshake": "handshake time",
    "step": "time from connect to the expected message, per ws: step",
}


def print_websocket_stats(ws: "WsStats", duration: float, file: TextIO | None = None) -> None:
    """Print the WebSocket-specific section of the results.

    Handshake and round-trip latency are shown separately even though one of
    them is also the run's headline latency: a service that connects instantly
    and answers slowly and one that does the reverse are different problems,
    and a single latency line cannot tell them apart. Which of the two the
    thresholds were applied to is stated rather than implied.
    """
    out = file if file is not None else sys.stdout
    per_sec = (lambda n: n / duration) if duration > 0 else (lambda n: 0.0)

    print(f"\n{'=' * 70}", file=out)
    print("  WEBSOCKET STATISTICS", file=out)
    print(f"{'=' * 70}", file=out)
    print(f"  Connections Opened:  {ws.connections_opened:,}", file=out)
    print(f"  Connections Failed:  {ws.connections_failed:,}", file=out)
    print(f"  Connections Dropped: {ws.connections_dropped:,}", file=out)
    if ws.reconnects:
        print(f"  Reconnects:          {ws.reconnects:,}", file=out)
    if ws.peak_concurrent:
        # Only the standalone mode holds a fleet of sockets whose concurrency
        # is a meaningful number; a scenario opens one per step and closes it.
        print(f"  Peak Concurrent:     {ws.peak_concurrent:,}", file=out)
    print(
        f"  Messages Sent:       {ws.messages_sent:,} ({per_sec(ws.messages_sent):,.2f}/s)",
        file=out,
    )
    print(
        f"  Messages Received:   {ws.messages_received:,} ({per_sec(ws.messages_received):,.2f}/s)",
        file=out,
    )
    print(f"  Bytes Sent:          {format_bytes(ws.bytes_sent)}", file=out)
    print(f"  Bytes Received:      {format_bytes(ws.bytes_received)}", file=out)
    if ws.reply_timeouts:
        print(f"  Reply Timeouts:      {ws.reply_timeouts:,}", file=out)
    print(f"  Close Frames Sent:   {ws.close_frames_sent:,}", file=out)
    if ws.close_unacked:
        print(f"  Close Unacked:       {ws.close_unacked:,}", file=out)
    if ws.close_codes:
        codes = ", ".join(f"{code}: {count:,}" for code, count in sorted(ws.close_codes.items()))
        print(f"  Close Codes:         {codes}", file=out)

    for label, samples in (("Handshake", ws.handshake_latencies), ("Round-trip", ws.rtt_latencies)):
        finite = [x for x in samples if math.isfinite(x)]
        if not finite:
            continue
        pct = dict(compute_percentiles(finite))
        print(
            f"\n  {label} latency: "
            f"min {format_duration(min(finite))} · "
            f"mean {format_duration(statistics.mean(finite))} · "
            f"p50 {format_duration(pct.get(50, 0.0))} · "
            f"p95 {format_duration(pct.get(95, 0.0))} · "
            f"p99 {format_duration(pct.get(99, 0.0))} · "
            f"max {format_duration(max(finite))}",
            file=out,
        )
    measured = _WS_LATENCY_DESCRIPTIONS.get(ws.latency_metric, ws.latency_metric)
    print(f"\n  Latency statistics above measure the {measured}.", file=out)


def _print_console_results(
    stats: WorkerStats,
    duration: float,
    connections: int,
    start_time: float,
    config: BenchmarkConfig,
    rate_limiter: RateLimiter | None = None,
    file: TextIO | None = None,
) -> None:
    """Render all console output for a completed benchmark run.

    Pure console I/O — no files are written and no network calls are made.
    Callers that need to suppress or redirect output pass ``file``.
    """
    out = file if file is not None else sys.stdout

    rps = stats.total_requests / duration if duration > 0 else 0
    transfer_rate = stats.total_bytes / duration if duration > 0 else 0

    print("=" * 70, file=out)
    print("  BENCHMARK RESULTS", file=out)
    print("=" * 70, file=out)

    if config.websocket is not None:
        mode = f"websocket, {config.duration}s duration"
    elif config.scenario:
        mode = f"scenario '{config.scenario.name}'"
        if config.users:
            mode += f", {config.users} virtual users, {config.duration}s"
        elif config.duration:
            mode += f", {config.duration}s duration"
    elif config.users:
        mode = f"{config.users} virtual users, {config.duration}s"
    elif config.num_requests:
        mode = f"{config.num_requests} requests"
    else:
        mode = f"{config.duration}s duration"
    print(f"\n  Mode:              {mode}", file=out)
    print(f"  Duration:          {format_duration(duration)}", file=out)
    if config.users:
        print(f"  Virtual Users:     {config.users}", file=out)
        print(f"  Ramp-up:           {format_duration(config.ramp_up)}", file=out)
        print(
            f"  Think Time:        {format_duration(config.think_time)} "
            f"(+/-{config.think_time_jitter:.0%})",
            file=out,
        )
        if config.users > 0:
            print(f"  Avg Reqs/User:     {stats.total_requests / config.users:,.1f}", file=out)
    else:
        print(f"  Connections:       {connections}", file=out)
    if config.websocket is None:
        # A WebSocket is persistent by definition; printing "Keep-Alive: yes"
        # would imply a choice that does not exist in this mode.
        print(f"  Keep-Alive:        {'yes' if config.keepalive else 'no'}", file=out)
    if config.users:
        # Only meaningful where there are virtual users to isolate; plain
        # connection mode has no per-user identity.
        print(f"  Sessions:          {describe_session_mode(config)}", file=out)
    if config.websocket is not None and stats.ws is not None:
        label = "Messages Sent" if stats.ws.primary_metric == "messages" else "Connections Made"
        print(f"  {label + ':':<18} {stats.total_requests:,}", file=out)
    else:
        print(f"  Total Requests:    {stats.total_requests:,}", file=out)
    print(f"  Total Errors:      {stats.errors:,}", file=out)
    if stats.content_length_errors:
        print(f"  Content-Len Errs:  {stats.content_length_errors:,}", file=out)
    if stats.extract_failures:
        print(f"  Extract Failures:  {stats.extract_failures:,}", file=out)
    if stats.template_errors:
        print(f"  Template Errors:   {stats.template_errors:,}", file=out)
    print(f"  Requests/sec:      {rps:,.2f}", file=out)
    if config.rate is not None:
        print(f"  Target RPS:        {config.rate:,.2f}", file=out)
        if config.rate_ramp is not None:
            print(f"  Ramp Target RPS:   {config.rate_ramp:,.2f}", file=out)
        if config.traffic_profile is not None:
            print(f"  Traffic Profile:   {config.traffic_profile.describe()}", file=out)
        if rate_limiter is not None:
            print(f"  Rate Limit Waits:  {rate_limiter.waits:,}", file=out)
    print(f"  Transfer/sec:      {format_bytes(transfer_rate)}/s", file=out)
    print(f"  Total Transfer:    {format_bytes(stats.total_bytes)}", file=out)

    if stats.ws is not None:
        print_websocket_stats(stats.ws, duration, file=out)

    # Latency stats (computed on finite samples only to avoid NaN/inf poisoning)
    finite_latencies = [x for x in stats.latencies if math.isfinite(x)]
    if finite_latencies:
        pct_map = dict(compute_percentiles(finite_latencies))
        # Nearest-rank p50, consistent with the ab-style table / percentiles.
        median = pct_map.get(50, statistics.median(finite_latencies))
        print(f"\n{'=' * 70}", file=out)
        print("  LATENCY STATISTICS", file=out)
        print(f"{'=' * 70}", file=out)
        print(f"    Min:       {format_duration(min(finite_latencies)):>12}", file=out)
        print(f"    Max:       {format_duration(max(finite_latencies)):>12}", file=out)
        print(f"    Mean:      {format_duration(statistics.mean(finite_latencies)):>12}", file=out)
        print(f"    Median:    {format_duration(median):>12}", file=out)
        if len(finite_latencies) > 1:
            print(
                f"    Stdev:     {format_duration(statistics.stdev(finite_latencies)):>12}",
                file=out,
            )

        print(file=out)
        print_percentiles(finite_latencies, file=out)

        # ab-style "percentage of requests served within" table
        sorted_lat = sorted(finite_latencies)
        n = len(sorted_lat)
        print(file=out)
        print("  Percentage of requests served within a certain time:", file=out)
        for pct in [50, 66, 75, 80, 90, 95, 98, 99, 100]:
            print(
                f"    {pct:>3}%    {format_duration(sorted_lat[_nearest_rank_idx(pct, n)]):>12}",
                file=out,
            )

        print(file=out)
        print_latency_histogram(finite_latencies, file=out)

    # Latency breakdown
    if stats.breakdowns:
        agg = aggregate_breakdowns(stats.breakdowns)
        print(f"\n{'=' * 70}", file=out)
        print("  LATENCY BREAKDOWN (averages)", file=out)
        print(f"{'=' * 70}", file=out)
        for phase, label in [
            ("dns", "DNS Lookup"),
            ("connect", "TCP Connect"),
            ("tls", "TLS Handshake"),
            ("ttfb", "TTFB"),
            ("transfer", "Transfer"),
            ("total", "Total"),
        ]:
            if phase in agg:
                d = agg[phase]
                print(
                    f"    {label + ':':18s} {format_duration(d['avg']):>12}"
                    f"  (min={format_duration(d['min'])},"
                    f" max={format_duration(d['max'])},"
                    f" p50={format_duration(d['p50'])},"
                    f" p95={format_duration(d['p95'])})",
                    file=out,
                )
        if "new_connections" in agg:
            print(f"\n    New Connections:    {agg['new_connections']:,}", file=out)
            print(f"    Reused Connections: {agg['reused_connections']:,}", file=out)
        else:
            print(
                "\n    Connection reuse:   not observable on this backend",
                file=out,
            )

    # Negotiated protocol. Only interesting when HTTP/2 was asked for, or when
    # a run somehow saw more than one protocol.
    if stats.http_versions and (config.http2 or len(stats.http_versions) > 1):
        print(f"\n{'=' * 70}", file=out)
        print("  NEGOTIATED PROTOCOL", file=out)
        print(f"{'=' * 70}", file=out)
        total_versioned = sum(stats.http_versions.values()) or 1
        for version, count in sorted(stats.http_versions.items()):
            pct = count / total_versioned * 100
            print(f"    HTTP/{version}: {count:>10,} ({pct:5.1f}%)", file=out)
        fallback = sum(c for v, c in stats.http_versions.items() if v != "2")
        if config.http2 and fallback:
            print(
                f"\n    WARNING: {fallback:,} request(s) did not use HTTP/2. The server "
                f"offered HTTP/1.1;\n             these numbers are not HTTP/2 numbers.",
                file=out,
            )

    # Status codes
    if stats.status_codes:
        print(f"\n{'=' * 70}", file=out)
        print("  STATUS CODE DISTRIBUTION", file=out)
        print(f"{'=' * 70}", file=out)
        for code in sorted(stats.status_codes):
            count = stats.status_codes[code]
            pct = count / stats.total_requests * 100 if stats.total_requests else 0
            print(f"    {code}: {count:>10,} ({pct:5.1f}%)", file=out)

    # Errors
    if stats.error_types:
        print(f"\n{'=' * 70}", file=out)
        print("  ERROR DISTRIBUTION", file=out)
        print(f"{'=' * 70}", file=out)
        for err, count in sorted(stats.error_types.items(), key=lambda x: -x[1]):
            print(f"    {err}: {count:>10,}", file=out)

    # Per-step stats (scenario mode)
    if stats.step_latencies:
        print(f"\n{'=' * 70}", file=out)
        print("  PER-STEP BREAKDOWN", file=out)
        print(f"{'=' * 70}", file=out)
        print_step_table(build_step_stats(stats, duration), file=out)

    # RPS timeline
    if stats.rps_timeline:
        print(f"\n{'=' * 70}", file=out)
        print("  THROUGHPUT TIMELINE", file=out)
        print(f"{'=' * 70}", file=out)
        print_rps_timeline(stats.rps_timeline, start_time, duration, file=out)

    print(f"\n{'=' * 70}", file=out)


def _write_output_files(
    stats: WorkerStats,
    duration: float,
    connections: int,
    start_time: float,
    config: BenchmarkConfig,
    rate_limiter: RateLimiter | None = None,
    file: TextIO | None = None,
) -> None:
    """Write any configured output files (CSV, JSON, HTML).

    Only file I/O — no console output except the brief confirmation
    lines that tell the user where each file was written.
    Observability exports (OTel, Prometheus) are handled separately by
    ``run_observability_exports`` (called from ``_finalize_run``) so that
    their failures can influence the process exit code.
    """
    out = file if file is not None else sys.stdout

    if config.csv_output:
        write_csv_output(config.csv_output, stats)
        print(f"\n  CSV percentile data written to: {config.csv_output}", file=out)

    if config.json_output:
        results = build_results_dict(stats, duration, connections, config, rate_limiter)
        write_json_output(config.json_output, results)
        print(f"\n  JSON results written to: {config.json_output}", file=out)

    if config.html_output:
        html = generate_html_report(stats, duration, connections)
        print(f"\n{html}", file=out)

    if config.html_report:
        html = generate_gatling_html_report(
            stats, duration, connections, config, rate_limiter, start_time
        )
        write_html_report(config.html_report, html)
        print(f"\n  HTML report written to: {config.html_report}", file=out)


def print_results(
    stats: WorkerStats,
    duration: float,
    connections: int,
    start_time: float,
    config: BenchmarkConfig,
    rate_limiter: RateLimiter | None = None,
    file: TextIO | None = None,
) -> None:
    """Print full benchmark results to stdout and write any configured output files."""
    _print_console_results(stats, duration, connections, start_time, config, rate_limiter, file)
    _write_output_files(stats, duration, connections, start_time, config, rate_limiter, file)


# ---------------------------------------------------------------------------
# Autofind reporting
# ---------------------------------------------------------------------------


def _format_latency_short(secs: float) -> str:
    """Format latency for autofind summary table (compact)."""
    if secs < 1.0:
        return f"{secs * 1000:.0f}ms"
    return f"{secs:.1f}s"


def print_autofind_summary(steps: list[StepResult], max_users: int | None) -> None:
    """Print the autofind summary table."""
    print()
    print("=" * 60)
    print("  AUTOFIND RESULTS")
    print("=" * 60)
    if max_users is not None and max_users > 0:
        print(f"  Maximum sustainable load: {max_users} users")
    else:
        print("  Maximum sustainable load: could not be determined")
    print()
    print("  Step Results:")
    print(
        f"  {'Users':>5} | {'RPS':>8} | {'p50':>7}"
        f" | {'p95':>7} | {'p99':>7} | {'Errors':>6} | Status"
    )
    for s in steps:
        status = "OK" if s.passed else "FAIL"
        print(
            f"  {s.users:>5} | {s.rps:>8.1f} | {_format_latency_short(s.p50):>7} | "
            f"{_format_latency_short(s.p95):>7} | {_format_latency_short(s.p99):>7} | "
            f"{s.error_rate:>5.1f}% | {status}"
        )
    print("=" * 60)


# ---------------------------------------------------------------------------
# Multi-URL reporting
# ---------------------------------------------------------------------------


def print_multi_url_summary(results: "list[MultiUrlResult]", file: TextIO | None = None) -> None:  # noqa: F821
    """Print a comparison table across all URLs."""
    out = file if file is not None else sys.stdout
    print(f"\n{'=' * 90}", file=out)
    print("  MULTI-URL COMPARISON SUMMARY", file=out)
    print(f"{'=' * 90}", file=out)

    # Header
    print(
        f"\n  {'#':>3}  {'Method':<7} {'URL':<40} {'Reqs':>7} {'RPS':>9} "
        f"{'p50':>9} {'p95':>9} {'p99':>9} {'Errs':>6}",
        file=out,
    )
    d = "\u2500"
    print(f"  {d * 3}  {d * 7} {d * 40} {d * 7} {d * 9} {d * 9} {d * 9} {d * 9} {d * 6}", file=out)

    for i, r in enumerate(results, 1):
        rps = r.stats.total_requests / r.duration if r.duration > 0 else 0
        url_display = r.url if len(r.url) <= 40 else r.url[:37] + "..."

        # Compute percentiles
        p50 = p95 = p99 = 0.0
        if r.stats.latencies:
            pct_map = dict(compute_percentiles(r.stats.latencies))
            p50 = pct_map.get(50, 0.0)
            p95 = pct_map.get(95, 0.0)
            p99 = pct_map.get(99, 0.0)

        err_pct = (
            (r.stats.errors / r.stats.total_requests * 100) if r.stats.total_requests > 0 else 0
        )

        print(
            f"  {i:>3}  {r.method:<7} {url_display:<40} "
            f"{r.stats.total_requests:>7,} {rps:>9,.1f} "
            f"{format_duration(p50):>9} {format_duration(p95):>9} {format_duration(p99):>9} "
            f"{err_pct:>5.1f}%",
            file=out,
        )

    print(f"\n{'=' * 90}", file=out)

    # Totals
    total_reqs = sum(r.stats.total_requests for r in results)
    total_errs = sum(r.stats.errors for r in results)
    total_bytes = sum(r.stats.total_bytes for r in results)
    print(
        f"  Total: {len(results)} endpoints, {total_reqs:,} requests, "
        f"{total_errs:,} errors, {format_bytes(total_bytes)} transferred",
        file=out,
    )
    print(f"{'=' * 90}\n", file=out)


def build_multi_url_json(results: "list[MultiUrlResult]") -> dict:  # noqa: F821
    """Build a JSON-serializable dict for multi-URL results."""
    endpoints = []
    for r in results:
        entry = build_results_dict(r.stats, r.duration, 0)
        entry["url"] = r.url
        entry["method"] = r.method
        endpoints.append(entry)

    return {
        "mode": "multi_url",
        "endpoint_count": len(results),
        "total_requests": sum(r.stats.total_requests for r in results),
        "total_errors": sum(r.stats.errors for r in results),
        "endpoints": endpoints,
    }
