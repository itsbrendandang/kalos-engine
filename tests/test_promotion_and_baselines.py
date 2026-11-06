"""The final wiring of the promotion verdict, plus three evaluation-hygiene
ports (leave-one-group-out, top-k overlap, the group-mean baseline floor).

PROMOTION. `check_gates` (kalos/core/gates.py) has existed since the lean-
engine port but had zero callers on the analysis path, and
`feasibility_cv_auc` (kalos/core/feasibility.py) had zero callers outside its
own tests - the fail-closed gate the codebase already built was never
actually asked anything. `_analyze` now computes the four gate metrics and
surfaces `check_gates`'s verdict as a top-level `promotion` block. This does
NOT change what the API accepts: the verdict is reported, never enforced -
gating uploads on it would be a product decision this change deliberately
does not make.

THE THREE PORTS (see `kalos/core/evaluation.py`'s docstrings for the full
case each makes):

  * `logo_report` - leave-one-group-out, the harder generalization question
    grouped K-fold does not ask. On the owner's real clone-selection data
    LOSO Spearman was -0.12 while a shuffled 5-fold read 0.91 on the same
    model.
  * `top_k_overlap` - "which N recipes do I advance", which Spearman can
    obscure on a zero-inflated target.
  * `group_mean_baseline_spearman` - how much of the apparent CV signal is
    just the model recognizing which recipe a row belongs to. On the owner's
    real data this floor alone captured ~0.75 of a trained model's ~0.86
    headline Spearman.
"""
from __future__ import annotations

import json

import numpy as np
import pandas as pd
import pytest

from kalos.core.evaluation import (
    group_mean_baseline_spearman,
    logo_report,
    top_k_overlap,
)
from kalos.core.feasibility import feasibility_cv_report

pytest.importorskip("fastapi")
pytest.importorskip("botorch")

from kalos.core.splits import assert_no_group_leakage, make_splits
from kalos.portal.analysis import (
    CV_TOPK_K,
    GROUP_MEAN_BASELINE_MIN_GROUPS,
    LOGO_MAX_GROUPS,
    _analyze,
)

# --- a known case: a calibrated coin, checked at the metric level ----------- #


def test_calibrated_coin_scores_brier_quarter_and_ece_near_zero():
    """A classifier that always predicts P(feasible)=0.5, scored against labels
    that are truly 50/50, is the textbook calibrated case: `(0.5 - label)^2` is
    exactly 0.25 whichever way the label falls, so Brier is EXACTLY 0.25
    regardless of the label draw - not just approximately, by construction.
    ECE should be near zero too: the single bin all the 0.5 predictions land in
    has an empirical accuracy near 0.5, matching its confidence.

    Exercised through `feasibility_cv_report` on data engineered so the fitted
    classifier's own out-of-fold predictions land near 0.5: two classes with
    heavily overlapping (indistinguishable) feature distributions, so logistic
    regression cannot separate them and predicts close to the base rate.
    """
    rng = np.random.default_rng(0)
    n = 2000
    X = rng.normal(0.0, 1.0, size=(n, 2))  # no relationship to the label at all
    y = (rng.random(n) < 0.5).astype(float)  # 0/1, exactly 50/50
    rep = feasibility_cv_report(X, y, threshold=0.5, n_splits=5, seed=0)  # feasible iff y == 1
    assert rep["evaluable"] is True
    assert rep["brier"] == pytest.approx(0.25, abs=0.02)
    assert rep["ece"] < 0.05


# --- logo_report: LOGO semantics --------------------------------------------- #


def _grouped_blobs(n_groups: int = 8, reps: int = 3, seed: int = 0):
    rng = np.random.default_rng(seed)
    f0 = rng.uniform(0.0, 4.0, n_groups)
    y_mu = 1.3 * f0
    X, y, g = [], [], []
    for k in range(n_groups):
        for _ in range(reps):
            X.append([f0[k] + rng.normal(0.0, 0.05)])
            y.append(y_mu[k] + rng.normal(0.0, 0.2))
            g.append(k)
    return np.array(X), np.array(y), np.array(g)


def test_logo_report_holds_out_each_group_exactly_once():
    """The defining property, checked directly against `make_splits` rather than
    trusted from the docstring: `GroupKFold(n_splits=n_groups)` must assign
    every group to exactly one fold's validation set, never split across two,
    and never omitted."""
    X, y, g = _grouped_blobs(n_groups=8, reps=3)
    splits = make_splits(X, y, g, n_splits=len(np.unique(g)))
    assert_no_group_leakage(splits, g)  # no group straddles train/val
    assert len(splits) == 8
    held_out_groups: list[int] = []
    for _tr, va in splits:
        held = set(g[va].tolist())
        assert len(held) == 1, "each fold must hold out exactly one group"
        held_out_groups.append(held.pop())
    assert sorted(held_out_groups) == list(range(8))  # every group, exactly once


