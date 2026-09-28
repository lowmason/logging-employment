"""Stage 4's exit criteria, witnessed on the committed fixture layer rather than on data/staged.

The fixture is in git, so these run on a clean checkout. Where a claim is about D1 specifically the
test says so and carries the `data/staged` skipif.
"""

from pathlib import Path

import polars as pl
import pytest
from tests.conftest import STAGED, requires_staged

from logging_employment import contracts
from logging_employment.baselines.runner import REGISTRY
from logging_employment.cli import _input_digests
from logging_employment.config import Config, load_config
from logging_employment.contracts import (
    VALIDATION_SCORE_SCHEMA,
    HarmonizedData,
    validate_frame,
)
from logging_employment.reconcile.scaling import Bounds
from logging_employment.runs import run_id
from logging_employment.validate import harness
from logging_employment.validate.harness import run_pseudo_suppression

REPO = Path(__file__).resolve().parents[2]
FIXTURE = REPO / "tests" / "fixtures" / "baselines"


def _fixture_config() -> Config:
    cfg = load_config(REPO / "config.yaml")
    return cfg.model_copy(
        update={
            "validation": cfg.validation.model_copy(
                update={"replicates_per_regime": 3, "pseudo_suppression_seeds": [1024]}
            )
        }
    )


@pytest.fixture(scope="module")
def fixture_run():
    """One full-registry harness pass, shared by every test here.

    Module scope because the pass costs ~11s and both tests need the same one; nothing about
    parallelism — no xdist plugin is installed in this venv and nothing configures it.
    """
    return run_pseudo_suppression(HarmonizedData.load(FIXTURE), REGISTRY, _fixture_config())


def test_the_rolling_origin_entry_records_the_origins_its_guard_checked(fixture_run):
    """R-S4C-4: the guard is the deliverable, so the manifest must say where it ran.

    On this fixture the answer is NONE — it carries 2023 alone, so no January has the configured
    six months of history behind it. An empty list is the honest record and is not the same as an
    absent key: absent would mean the guard was never reached.
    """
    entry = fixture_run.manifest["regimes"]["rolling_origin"]
    assert "origins_checked" in entry
    assert entry["origins_checked"] == []
    assert entry["n_scored"] == 0


def test_only_the_truncating_regime_records_origins(fixture_run):
    """A key that appeared on every entry would say nothing about which regime owns the guard."""
    carrying = {
        name
        for name, entry in fixture_run.manifest["regimes"].items()
        if "origins_checked" in entry
    }
    assert carrying == {"rolling_origin"}


@pytest.mark.slow
@requires_staged
def test_the_guard_is_binding_on_the_d1_panel():
    """The fixture makes the guard vacuous, so the binding case is witnessed separately.

    Two estimators rather than the registry: this test is about the origins, and §13.7's CRPS is
    the harness's dominant cost.
    """
    cfg = load_config(REPO / "config.yaml")
    cfg = cfg.model_copy(
        update={
            "validation": cfg.validation.model_copy(update={"pseudo_suppression_seeds": [1024]})
        }
    )
    result = run_pseudo_suppression(HarmonizedData.load(STAGED), REGISTRY[:2], cfg)
    origins = result.manifest["regimes"]["rolling_origin"]["origins_checked"]
    assert origins == [
        "2018-01",
        "2019-01",
        "2020-01",
        "2021-01",
        "2022-01",
        "2023-01",
        "2024-01",
    ]


def test_a_regime_excluded_by_its_switch_appears_with_a_reason_naming_the_switch(fixture_run):
    """R-S4C-12: excluded is not absent. A vanishing regime is the empty partition this refuses."""
    for regime, switch in (
        ("retrospective_smoothing", "include_retrospective_smoothing"),
        ("preliminary_to_final_vintage", "include_vintage_comparison"),
    ):
        entry = fixture_run.manifest["regimes"][regime]
        assert entry["n_scored"] == 0
        assert switch in entry["reason"], entry["reason"]


def test_the_config_derived_reason_still_carries_the_declared_one(fixture_run):
    """The switch is WHY it did not run here; the declared reason is why it could not anyway."""
    entry = fixture_run.manifest["regimes"]["preliminary_to_final_vintage"]
    assert "second snapshot" in entry["reason"]


def test_an_enabled_switch_leaves_its_regime_alone(fixture_run):
    """`include_long_runs` ships true, so `long_consecutive_runs` must still score."""
    entry = fixture_run.manifest["regimes"]["long_consecutive_runs"]
    assert entry["n_scored"] > 0
    assert "include_long_runs" not in str(entry.get("reason", ""))


