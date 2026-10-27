"""Reducers for force-call tables.

The archive mean is awk ``printf "%.0f"``. On halves that rounds to even,
which is what Python ``round`` does for these ties.

The v2 cost is the PAR-2 mean. A failure is charged ``2 * cap`` instead
of being dropped. The success-rate interval and the bootstrap median sit
beside that mean. See ``docs/design/decision.md``.
"""

from __future__ import annotations

import math
import random
import statistics

import numpy as np

from .failures import FAILURES, failure_tally

RATE_Z = 1.959963984540054
PAR_FACTOR = 2
BOOTSTRAP_RESAMPLES = 2000
BOOTSTRAP_SEED = 20261015


def half_even(value: float) -> int:
    """Round to an integer, ties to even."""
    return round(value)


def _median(values: list[float]) -> float:
    ordered = sorted(values)
    n = len(ordered)
    mid = n // 2
    if n % 2:
        return float(ordered[mid])
    return (float(ordered[mid - 1]) + float(ordered[mid])) / 2


def summarize_all(counts: list[int], nfailed: int) -> dict[str, int | float | None]:
    """Mean, min, max, and median of every count, failures included.

    Transition-state rows use this reducer. A start that hit the step cap
    stays in the mean, and ``nfailed`` counts those starts.
    """
    if nfailed < 0:
        raise ValueError("nfailed must be zero or positive")
    if not counts:
        return {
            "force_calls": None,
            "force_calls_min": None,
            "force_calls_max": None,
            "force_calls_median": None,
            "nfailed": nfailed,
        }
    return {
        "force_calls": half_even(sum(counts) / len(counts)),
        "force_calls_min": min(counts),
        "force_calls_max": max(counts),
        "force_calls_median": _median([float(count) for count in counts]),
        "nfailed": nfailed,
    }


def band_total(force_calls: float, *, images: int | None, call_unit: str) -> tuple[float, float | None]:
    """Band total and the per-image quotient of that same total.

    ``call_unit`` is ``total`` or ``per_image``. The per-image value is
    ``None`` when the problem states no image count.
    """
    if call_unit == "total":
        total = float(force_calls)
    elif call_unit == "per_image":
        if not images:
            raise ValueError("per-image count has no image count")
        total = float(force_calls) * images
    else:
        raise ValueError(f"unknown call unit {call_unit}")
    per = None if not images else total / images
    return total, per


def normalize_start(raw: dict, images: int | None, *, per_image_track: bool = False) -> dict:
    """One start whose ``force_calls`` is the harness total across the band.

    A ``force_calls_neb`` row stores the per-image quotient in
    ``force_calls`` and the band counter in ``raw``. An old ASE asv track
    stored the per-image quotient; ``per_image_track`` puts that track back
    on the total. Every other row is already a total. ``per_image`` divides
    the total by ``images``, the same divisor for every code on the problem.
    """
    if not isinstance(raw, dict):
        raise ValueError("start is not a record")
    scaled = dict(raw)
    count_key = str(raw.get("count_key") or "")
    stated = str(raw.get("call_unit") or "")
    try:
        if count_key == "force_calls_neb":
            if raw.get("raw") not in (None, ""):
                total = float(raw["raw"])
                per = None if not images else total / images
            else:
                total, per = band_total(float(raw["force_calls"]), images=images, call_unit="per_image")
        elif stated == "per_image" or per_image_track:
            calls = raw.get("force_calls")
            if calls is None:
                raise ValueError("per-image count has no force calls")
            total, per = band_total(float(calls), images=images, call_unit="per_image")
        else:
            calls = raw.get("force_calls", raw.get("raw", raw.get("per_search")))
            if calls is None:
                return scaled
            total, per = band_total(float(calls), images=images, call_unit="total")
    except (TypeError, ValueError) as exc:
        raise ValueError(str(exc) or "per-image count has no image count") from exc
    scaled["force_calls"] = total
    scaled["call_unit"] = "total"
    if per is not None:
        scaled["per_image"] = per
    return scaled