def test_logo_report_matches_pooled_spearman_over_all_folds():
    X, y, g = _grouped_blobs(n_groups=8, reps=3)
    bounds = np.vstack([X.min(0), X.max(0)])
    rep = logo_report(X, y, g, bounds=bounds)
    assert rep["n_groups"] == 8
    assert rep["n_oof"] == 8 * 3  # every row comes back out-of-fold
    assert np.isfinite(rep["spearman"])
    assert rep["spearman"] > 0.5  # the underlying relationship is strong


def test_logo_report_declines_with_fewer_than_two_groups():
    X = np.zeros((3, 1))
    y = np.zeros(3)
    g = np.zeros(3)  # one group only
    rep = logo_report(X, y, g)
    assert np.isnan(rep["spearman"])
    assert rep["n_groups"] == 1
    assert rep["n_oof"] == 0


# --- top_k_overlap: hand-computed, ties, n < k ------------------------------- #


def test_top_k_overlap_hand_computed_example():
    """True ranking (descending): rows 0,1,2,3,4,5 = 5,4,3,2,1,0 -> true top-3 is
    rows {0,1,2}. Predicted ranking: rows 1,2,3 = 5,4,3 (highest) -> predicted
    top-3 is {1,2,3}. Intersection {1,2}, size 2, overlap = 2/3."""
    actual = np.array([5.0, 4.0, 3.0, 2.0, 1.0, 0.0])
    pred = np.array([1.0, 5.0, 4.0, 3.0, 2.0, 0.0])
    out = top_k_overlap(actual, pred, 3)
    assert out["evaluable"] is True
    assert out["overlap"] == pytest.approx(2.0 / 3.0)
    assert out["k"] == 3
    assert out["n"] == 6


def test_top_k_overlap_perfect_agreement_is_one():
    actual = np.array([1.0, 2.0, 3.0, 4.0, 5.0])
    out = top_k_overlap(actual, actual.copy(), 2)
    assert out["overlap"] == pytest.approx(1.0)


def test_top_k_overlap_ties_use_a_deterministic_stable_order():
    """All four values tied: `np.argsort(..., kind='stable')` on a constant
    array preserves input order, so the top-2 by both true and predicted rank
    is deterministically {0, 1} on both sides - full overlap, reproducibly,
    not an arbitrary re-roll each call."""
    actual = np.array([1.0, 1.0, 1.0, 1.0])
    pred = np.array([1.0, 1.0, 1.0, 1.0])
    out1 = top_k_overlap(actual, pred, 2)
    out2 = top_k_overlap(actual, pred, 2)
    assert out1 == out2  # deterministic
    assert out1["overlap"] == pytest.approx(1.0)


def test_top_k_overlap_n_less_than_k_is_unevaluable_not_misleading():
    out = top_k_overlap([1.0, 2.0], [1.0, 2.0], 5)
    assert out["evaluable"] is False
    assert np.isnan(out["overlap"])
    assert "k=5" in out["reason"]


def test_top_k_overlap_nonpositive_k_is_unevaluable():
    out = top_k_overlap([1.0, 2.0, 3.0], [1.0, 2.0, 3.0], 0)
    assert out["evaluable"] is False
    assert np.isnan(out["overlap"])


def test_top_k_overlap_mismatched_lengths_is_a_caller_error():
    with pytest.raises(ValueError):
        top_k_overlap([1.0, 2.0], [1.0, 2.0, 3.0], 2)


# --- group_mean_baseline_spearman -------------------------------------------- #


def test_group_mean_baseline_scores_high_when_group_identity_is_the_signal():
    """Construct data where the ONLY signal is which group a row belongs to
    (within-group noise is tiny relative to between-group spread): the
    leave-one-row-out group mean should predict the held-out row almost
    perfectly, so Spearman should be high."""
    rng = np.random.default_rng(0)
    n_groups = 10
    group_means = np.arange(n_groups) * 5.0  # widely separated
    groups = np.repeat(np.arange(n_groups), 4)
    y = group_means[groups] + rng.normal(0.0, 0.05, len(groups))
    out = group_mean_baseline_spearman(y, groups)
    assert out["evaluable"] is True
    assert out["spearman"] > 0.9
    assert out["n_evaluable"] == 40
    assert out["n_groups_used"] == 10


def test_group_mean_baseline_null_with_reason_when_every_group_is_a_singleton():
    """No group has a second row, so leave-one-row-out has nothing to average -
    "group-less" data in the sense that matters for this baseline."""
    rng = np.random.default_rng(1)
    y = rng.normal(size=20)
    groups = np.arange(20)  # every row its own group
    out = group_mean_baseline_spearman(y, groups)
    assert out["evaluable"] is False
    assert np.isnan(out["spearman"])
    assert out["n_evaluable"] == 0
    assert "singleton" in out["reason"]


