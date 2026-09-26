"""§10.3's five historical state-share baselines.

The spec lists exactly five (§10.3): last observed share, same-month previous-year share,
rolling median share, exponentially weighted historical share, and a robust break-adjusted share.
All five share one history extractor and differ only in how they reduce a series of shares to one
number, which is the whole reason they belong in one module.

CLASSIFICATION-CONSISTENT PERIODS. §10.3 requires them and does not define them. The D1 window
carries a NAICS vintage break at 2022-01 -- NAICS 2017 through 2021-12, NAICS 2022 from 2022-01 --
so a 24-month lookback from 2022-06 would otherwise mix two classifications. The default is to stop
at the break, and CITED 2026-09-08 that default is the right one: BLS still places reference years
2017-2021 on NAICS 2017 four years after NAICS 2022 arrived, so the break is real and prior years
were not recoded. The quotation, its source and its one qualification live at
`harmonize/naics.py`'s `_VINTAGE_BOUNDARY_YEAR`.

The behaviour stays a config key rather than becoming a constant, but for a narrower reason than
this docstring used to give. It used to say the premise was UNCITED and that "a key can be flipped
by whoever finds the citation". The citation is now found and it CONFIRMS the default rather than
changing it; what stays open is the estimator question of whether crossing a real break is ever
preferable to a shorter history, which is a §10.3 judgement and not a sourcing one. Flipping the
key is also not free: `runs.run_id` hashes the resolved config, so a flip re-numbers the run.

THE LOOKBACK IS BOUNDED IN MONTHS, NOT ROWS. `historical_lookback_months` names a span of calendar
time, so taking the last N rows of an observed-only series is a different estimator: a state
observed in only 8 of the last 60 months would reach back five years under a row bound while the
config says two. Both bounds are applied -- months first, then the row cap -- so the config key
means what it says.

WHY THE OWN ARM IS IN EMPLOYEES. A reduced share is dimensionless and runs around 1e-3, while the
establishment fallback runs 1..282. `allocate` normalizes the union of the two, so merging them
raw lets the fallback absorb essentially the whole residual -- measured on 2024-03, the states
holding real histories received 0.037% of R_t between them. The share is therefore multiplied by
the published national total for the month, making the own arm a predicted employment level, and
the fallback arrives already scaled to employees. Neither step invents a number.

COVERAGE. Six states have zero observed employment months in the whole window -- AK, DE, HI, ND,
NV, VT -- so no in-window share exists for them, and every one of the 96 months' missing sets
contains at least one. The own/fallback split is a measurement that a revision moves, so it is
recorded in the run manifest rather than written here. Without composition this entire family
would decline in 96/96 months and §10.8's rung 3 would be permanently empty.
"""

from __future__ import annotations

import statistics
from collections.abc import Mapping

import polars as pl

from ..reconcile.allocate import Weights
from ..reconcile.anchor import Anchor, Partition
from .fallback import DISCLOSED_QCEW, compose_with_declared_fallback
from .interfaces import Decline, EmployeeWeights, EstimatorContext


def _month_index(month: str) -> int:
    """A `YYYY-MM` as a count of months, so two months subtract to their calendar distance."""
    year, index = (int(part) for part in month.split("-"))
    return year * 12 + (index - 1)


def _months_before(month: str, count: int) -> str:
    """The `YYYY-MM` exactly `count` months earlier, for bounding a lookback in calendar time."""
    total = _month_index(month) - count
    return f"{total // 12:04d}-{total % 12 + 1:02d}"


