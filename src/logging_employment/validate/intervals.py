"""§10.7's empirical predictive intervals, from pseudo-suppression residuals.

§10.7 asks for them "from ROLLING pseudo-suppression residuals" and this package does not
compute that: `metrics.probabilistic_metrics` pools every OTHER scored residual in the same
(regime, seed, arm, estimator) group and drops the target's own by INDEX, which is
cross-sectional leave-one-out within a replicate — no time ordering, no window. That gap is
R-S5P-7, and `contracts.INTERVAL_SOURCES` now NAMES it rather than repeating the spec's word;
the spec's word is quoted here so the divergence stays visible to a reader of this module and
is not mistaken for a docstring that drifted. Plan 16 did NOT build the time-ordered version:
the state-total model's intervals come from its own reconciled draws
(`metrics.draw_interval_metrics`), and §13.10 reads the baselines' intervals as this module
computes them, under their own name.

ONE object: the residual-shifted ensemble. Both the quantiles and the CRPS are derived from it, so
an interval and a score can never disagree about the same predictive distribution.

Log score is deliberately NOT offered. An empirical ensemble assigns zero density outside its own
range, so a log score is -inf whenever the truth falls outside — a property of the density
estimator, not of the method being scored. §13.7 permits "CRPS or log score"; this package reports
CRPS.
"""

from __future__ import annotations

import numpy as np


def residual_ensemble(residuals: np.ndarray, point: float) -> np.ndarray:
    """The truths the point estimate implies, one per pooled residual: `point - residual`.

    A scoring residual is `estimate - truth`, the difference `point_metrics`' WAPE error also takes
    (the anchor's adding-up `residual` in `harness.py` is a different quantity), so the truth it
    predicts is `estimate - residual`. §10.7 states no
    sign, and from Stage 4 until `D-112` this ADDED the pool, which doubles an estimator's bias
    instead of removing it: on a synthetic method biased +25%, 90% coverage was 0.00 added and 0.85
    subtracted. The sign lives here rather than in `probabilistic_metrics`' pool so the orientation
    has one owner. A symmetric pool passed whole sorts to the same ensemble under either sign, which
    is why `test_validate_intervals.py` pins this with a one-sided one.

    The residual pool MUST exclude the target's own cell: a residual computed on the cell being
    scored is the withheld truth in another form (§13.4 bullet 1).
    """
    return float(point) - np.asarray(residuals, dtype=float)


def clip_at_zero(ensemble: np.ndarray) -> tuple[np.ndarray, int]:
    """Employment cannot be negative. Returns the clipped ensemble AND the count clipped.

    The count is returned rather than discarded because clipping shifts nominal coverage; a
    coverage number computed over a clipped ensemble with an unreported clip rate is not
    interpretable.
    """
    clipped = np.maximum(ensemble, 0.0)
    return clipped, int((ensemble < 0.0).sum())


def empirical_interval(ensemble: np.ndarray, level: float) -> tuple[float, float]:
    """A central `level` interval from the ensemble's own quantiles."""
    tail = (1.0 - level) / 2.0
    return (
        float(np.quantile(ensemble, tail)),
        float(np.quantile(ensemble, 1.0 - tail)),
    )


def crps(ensemble: np.ndarray, truth: float) -> float:
    """CRPS by the energy form: E|X - y| - 0.5 * E|X - X'|.

    The second term uses the sorted-ensemble identity
    `sum_i sum_j |x_i - x_j| = 2 * sum_i (2i - n + 1) * x_(i)`
    rather than materialising the n x n pairwise matrix. It is an IDENTITY, not an approximation —
    `test_the_closed_form_matches_the_pairwise_matrix` pins the two against each other.

    The reason is cost, and it is not academic. The harness scores one CRPS per masked cell over an
    ensemble of the other cells' residuals, so the pairwise form is O(n^2) per cell and O(n^3) per
    estimator; `whole_seasonal_blocks` masks 291 cells, and §13.7's metrics — not `run_baselines` —
    became the harness's dominant cost.
    """
    x = np.sort(np.asarray(ensemble, dtype=float))
    n = x.size
    term_one = np.abs(x - float(truth)).mean()
    weights = 2.0 * np.arange(n, dtype=float) - n + 1.0
    term_two = 2.0 * float(np.dot(weights, x)) / (n * n)
    return float(term_one - 0.5 * term_two)