def test_group_mean_baseline_length_mismatch_reports_rather_than_raises():
    """The one function in this trio that reports a caller's length mismatch as
    `evaluable=False` instead of raising, so a shape bug upstream cannot
    surface as an uncaught exception in an already fail-closed pipeline."""
    out = group_mean_baseline_spearman(np.zeros(5), np.zeros(4))
    assert out["evaluable"] is False
    assert "same length" in out["reason"]


# --- _analyze integration: fixtures ------------------------------------------ #


def _strong_signal_with_producers(n: int = 70, seed: int = 0, n_groups: int = 8) -> pd.DataFrame:
    """Two continuous features, a clean monotone relationship among producers,
    and a DETERMINISTIC (not random) feasibility rule (f0 > 2.0) so the
    feasibility classifier has real structure to learn, not noise to fail on.
    A declared, low-cardinality group column so `cv_logo` has something to run
    on without exceeding `LOGO_MAX_GROUPS`."""
    rng = np.random.default_rng(seed)
    f0 = rng.uniform(0.0, 5.0, n)
    f1 = rng.uniform(0.0, 5.0, n)
    feasible = f0 > 2.0
    y = np.where(feasible, 5.0 + 2.0 * f0 - 0.3 * f1 + rng.normal(0.0, 0.2, n), 0.0)
    return pd.DataFrame(
        {
            "campaign": rng.integers(0, n_groups, n).astype(str),
            "Methanol": f0.round(3),
            "pH": f1.round(3),
            "lipase_titer": y.round(3),
        }
    )


def _all_producer_sheet(n: int = 40, seed: int = 0) -> pd.DataFrame:
    """No non-producers anywhere: the feasibility classifier has a single class
    to learn from, so its AUC/Brier/ECE are all unmeasurable by construction -
    the sheet the fail-closed gate exists to catch."""
    rng = np.random.default_rng(seed)
    f0 = rng.uniform(0.0, 5.0, n)
    f1 = rng.uniform(0.0, 5.0, n)
    y = np.clip(5.0 + 2.0 * f0 - 0.3 * f1 + rng.normal(0.0, 0.3, n), 0.1, None)
    return pd.DataFrame(
        {
            "Methanol": f0.round(3),
            "pH": f1.round(3),
            "lipase_titer": y.round(3),
        }
    )


def _replicated_sheet_many_groups(n_groups: int = 20, reps: int = 3, seed: int = 0) -> pd.DataFrame:
    """More declared groups than `LOGO_MAX_GROUPS`, so `cv_logo` must decline
    rather than pay for 20 extra GP fits. Also replicated (multiple rows share
    a feature vector per group), which is what feeds `cv_group_mean_baseline`."""
    rng = np.random.default_rng(seed)
    f0 = rng.uniform(0.0, 4.0, n_groups)
    f1 = rng.uniform(0.0, 4.0, n_groups)
    mu = 1.5 * f0 - 0.8 * (f1 - 2.0) ** 2
    rows = []
    for k in range(n_groups):
        for _ in range(reps):
            rows.append(
                {
                    "campaign": f"camp{k}",
                    "Methanol": round(float(f0[k]), 3),
                    "pH": round(float(f1[k]), 3),
                    "lipase_titer": float(mu[k] + rng.normal(0.0, 0.3)),
                }
            )
    return pd.DataFrame(rows)


# --- _analyze: the promotion block ------------------------------------------- #


def test_promotion_block_appears_with_the_documented_shape():
    out = _analyze(_strong_signal_with_producers())
    promo = out["promotion"]
    assert set(promo) == {
        "passed", "failures", "metrics", "summary", "meaning", "not_judged", "status",
        "unmeasured",
    }
    assert isinstance(promo["passed"], bool)
    assert isinstance(promo["failures"], list)
    assert isinstance(promo["metrics"], dict)
    assert isinstance(promo["summary"], str)
    assert "not yet shown fit to promote" in promo["meaning"]
    assert "not a rejection" in promo["meaning"]


def test_promotion_passes_on_an_engineered_strong_signal_sheet_or_states_why_not():
    """Engineered for strong surrogate signal, a real feasibility split, and (if
    the CV happens to land calibrated) all four gates. GP-CV outcomes on real
    fits are not 100% deterministic across environments even with a fixed
    seed, so if this particular run does not clear every gate, the fallback
    assertion demands the failure list be EXACTLY the honest one - not a
    vacuous pass and not a mysterious one either."""
    out = _analyze(_strong_signal_with_producers())
    promo = out["promotion"]
    if promo["passed"]:
        assert promo["failures"] == []
        # Gates not judged (ECE below 20 runs, no group-mean floor) are appended.
        assert promo["summary"].startswith("ALL GATES PASSED")
        for key in ("surrogate_spearman", "feasibility_auc", "ece", "brier"):
            assert key in promo["metrics"]
            assert np.isfinite(promo["metrics"][key])
    else:
        # Every failure must be an honest, explained one: either a floor/ceiling
        # miss on a measured value, or an explicit "unmeasured" - never silent.
        for f in promo["failures"]:
            assert ("< min" in f) or ("> max" in f) or ("unmeasured" in f)