def observed_share_history(
    monthly: pl.DataFrame,
    partitions: Mapping[str, Partition],
    *,
    state_fips: str,
    before: str,
    lookback_months: int,
    may_cross_vintage: bool,
    vintage: str,
) -> pl.DataFrame:
    """One state's disclosed shares of the national total, most recent last.

    VISIBILITY COMES FROM THE PARTITION, NEVER FROM `observation_status`. This is the same
    mask-parameterised rule the anchor follows, and here it is a leakage control rather than a
    matter of taste: under a Stage 4 pseudo-suppression mask the held-out cell still carries its
    published value in `qcew_monthly`, so a history filtered on the table would hand this
    estimator the very value it is being tested on. Measured on a two-month panel, the table-based
    filter returned a masked cell's own published employment back to it exactly, through the
    share. §13.4 forbids a derived feature retaining a held-out value, and a share of it is one.

    Reading the partition also fixes what the table filter got wrong even unmasked: `disclosed`
    holds `true_zero` as well as `observed`, so a published zero now enters the history as the
    zero share it is. Filtering on `== "observed"` skipped past it to an older positive value.
    """
    national = monthly.filter(pl.col("area_type") == "national").select(
        ["reference_month", pl.col("employment_value").alias("national_value")]
    )
    floor = _months_before(before, lookback_months)
    windows = [
        partition.disclosed for month, partition in partitions.items() if floor <= month < before
    ]
    if not windows:
        return pl.DataFrame(schema={"reference_month": pl.String, "share": pl.Float64})
    rows = (
        pl.concat(windows)
        .filter(pl.col("state_fips") == state_fips)
        .join(national, on="reference_month", how="inner")
        .filter(pl.col("national_value") > 0)
    )
    if not may_cross_vintage:
        rows = rows.filter(pl.col("naics_vintage") == vintage)
    return (
        rows.with_columns((pl.col("employment_value") / pl.col("national_value")).alias("share"))
        .sort("reference_month")
        .tail(lookback_months)
        .select(["reference_month", "share"])
    )


def _vintage_at(monthly: pl.DataFrame, reference_month: str) -> str:
    """The NAICS vintage the target month is published under."""
    rows = monthly.filter(pl.col("reference_month") == reference_month)
    return str(rows["naics_vintage"][0])


def _national_total(monthly: pl.DataFrame, reference_month: str) -> float:
    """The published national employment row for the month, which puts a share into employees."""
    rows = monthly.filter(
        (pl.col("area_type") == "national") & (pl.col("reference_month") == reference_month)
    )
    return float(rows["employment_value"][0])


class _ShareBaseline:
    """Shared plumbing: extract each missing cell's share history, reduce it, then compose."""

    estimator_id = "historical_share"
    # §10.3 has no shrinkage limit to appeal to, so its fallback is scaled by the published ratio
    # of two published sums over the month's disclosed cells (R-COMP-7).
    fallback_intensity = DISCLOSED_QCEW

    def _reduce(self, shares: list[float], anchor: Anchor, history: pl.DataFrame) -> float | None:
        """Collapse one state's share history to a single share, or `None` to take the fallback.

        The only thing the five variants differ in. `history` is passed alongside `shares` because
        the same-month-previous-year variant selects by month rather than by position.
        """
        raise NotImplementedError

    def weights(self, context: EstimatorContext, anchor: Anchor) -> Weights | Decline:
        """A predicted employment level per cell with a usable history, composed with the fallback."""
        cfg = context.config.baselines
        vintage = _vintage_at(context.monthly, anchor.reference_month)
        national = _national_total(context.monthly, anchor.reference_month)
        own: dict[str, float] = {}
        for cell in anchor.missing_cells:
            history = observed_share_history(
                context.monthly,
                context.partitions,
                state_fips=cell,
                before=anchor.reference_month,
                lookback_months=cfg.historical_lookback_months,
                may_cross_vintage=cfg.historical_may_cross_naics_vintage,
                vintage=vintage,
            )
            shares = history["share"].to_list()
            if not shares:
                continue
            reduced = self._reduce(shares, anchor, history)
            if reduced is not None and reduced > 0.0:
                # Share -> employees, so both arms of the composite share a unit.
                own[cell] = reduced * national
        return compose_with_declared_fallback(self, EmployeeWeights(own), context, anchor)


class LastObservedShare(_ShareBaseline):
    """§10.3 variant 1."""

    estimator_id = "share_last_observed"

    def _reduce(self, shares, anchor, history):
        """The most recent observed share."""
        return shares[-1]


class SameMonthPreviousYearShare(_ShareBaseline):
    """§10.3 variant 2: the same calendar month one year earlier, or nothing.

    Falls back to no own weight rather than to the nearest month: substituting a different month
    would make this variant indistinguishable from `LastObservedShare` exactly when it matters.
    """

    estimator_id = "share_same_month_prior_year"

    def _reduce(self, shares, anchor, history):
        """The share twelve months back, or `None` if that month was not observed."""
        year, month = anchor.reference_month.split("-")
        wanted = f"{int(year) - 1:04d}-{month}"
        matched = history.filter(pl.col("reference_month") == wanted)["share"].to_list()
        return matched[0] if matched else None