def summarize_divided(
    counts: list[int],
    failed: list[bool],
    *,
    images: int,
    cap: int,
) -> dict[str, int | float | str | None]:
    """Mean of band totals that converged under ``cap``.

    ``cap`` is a total across the band, compared with ``count`` itself.
    ``force_calls`` is that total. ``force_calls_per_image`` divides the
    same kept totals by ``images``.
    """
    if images <= 0:
        raise ValueError("images must be positive")
    if cap <= 0:
        raise ValueError("cap must be positive")
    if len(counts) != len(failed):
        raise ValueError("counts and failed must have the same length")
    ok_raw: list[int] = []
    ok_per: list[float] = []
    nfailed = 0
    for count, flag in zip(counts, failed):
        if flag or count >= cap:
            nfailed += 1
            continue
        ok_raw.append(count)
        ok_per.append(count / images)
    if not ok_per:
        return {
            "force_calls": None,
            "force_calls_min": None,
            "force_calls_max": None,
            "force_calls_median": None,
            "force_calls_raw": None,
            "force_calls_per_image": None,
            "force_calls_per_image_min": None,
            "force_calls_per_image_max": None,
            "force_calls_per_image_median": None,
            "call_unit": "total",
            "nfailed": nfailed,
        }
    total_mean = half_even(sum(ok_raw) / len(ok_raw))
    return {
        "force_calls": total_mean,
        "force_calls_min": min(ok_raw),
        "force_calls_max": max(ok_raw),
        "force_calls_median": _median([float(value) for value in ok_raw]),
        "force_calls_raw": total_mean,
        "force_calls_per_image": half_even(sum(ok_per) / len(ok_per)),
        "force_calls_per_image_min": half_even(min(ok_per)),
        "force_calls_per_image_max": half_even(max(ok_per)),
        "force_calls_per_image_median": _median(ok_per),
        "call_unit": "total",
        "nfailed": nfailed,
    }


def summarize_capped(counts: list[int], cap: int) -> dict[str, int | None]:
    """Mean, min, and max of counts below ``cap``, and how many meet the cap.

    A count at or above ``cap`` is a failure and is left out of the mean.
    The mean is rounded with :func:`half_even`.
    """
    if cap <= 0:
        raise ValueError("cap must be positive")
    ok = [count for count in counts if count < cap]
    failed = len(counts) - len(ok)
    if not ok:
        return {
            "force_calls": None,
            "force_calls_min": None,
            "force_calls_max": None,
            "nfailed": failed,
        }
    return {
        "force_calls": half_even(sum(ok) / len(ok)),
        "force_calls_min": min(ok),
        "force_calls_max": max(ok),
        "nfailed": failed,
    }


def rate_interval(successes: int, starts: int, z: float = RATE_Z) -> tuple[float, float]:
    """Success-rate interval for ``successes / starts``.

    ``z`` is the standard-normal quantile. The default is the 95% value.
    The board does not show this interval.
    """
    if starts <= 0:
        raise ValueError("starts must be positive")
    if successes < 0 or successes > starts:
        raise ValueError("successes must lie between 0 and starts")
    phat = successes / starts
    z2 = z * z
    denom = 1.0 + z2 / starts
    center = (phat + z2 / (2.0 * starts)) / denom
    margin = z * math.sqrt(phat * (1.0 - phat) / starts + z2 / (4.0 * starts * starts)) / denom
    low = max(0.0, center - margin)
    high = min(1.0, center + margin)
    # k = 0 and k = n are exactly 0 and 1. Float error can land just inside.
    if successes == 0:
        low = 0.0
    if successes == starts:
        high = 1.0
    return low, high


def penalised_cost(force_calls: float, success: bool, cap: int | None, factor: int = PAR_FACTOR) -> float:
    """PAR cost. A failure, or a success at or above the cap, costs ``factor * cap``."""
    if cap is not None and (not success or force_calls >= cap):
        return float(factor * cap)
    if not success:
        raise ValueError("a failure needs a cap")
    return float(force_calls)


def quantile(values: list[float], fraction: float) -> float:
    """Linear quantile, the same ranks as ``sample_stats``."""
    if not values:
        raise ValueError("values is empty")
    ordered = sorted(float(value) for value in values)
    count = len(ordered)
    if count == 1:
        return ordered[0]
    position = (count - 1) * fraction
    low = int(position)
    high = min(low + 1, count - 1)
    weight = position - low
    return ordered[low] * (1.0 - weight) + ordered[high] * weight