def test_promotion_fails_closed_with_unmeasured_wording_on_all_producer_sheet():
    out = _analyze(_all_producer_sheet())
    promo = out["promotion"]
    assert promo["passed"] is False
    # feasibility_auc/ece/brier are unmeasurable with zero non-producers;
    # surrogate_spearman is not affected by producer/non-producer status.
    unmeasured = {f for f in promo["failures"] if "unmeasured" in f}
    assert {"feasibility_auc missing/NaN (unmeasured)",
            "ece missing/NaN (unmeasured)",
            "brier missing/NaN (unmeasured)"} == unmeasured
    assert "feasibility_auc" not in promo["metrics"]
    assert "ece" not in promo["metrics"]
    assert "brier" not in promo["metrics"]
    assert "GATES FAILED" in promo["summary"]


def test_analyze_output_is_json_dumps_serializable():
    """The whole point of `None`-not-`NaN` throughout this response: it has to
    actually serialize. Checked on both the strong-signal sheet (promotion
    likely passes) and the all-producer sheet (promotion fails closed with
    NaN metrics that must become `None`/be omitted, never raw NaN)."""
    for out in (_analyze(_strong_signal_with_producers()), _analyze(_all_producer_sheet())):
        json.dumps(out)  # must not raise


# --- _analyze: cv_logo -------------------------------------------------------- #


def test_cv_logo_skipped_with_reason_on_recipe_hash_only_sheet():
    """No declared/detected group column: `cv_logo` must decline and say why,
    not silently run LOGO over the recipe-hash fallback (which would just be a
    costlier copy of `cv_spearman`)."""
    out = _analyze(_all_producer_sheet())
    logo = out["cv_logo"]
    assert logo["spearman"] is None
    assert logo["n_groups"] is None
    assert "recipe-hash" in logo["reason"]


def test_cv_logo_populated_when_a_group_column_exists_with_few_groups():
    # `campaign` is a declared group here. A name-matched column is only a group when
    # every level is one recipe (H1), so the group is declared in roles.
    from kalos.domains import ColumnRoles

    roles = ColumnRoles.from_dict({"target": "lipase_titer", "groups": "campaign"})
    out = _analyze(_strong_signal_with_producers(n_groups=8), roles=roles)
    logo = out["cv_logo"]
    assert logo["reason"] is None
    assert logo["n_groups"] == 8
    assert logo["n_oof"] is not None and logo["n_oof"] > 0
    assert logo["spearman"] is None or isinstance(logo["spearman"], float)


def test_cv_logo_declines_above_the_group_cap():
    out = _analyze(_replicated_sheet_many_groups(n_groups=20, reps=3))
    logo = out["cv_logo"]
    assert logo["spearman"] is None
    assert logo["n_groups"] == 20
    assert str(LOGO_MAX_GROUPS) in logo["reason"]


# --- _analyze: cv_topk and cv_group_mean_baseline ---------------------------- #


def test_cv_topk_reports_the_stated_k():
    out = _analyze(_strong_signal_with_producers())
    topk = out["cv_topk"]
    assert topk["k"] == CV_TOPK_K
    if topk["evaluable"]:
        assert 0.0 <= topk["overlap"] <= 1.0
    else:
        assert topk["overlap"] is None
        assert topk["reason"]


def test_cv_group_mean_baseline_null_with_reason_below_the_group_floor():
    """`_strong_signal_with_producers` has all-distinct feature rows (no two
    rows share a recipe), so every recipe-hash group is a singleton and there
    are zero groups with 2+ rows - well below `GROUP_MEAN_BASELINE_MIN_GROUPS`."""
    out = _analyze(_strong_signal_with_producers())
    gmb = out["cv_group_mean_baseline"]
    assert gmb["spearman"] is None
    assert gmb["interpretation"] is None
    assert str(GROUP_MEAN_BASELINE_MIN_GROUPS) in gmb["reason"]


def test_cv_group_mean_baseline_populated_on_a_replicated_sheet():
    out = _analyze(_replicated_sheet_many_groups(n_groups=20, reps=3))
    gmb = out["cv_group_mean_baseline"]
    assert gmb["spearman"] is not None
    assert 0.0 <= gmb["spearman"] <= 1.0
    assert gmb["n_groups_used"] >= GROUP_MEAN_BASELINE_MIN_GROUPS
    assert "recognizing recipes" in gmb["interpretation"]
    assert gmb["reason"] is None