class RollingMedianShare(_ShareBaseline):
    """§10.3 variant 3."""

    estimator_id = "share_rolling_median"

    def _reduce(self, shares, anchor, history):
        """The median share over the lookback."""
        return statistics.median(shares)


class ExponentiallyWeightedShare(_ShareBaseline):
    """§10.3 variant 4: a geometric discount whose half-life is twelve CALENDAR MONTHS.

    `_reduce` weighs each share by `decay` raised to its age in months, so a share a year older
    than the newest counts half as much. Until `D-113` it raised `decay` to the share's POSITION in
    the list instead, and because `observed_share_history` keeps disclosed months only, a
    suppressed month shortened the list rather than ageing the shares behind it: the half-life was
    twelve OBSERVATIONS, and every gap stretched it in calendar time (`D-095` measured how far).
    §10.3 names no decay form, so the unit is a modelling choice; the owner chose calendar months.

    AGES ARE COUNTED BACK FROM THE NEWEST OBSERVATION, NOT FROM THE TARGET MONTH. The weights are
    normalized, so the two differ by a common factor that cancels and give the same mean. Counting
    from the newest share keeps a gap-free history's exponents equal to the old list positions, so
    such a history reduces bit-identically to the per-observation form and only gappy histories
    move. It also means how long ago the newest share was published changes nothing here: the
    staleness of a whole history is the lookback's business, and the lookback is bounded in months.
    """

    estimator_id = "share_exponentially_weighted"
    decay = 0.5 ** (1.0 / 12.0)

    def _reduce(self, shares, anchor, history):
        """A geometrically discounted mean, each share weighted by its age in calendar months."""
        months = [_month_index(month) for month in history["reference_month"].to_list()]
        newest = max(months)
        weights = [self.decay ** (newest - month) for month in months]
        return sum(w * s for w, s in zip(weights, shares, strict=True)) / sum(weights)


class BreakAdjustedShare(_ShareBaseline):
    """§10.3 variant 5: robust to a level break in the share series.

    Uses the median of the most recent segment after the largest single-step change, so one
    reclassification or one plant closure does not drag the estimate toward a regime that ended.

    REFUSES RATHER THAN IMPERSONATES. A cut leaving fewer than two points in the recent segment
    is not evidence of a regime, so this variant declines it: a one-point segment IS the last
    observation, which is variant 1, and a history too short to cut at all reduces to the plain
    median, which is variant 3. Either would ship another variant's number under this one's name.
    `_reduce` returns `None` instead and the cell takes the declared §10.2 fallback -- the same
    refusal `SameMonthPreviousYearShare` makes, for the same reason.

    THE THRESHOLD IS A PROPERTY OF THE SELECTED CUT, NOT OF THE HISTORY LENGTH. A three-point
    history cut in the middle leaves two points and is kept; a twelve-point history whose largest
    step is its last leaves one point and is refused. No bound on the number of shares separates
    those two cases.

    THE EARLIEST TIED STEP WINS. `steps.index(max(steps))` takes the first maximum, so a history
    with two equal largest steps segments at the earlier one. That is declared here, not chosen
    here: it is the behaviour this class has always had, and moving it would move cells for a
    reason nothing has argued.
    """

    estimator_id = "share_break_adjusted"

    def _reduce(self, shares, anchor, history):
        """The median of the segment following the largest single-step level change, or `None`.

        The length guard is not the threshold: it is what makes `max(steps)` legal, since a
        one-point history has no steps to take a maximum over and `max(())` raises. The threshold
        proper is the segment check, which is why it reads the cut rather than the input.
        """
        if len(shares) < 2:
            return None
        steps = [abs(shares[i + 1] - shares[i]) for i in range(len(shares) - 1)]
        cut = steps.index(max(steps)) + 1
        segment = shares[cut:]
        if len(segment) < 2:
            return None
        return statistics.median(segment)