def test_turning_the_vintage_switch_on_still_raises(fixture_run):
    """The fail-closed refusal must survive the switch gating, not be swallowed by it.

    `tests/unit/test_validate_declared_regimes.py::test_asking_for_the_vintage_regime_makes_the
    _harness_refuse` is the pin; this asserts the ORDER — the switch check must not return a
    config-derived reason for a regime the operator explicitly asked for.
    """
    del fixture_run
    cfg = _fixture_config()
    cfg = cfg.model_copy(
        update={
            "validation": cfg.validation.model_copy(update={"include_vintage_comparison": True})
        }
    )
    with pytest.raises(NotImplementedError, match="second snapshot"):
        run_pseudo_suppression(HarmonizedData.load(FIXTURE), REGISTRY[:1], cfg)


def test_the_scores_frame_produces_exactly_what_it_declares(fixture_run):
    """M11: 23 produced against 20 declared, overlapping in 17 — a three-way disagreement.

    `cli.py` called the produced set "a superset", which it was not: three declared columns were
    produced by nothing. Set equality, not containment, is the assertion.
    """
    assert set(fixture_run.scores.columns) == set(VALIDATION_SCORE_SCHEMA)
    validate_frame(fixture_run.scores, VALIDATION_SCORE_SCHEMA, "validation_scores")


def test_the_seed_column_is_int64_in_both_frames(fixture_run):
    """R-S4C-18: resolved toward the DECLARATION, not by weakening the schema to Int32.

    `pl.lit(seed)` infers Int32 on polars 1.44 while the metrics frame builds Int64 from Python
    dicts, so the two disagreed. Seeds come from `config.validation.pseudo_suppression_seeds` and
    nothing bounds them to 32 bits.
    """
    assert fixture_run.scores.schema["seed"] == pl.Int64
    assert fixture_run.metrics.schema["seed"] == pl.Int64


def test_the_two_constraint_hashes_are_different_columns(fixture_run):
    """M11: `masked_constraint_set_hash` is not a rename of `constraint_set_hash`.

    Neither may be dropped as a duplicate. The masked one is the hash of the system this replicate
    actually solved; the unmasked one rides in from `run_baselines` and is null on this fixture.
    """
    assert "constraint_set_hash" in fixture_run.scores.columns
    assert "masked_constraint_set_hash" in fixture_run.scores.columns
    assert fixture_run.scores["masked_constraint_set_hash"].null_count() == 0


def test_the_three_new_columns_are_derived_rather_than_constant(fixture_run):
    """A column with one value on every row records nothing.

    Two of the three legitimately have one HERE: `mask_arm` is `state_total` by design, and
    `replicate` is `[0]` because this fixture configures a single seed — it varies only across a
    multi-seed run. `lookback_months_masked` is the one this test actually shows varying.
    """
    scores = fixture_run.scores
    assert scores["mask_arm"].null_count() == 0
    assert scores["mask_arm"].unique().to_list() == ["state_total"]
    assert scores["replicate"].unique().to_list() == [0]
    # `lookback_months_masked` is the per-state masked-month count, so a blackout regime's rows
    # must carry more than a single-month regime's.
    blackout = scores.filter(pl.col("regime") == "long_consecutive_runs")
    single = scores.filter(pl.col("regime") == "small_cell_biased")
    assert blackout["lookback_months_masked"].max() > single["lookback_months_masked"].max()


def test_an_empty_run_reads_as_nothing_scored_rather_than_a_schema_failure():
    """The distinction the gate must preserve: "this run scored nothing" is a RESULT;
    "thirteen columns missing" is a schema failure, and reporting the second for the first is how
    an empty run gets mistaken for a broken one.

    An empty estimator list is the cheapest trigger — measured, it leaves `metrics` and
    `scoreboard` bare while the manifest still carries all thirteen regimes.
    """
    result = run_pseudo_suppression(HarmonizedData.load(FIXTURE), [], _fixture_config())

    assert result.metrics.height == 0
    contracts.validate_frame(
        result.metrics, contracts.VALIDATION_METRIC_SCHEMA, "validation_metrics"
    )

    assert result.scoreboard.height == 0
    contracts.validate_frame(
        result.scoreboard, contracts.VALIDATION_SCOREBOARD_SCHEMA, "validation_scoreboard"
    )

    # The run happened; it just scored nothing. That is what the shaped frames must not obscure.
    assert len(result.manifest["regimes"]) == 13


@requires_staged
def test_the_shipped_config_resolves_to_the_parent_margin_comparand_run():
    """V1: the sharpest single check that no config field and no staged input changed unnoticed.

    `run_id` hashes `resolved_dict(cfg)` — the whole pydantic model — and the input digests. This
    cannot use the `staged_repo` fixture: that rewrites every `storage.*_uri` into a tmp path and
    copies the smaller fixture parquets, so both halves of the payload differ by construction. It
    needs the real `config.yaml` and the real staged layer.

    MOVED ONCE, deliberately, by plan 15 Task 4: the fifth staged table (`qcew_state_parent`) and
    `D-114`'s rewrite of `cbp_state_size.parquet` re-id every run. The previous pin, `f03023ac9f3a`,
    is Stage 4's acceptance run; it stays on disk as the comparand plan 15 Task 9 measures against.

    MOVED AGAIN by plan 16's config task: Appendix A's `model:` block joined `resolved_dict`. The
    pin before it, `4cf47a918dd8`, is the §13.10 comparand. Plan 16 re-runs it under this id,
    checks the two byte for byte, and keeps the old directory on disk.
    """
    cfg = load_config(REPO / "config.yaml")
    assert run_id(cfg, _input_digests(cfg)) == "dd7337e89047"