def _percentile(sorted_values: list[float], fraction: float) -> float:
    return quantile(sorted_values, fraction)


def _row_quantile(ordered: np.ndarray, fraction: float) -> np.ndarray:
    """Linear quantile down each already-sorted row. Same ranks as ``quantile``."""
    count = ordered.shape[1]
    if count == 1:
        return ordered[:, 0]
    position = (count - 1) * fraction
    low = int(position)
    high = min(low + 1, count - 1)
    weight = position - low
    return ordered[:, low] * (1.0 - weight) + ordered[:, high] * weight


def _row_median(ordered: np.ndarray) -> np.ndarray:
    """``statistics.median`` down each already-sorted row."""
    count = ordered.shape[1]
    mid = count // 2
    if count % 2:
        return ordered[:, mid]
    return (ordered[:, mid - 1] + ordered[:, mid]) / 2.0


def _python_mt19937(seed: int) -> np.random.MT19937:
    """NumPy MT19937 sitting on the state ``random.Random(seed)`` would use."""
    version, state, _gauss = random.Random(seed).getstate()
    if version != 3:
        raise RuntimeError(f"unexpected random state version {version}")
    bitgen = np.random.MT19937()
    bitgen.state = {
        "bit_generator": "MT19937",
        "state": {"key": np.array(state[:-1], dtype=np.uint32), "pos": int(state[-1])},
    }
    return bitgen


class _Randrange:
    """``random.Random.randrange(count)`` drawn from one MT19937 stream.

    ``randrange`` keeps the top ``bit_length`` bits of each word and rejects
    a word that falls outside ``count``. A batch can accept more values than
    the caller asked for. Those values stay queued, so the next batch
    continues the same sequence instead of skipping ahead.
    """

    def __init__(self, seed: int, count: int) -> None:
        width = count.bit_length()
        if width > 32 or count <= 0:
            raise ValueError("randrange index draw does not fit this stream")
        self.bitgen = _python_mt19937(seed)
        self.count = count
        self.shift = np.uint64(32 - width)
        self.pending = np.empty(0, dtype=np.int64)

    def take(self, needed: int) -> np.ndarray:
        parts: list[np.ndarray] = []
        have = 0
        if self.pending.size:
            use = min(needed, int(self.pending.size))
            parts.append(self.pending[:use])
            self.pending = self.pending[use:]
            have = use
        while have < needed:
            remain = needed - have
            raw = np.asarray(self.bitgen.random_raw(remain * 2 + 64), dtype=np.uint64)
            draw = (raw & np.uint64(0xFFFFFFFF)) >> self.shift
            chosen = draw[draw < self.count].astype(np.int64, copy=False)
            if chosen.size == 0:
                continue
            parts.append(chosen)
            have += int(chosen.size)
        out = parts[0] if len(parts) == 1 else np.concatenate(parts)
        if out.size > needed:
            self.pending = out[needed:]
            out = out[:needed]
        return out