def test_no_scoring_regime_gained_or_lost_a_score(fixture_run):
    """V2: seven regimes score on this fixture and the same seven must score after.

    SEVEN, not V2's nine: nine is the D1 figure. `structural_break` and `naics_transition` find no
    in-window month on a fixture that carries 2023 alone, so they draw no target here.
    """
    scoring = {
        name for name, entry in fixture_run.manifest["regimes"].items() if entry["n_scored"] > 0
    }
    assert scoring == {
        "small_cell_biased",
        "concentration_proxy",
        "clustered_states_within_month",
        "long_consecutive_runs",
        "whole_state_year_blocks",
        "whole_seasonal_blocks",
        "regional_blocks",
    }


def test_the_scoreboard_is_unchanged_by_everything_in_this_plan(fixture_run):
    """V2: the board must be byte-identical, because nothing here touches a scored number.

    The `mask_arm` the declines family gained rides on the `declines` rows, and `build_scoreboard`
    joins those onto the point rows by (regime, seed, estimator_id) — `mask_arm` is not in the join
    key, so the join is unmoved. This asserts that rather than trusting it.
    """
    board = fixture_run.scoreboard
    assert board.height == 70
    assert board["mask_arm"].unique().to_list() == ["state_total"]
    assert board["wape"].null_count() == 13
    assert board["regime"].n_unique() == 7


def test_exactly_four_regimes_carry_a_changed_reason(fixture_run):
    """V4: two gain measured reasons and two gain config-derived ones. No other entry moves.

    SIX regimes carry a reason on this fixture, not four — measured 2026-09-08 before any of this
    plan landed. `structural_break` and `naics_transition` draw no target here (the fixture carries
    2023 alone, and their windows are 2020-2022), so the harness's selector-returned-nothing branch
    already gave each of them a reason and this plan does not touch either. V4's "exactly four" is
    about which reasons CHANGE, so this asserts the four individually and pins the other two as
    untouched rather than asserting a set of four that was never four.
    """
    regimes = fixture_run.manifest["regimes"]
    for name in ("rolling_origin", "cbp_size_gaps"):
        assert "2026-09-08" in regimes[name]["reason"], name
    for name in ("retrospective_smoothing", "preliminary_to_final_vintage"):
        assert "excluded by `validation.include_" in regimes[name]["reason"], name
    for name in ("structural_break", "naics_transition"):
        assert (
            "no eligible target" in regimes[name]["reason"]
            or "carries no population" in (regimes[name]["reason"])
        ), name
    with_reason = {name for name, entry in regimes.items() if entry.get("reason")}
    assert with_reason == {
        "rolling_origin",
        "cbp_size_gaps",
        "retrospective_smoothing",
        "preliminary_to_final_vintage",
        "structural_break",
        "naics_transition",
    }


def test_the_harness_hands_the_baselines_the_masked_bounds_it_solved(monkeypatch):
    """D-087: every scoring call to `run_baselines` carries the MASKED system's bounds.

    A bound-blind harness would score estimates production rescales before release, and bounds
    solved from the unmasked layer would leak the answer: there every pseudo-masked cell is still
    observed, pinned to its published value. This fixture layer carries no parent margin, so each
    cell the mask hid must reach `run_baselines` unbounded above.
    """
    seen: list[tuple[HarmonizedData, object]] = []
    real = harness.run_baselines

    def spy(data, config, **kwargs):
        seen.append((data, kwargs.get("bounds")))
        return real(data, config, **kwargs)

    monkeypatch.setattr(harness, "run_baselines", spy)
    layer = HarmonizedData.load(FIXTURE)
    run_pseudo_suppression(layer, REGISTRY[:1], _fixture_config())
    assert seen

    state = pl.col("area_type") == "state"
    key = ["state_fips", "reference_month"]
    visible = layer.qcew_monthly.filter(state & (pl.col("observation_status") != "suppressed"))
    hidden_cells = 0
    for masked, bounds in seen:
        assert isinstance(bounds, Bounds) and bounds.lower
        hidden = masked.qcew_monthly.filter(
            state & (pl.col("observation_status") == "suppressed")
        ).join(visible.select(key), on=key, how="semi")
        for fips, month in hidden.select(key).iter_rows():
            [cell] = [c for c in bounds.lower if c.startswith(f"state_total|{fips}|{month}|")]
            assert bounds.upper[cell] is None
            hidden_cells += 1
    assert hidden_cells