def _resample_order_statistics(
    values: list[float],
    resamples: int,
    seed: int,
    kinds: tuple[str, ...],
) -> dict[str, list[float]]:
    """Median and IQR of each resample.

    A campaign file is tens of thousands of starts, and the board scores
    every file. Drawing those resamples in Python and sorting each one
    with ``sorted`` is what made ``uv run pytest`` sit for over an hour.
    The draws are still ``random.Random.randrange``. NumPy sorts them.
    The point estimate is still the Python statistic on the original sample.
    """
    count = len(values)
    base = np.asarray(values, dtype=np.float64)
    draw = _Randrange(seed, count)
    block = max(1, min(resamples, max(1, 4_000_000 // count)))
    buckets = {kind: [] for kind in kinds}
    remaining = resamples
    while remaining:
        take = min(block, remaining)
        index = draw.take(take * count).reshape(take, count)
        ordered = np.sort(base[index], axis=1)
        if "median" in buckets:
            buckets["median"].extend(_row_median(ordered).tolist())
        if "iqr" in buckets:
            reduced = _row_quantile(ordered, 0.75) - _row_quantile(ordered, 0.25)
            buckets["iqr"].extend(reduced.tolist())
        remaining -= take
    return buckets


def _bounds(samples: list[float], alpha: float) -> tuple[float, float]:
    samples.sort()
    return _percentile(samples, alpha / 2.0), _percentile(samples, 1.0 - alpha / 2.0)


def bootstrap_interval(
    values: list[float],
    statistic,
    *,
    resamples: int = BOOTSTRAP_RESAMPLES,
    seed: int = BOOTSTRAP_SEED,
    alpha: float = 0.05,
) -> tuple[float, float, float]:
    """Point estimate and percentile bootstrap interval.

    Returns ``(statistic(values), low, high)``. Resamples are drawn with
    replacement from a fixed seed so a published interval can be recomputed.
    The median and the interquartile range are reduced in NumPy. The draws
    are the ``random.Random`` sequence, so the interval is unchanged.
    """
    if not values:
        raise ValueError("values is empty")
    if resamples <= 0:
        raise ValueError("resamples must be positive")
    point = float(statistic(values))
    if statistic is statistics.median:
        samples = _resample_order_statistics(values, resamples, seed, ("median",))["median"]
    elif statistic is _iqr:
        samples = _resample_order_statistics(values, resamples, seed, ("iqr",))["iqr"]
    else:
        rng = random.Random(seed)
        count = len(values)
        samples = []
        for _ in range(resamples):
            draw = [values[rng.randrange(count)] for _ in range(count)]
            samples.append(float(statistic(draw)))
    low, high = _bounds(samples, alpha)
    return point, low, high


def _iqr(values: list[float]) -> float:
    return quantile(values, 0.75) - quantile(values, 0.25)


def distribution_summary(
    values: list[float],
    *,
    resamples: int = BOOTSTRAP_RESAMPLES,
    seed: int = BOOTSTRAP_SEED,
) -> dict[str, float | int]:
    """Median, interquartile range, and bootstrap intervals of a cost sample."""
    if not values:
        raise ValueError("values is empty")
    # Both intervals use the same seed, so they share one resample stream.
    drawn = _resample_order_statistics(values, resamples, seed, ("median", "iqr"))
    median = float(statistics.median(values))
    median_low, median_high = _bounds(drawn["median"], 0.05)
    iqr = float(_iqr(values))
    iqr_low, iqr_high = _bounds(drawn["iqr"], 0.05)
    return {
        "n": len(values),
        "mean": statistics.fmean(values),
        "median": median,
        "median_low": median_low,
        "median_high": median_high,
        "q25": quantile(values, 0.25),
        "q75": quantile(values, 0.75),
        "iqr": iqr,
        "iqr_low": iqr_low,
        "iqr_high": iqr_high,
        "bootstrap_resamples": resamples,
        "bootstrap_seed": seed,
    }


def score_v2(
    records: list[dict],
    cap: int | None,
    *,
    factor: int = PAR_FACTOR,
    resamples: int = BOOTSTRAP_RESAMPLES,
    seed: int = BOOTSTRAP_SEED,
) -> dict:
    """PAR-2 mean, success-rate interval, and bootstrap median of one run.

    Each record has ``force_calls`` and ``success``. When ``cap`` is
    ``None`` every record must be a success, and ``par_applied`` is false.
    That is the Pt-island per-search sample: the problem states no cap.
    """
    if not records:
        raise ValueError("records is empty")
    successes = 0
    costs: list[float] = []
    for record in records:
        success = bool(record["success"])
        if success:
            successes += 1
        costs.append(penalised_cost(float(record["force_calls"]), success, cap, factor))
    starts = len(records)
    low, high = rate_interval(successes, starts)
    summary = distribution_summary(costs, resamples=resamples, seed=seed)
    tally = failure_tally(records, cap)
    failed = starts - successes
    if sum(tally.values()) != failed:
        raise RuntimeError("failure classes dropped a start")
    finished = [float(record["force_calls"]) for record in records if record["success"]]
    summary.update(
        {
            "scoring": "par2-bootstrap",
            "successes": successes,
            "nfailed": failed,
            "success_rate": successes / starts,
            "rate_low": low,
            "rate_high": high,
            "par_factor": factor,
            "cap": cap,
            "par_applied": cap is not None,
            "par2_mean": summary["mean"] if cap is not None else None,
            "includes_failures": True,
            "success_only_mean": (sum(finished) / len(finished)) if finished else None,
            **{f"n_{name}": tally[name] for name in FAILURES},
        }
    )
    return summary
