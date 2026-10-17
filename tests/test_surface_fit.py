"""Surface fit tests (design §7). Sampling is small and seeded; see FAST_CONFIG."""

import hashlib
import subprocess
import sys
from contextlib import nullcontext
from dataclasses import replace
from types import SimpleNamespace
from unittest import mock

import numpy as np
import pandas as pd
import pandera.errors
import pymc as pm
import pytest
import xarray as xr

from genomeos.observations.schema import OBSERVATIONS_SCHEMA
from genomeos.surfaces.fit import (
    EARTH_RADIUS_KM,
    MAX_LENGTHSCALE_ANCHOR_KM,
    ConvergenceError,
    FitConfig,
    derive_lengthscale_prior,
    fit_surface,
    h3_inducing_points,
    inducing_points,
    load_fit,
    save_fit,
    to_unit_sphere,
)
from genomeos.surfaces.footprint import ObservationSupportMetadata, uniform_area_disc_support
from genomeos.surfaces.observation import SurveyQueries
from genomeos.surfaces.prior import PRIOR_DRAWS
from genomeos.validation.predictive import CountPredictive, predictive_diagnostics

# Enough draws to actually converge: fit_surface now refuses a fit that has not mixed (§12),
# so a too-short chain is a failure rather than a fast approximation. numpyro keeps it quick.
FAST_CONFIG = FitConfig(draws=800, tune=1000, chains=4)

HBS = "chr11-5227002-T-A"


def _observations(
    n: int = 70,
    beta_design: float = -1.0,
    designs: tuple[str, ...] = ("population_random", "healthy_reference"),
    concentration: float = 40.0,
    seed: int = 7,
) -> pd.DataFrame:
    """Synthetic observations with a known east-west cline and a known design effect.

    The first entry of `designs` is the reference level, so its true offset is 0.
    """
    rng = np.random.default_rng(seed)
    lon = rng.uniform(-10.0, 10.0, n)
    lat = rng.uniform(-10.0, 10.0, n)
    design_idx = rng.integers(0, len(designs), n)
    logit = -1.5 + 0.15 * lon + beta_design * (design_idx != 0)
    p = 1.0 / (1.0 + np.exp(-logit))
    an = np.full(n, 200)
    # Overdispersed, like the real corpus: two surveys of one locality differ by more than
    # binomial sampling error, because they differ in method, sub-population and decade. Exactly
    # binomial fixtures would also leave the beta-binomial concentration unidentified at the top
    # end, so the fixture matches both reality and the default likelihood.
    ac = rng.binomial(an, rng.beta(p * concentration, (1.0 - p) * concentration))

    return OBSERVATIONS_SCHEMA.validate(
        pd.DataFrame(
            {
                "variant_id": HBS,
                "rsid": "rs334",
                "population_id": [f"pop-{i:03d}" for i in range(n)],
                "lat": lat,
                "lon": lon,
                "radius_km": 25.0,
                "ac": ac,
                "an": an,
                "source_record_id": [f"synthetic:{i}" for i in range(n)],
                "source": "synthetic",
                "assay": "genotype",
                "date_lower": 0,
                "date_upper": 0,
                "sampling_design": [designs[i] for i in design_idx],
                "disease_ascertainment_excluded": [bool(i != 0) for i in design_idx],
                "cohort_id": [f"cohort-{i % 4}" for i in range(n)],
                "ingest_version": "test",
            }
        )
    )


@pytest.fixture(scope="module")
def fit():
    return fit_surface(_observations(), FAST_CONFIG)


def test_fit_recovers_the_design_effect_when_designs_contrast(fit):
    """β_design is identified by contrast between designs — the reason MAP surveys are in P1."""
    effects = fit.design_effects()
    row = effects.loc[effects["sampling_design"] == "healthy_reference"].iloc[0]
    assert row["q025"] < -1.0 < row["q975"], f"true -1.0 outside CI: {row.to_dict()}"


def test_fit_records_which_designs_were_applied(fit):
    assert fit.beta_design_applied is True
    assert set(fit.design_effects()["sampling_design"]) == {"healthy_reference"}


def test_fit_records_actual_prediction_metadata(fit):
    metadata = fit.prediction_metadata
    assert metadata.convention == "new_cohort_count_v1"
    assert metadata.fitted_designs == ("population_random", "healthy_reference")
    assert metadata.training_cohort_ids == ("cohort-0", "cohort-1", "cohort-2", "cohort-3")
    assert metadata.cohort_effect_applied is True
    assert metadata.nugget_applied is False
    assert metadata.likelihood == "beta_binomial"


def test_predictions_carry_uncertainty_and_lie_on_the_frequency_scale(fit):
    pred = fit.predict(lat=[0.0, 5.0], lon=[-8.0, 8.0])
    assert list(pred.columns) == [
        "lat", "lon", "post_median", "post_mean", "post_sd", "q025", "q975", "q25", "q75",
    ]
    for column in ("post_median", "post_mean"):
        assert ((pred[column] > 0) & (pred[column] < 1)).all()
    assert (pred["post_sd"] > 0).all()
    assert (pred["q025"] <= pred["q25"]).all()
    assert (pred["q25"] <= pred["post_median"]).all()
    assert (pred["post_median"] <= pred["q75"]).all()
    assert (pred["q75"] <= pred["q975"]).all()


def _assert_pointwise_prior_protocol(fit):
    query = np.array([[9.0, 0.0], [20.0, 78.0], [-4.0, 22.0]])
    original = np.array(fit._model["x_pred"].get_value(), copy=True)
    sd = fit.prior_frequency_sd_at(query[:, 0], query[:, 1])
    with fit._model:
        pm.set_data({"x_pred": to_unit_sphere(query[:, 0], query[:, 1])})
        direct = pm.sample_prior_predictive(
            draws=PRIOR_DRAWS, var_names=["freq_pred"], random_seed=fit.config.seed
        )
        pm.set_data({"x_pred": original})
    expected = direct.prior["freq_pred"].to_numpy().reshape(PRIOR_DRAWS, 3).std(axis=0)
    np.testing.assert_allclose(sd, expected, rtol=0, atol=1e-10)
    np.testing.assert_allclose(fit.prior_frequency_sd_at(query[:, 0], query[:, 1]), sd, rtol=0, atol=1e-10)
    order = np.array([2, 0, 1])
    np.testing.assert_allclose(
        fit.prior_frequency_sd_at(query[order, 0], query[order, 1]), sd[order], rtol=0, atol=1e-10
    )
    split = np.concatenate(
        [
            fit.prior_frequency_sd_at(query[:1, 0], query[:1, 1]),
            fit.prior_frequency_sd_at(query[1:, 0], query[1:, 1]),
        ]
    )
    np.testing.assert_allclose(split, sd, rtol=0, atol=1e-10)


def test_hsgp_pointwise_prior_uses_the_retained_predictive_graph(fit):
    _assert_pointwise_prior_protocol(fit)


@pytest.mark.parametrize(
    "lat,lon,match",
    [
        ([], [], "nonempty"),
        ([0.0], [0.0, 1.0], "same"),
        ([[0.0]], [[0.0]], "one-dimensional"),
        ([np.nan], [0.0], "finite"),
        ([91.0], [0.0], "latitude"),
        ([0.0], [181.0], "longitude"),
        ([True], [False], "Boolean"),
    ],
)
def test_pointwise_prior_refuses_invalid_queries(fit, lat, lon, match):
    with pytest.raises(ValueError, match=match):
        fit.prior_frequency_sd_at(lat, lon)


def test_the_median_is_reported_because_the_mean_is_skewed_where_data_is_thin(fit):
    """Allele frequency is bounded and its posterior is right-tailed, so the mean runs high
    exactly where there is least data — the failure Piel et al. document in their appendix (#102).
    """
    pred = fit.predict(lat=[0.0], lon=[0.0])
    assert "post_median" in pred.columns
    assert "q25" in pred.columns and "q75" in pred.columns, "IQR needed for like-for-like §8 (#92)"


def test_prediction_follows_the_simulated_cline(fit):
    """The synthetic surface rises west-to-east; the fit must reproduce that ordering."""
    pred = fit.predict(lat=[0.0, 0.0], lon=[-8.0, 8.0])
    assert pred["post_median"].iloc[0] < pred["post_median"].iloc[1]


def test_fit_is_deterministic_given_the_same_seed():
    obs = _observations()
    a = fit_surface(obs, FAST_CONFIG).design_effects()["mean"].to_numpy()
    b = fit_surface(obs, FAST_CONFIG).design_effects()["mean"].to_numpy()
    assert np.allclose(a, b), "same (data, config, seed) must give the same fit (§5)"


def test_single_design_omits_beta_design_rather_than_pretending_to_estimate_it():
    """With one design there is no contrast, so β_design is unidentifiable (§7.1a)."""
    obs = _observations(designs=("population_random",))
    fit = fit_surface(obs, replace(FAST_CONFIG, reference_design="healthy_reference"))
    assert fit.beta_design_applied is False
    assert fit.design_effects().empty
    assert fit.prediction_metadata.fitted_designs == ("population_random",)


def test_beta_binomial_likelihood_is_selectable():
    """Overdispersion relative to binomial is a documented failure mode here (#83)."""
    obs = _observations()
    fit = fit_surface(obs, FitConfig(draws=800, tune=1000, chains=4, likelihood="beta_binomial"))
    assert fit.config.likelihood == "beta_binomial"
    assert (fit.predict(lat=[0.0], lon=[0.0])["post_sd"] > 0).all()


def test_more_than_one_variant_is_refused():
    """Surfaces are fitted per variant (§7); a mixed frame is a caller error, not a merge."""
    first = _observations(n=20)
    second = _observations(n=20)
    second["source_record_id"] = "synthetic-second:" + second.index.astype(str)
    obs = pd.concat([first, second], ignore_index=True)
    obs.loc[obs.index[:20], "variant_id"] = "chr7-117559590-ATCT-A"
    with pytest.raises(ValueError, match="exactly one variant"):
        fit_surface(obs, FAST_CONFIG)


def test_an_invalid_observation_frame_is_refused():
    obs = _observations(n=20)
    obs.loc[obs.index[0], "sampling_design"] = "unknown"
    with pytest.raises(pandera.errors.SchemaError):
        fit_surface(obs, FAST_CONFIG)


def test_unknown_likelihood_is_refused():
    with pytest.raises(ValueError, match="likelihood"):
        fit_surface(_observations(n=20), FitConfig(likelihood="poisson"))


def test_a_fit_that_has_not_converged_is_refused_not_published():
    """§12: a variant whose fit does not converge is excluded from the surface set.

    A non-converged chain produces a confident-looking map that nothing downstream can
    distinguish from a good one, so this has to fail loudly at the source.
    """
    with pytest.raises(ConvergenceError, match="did not converge"):
        fit_surface(_observations(n=30), FitConfig(draws=5, tune=5, chains=4))


def test_the_binomial_likelihood_remains_selectable():
    """Beta-binomial is the default, but the binomial §7 specifies must stay reachable (#83)."""
    assert FitConfig().likelihood == "beta_binomial"
    assert FitConfig(likelihood="binomial").likelihood == "binomial"


# --- inducing-point approximation (#103): degrees of freedom where the data is ---


def test_inducing_points_lie_on_the_sphere_and_follow_the_data():
    """Centroids are re-projected: the mean of points on a sphere sits inside it."""
    observations = _observations(n=120)
    x = to_unit_sphere(observations["lat"], observations["lon"])
    points = inducing_points(x, 30, seed=42)
    assert len(points) <= 30
    assert np.allclose(np.linalg.norm(points, axis=1), 1.0)


def test_inducing_placement_is_deterministic_given_the_seed():
    observations = _observations(n=120)
    x = to_unit_sphere(observations["lat"], observations["lon"])
    assert np.allclose(inducing_points(x, 25, seed=7), inducing_points(x, 25, seed=7))


@pytest.mark.parametrize("placement", ["h3", "kmeans"])
def test_the_inducing_approximation_fits_and_predicts(placement):
    observations = _observations(n=70)
    context = (
        pytest.warns(UserWarning, match=r"inducing points are .*They are redundant")
        if placement == "h3"
        else nullcontext()
    )
    with context:
        fit = fit_surface(
            observations,
            FitConfig(
                draws=400,
                tune=800,
                chains=4,
                approximation="inducing",
                inducing_placement=placement,
                n_inducing=40,
            ),
        )
    pred = fit.predict(lat=[0.0, 0.0], lon=[-8.0, 8.0])
    assert ((pred["post_median"] > 0) & (pred["post_median"] < 1)).all()
    assert pred["post_median"].iloc[0] < pred["post_median"].iloc[1], "must follow the cline"
    _assert_pointwise_prior_protocol(fit)


def test_inducing_resolution_is_set_by_point_count_not_by_a_global_grid():
    """The whole reason for this engine: HSGP resolves 2L/m everywhere, this follows density."""
    observations = _observations(n=200)
    x = to_unit_sphere(observations["lat"], observations["lon"])
    coarse = inducing_points(x, 20, seed=1)
    fine = inducing_points(x, 80, seed=1)
    assert len(fine) > len(coarse)


def test_an_unknown_approximation_is_refused():
    with pytest.raises(ValueError, match="approximation"):
        FitConfig(approximation="kriging")


def test_too_few_inducing_points_is_refused():
    with pytest.raises(ValueError, match="n_inducing"):
        FitConfig(n_inducing=1)


# --- H3 geodesic placement ---


def test_h3_inducing_points_cover_the_observations_not_an_arbitrary_index_block():
    """Selecting by H3 index order once put every point in the Arctic, 8,800 km from the data.

    Uniform spacing is necessary and nowhere near sufficient; coverage is the real test.
    """
    observations = _observations(n=120)
    lat = observations["lat"].to_numpy()
    lon = observations["lon"].to_numpy()
    points = h3_inducing_points(lat, lon, 200, reach_km=1500.0)

    degrees = np.degrees(
        np.column_stack([np.arcsin(points[:, 2]), np.arctan2(points[:, 1], points[:, 0])])
    )
    assert degrees[:, 0].min() <= lat.min() + 15
    assert degrees[:, 0].max() >= lat.max() - 15
    assert np.allclose(np.linalg.norm(points, axis=1), 1.0), "must lie on the sphere surface"


def test_h3_placement_is_deterministic_and_needs_no_seed():
    observations = _observations(n=100)
    lat, lon = observations["lat"].to_numpy(), observations["lon"].to_numpy()
    first = h3_inducing_points(lat, lon, 120, reach_km=1500.0)
    second = h3_inducing_points(lat, lon, 120, reach_km=1500.0)
    assert np.array_equal(first, second)


def _collocated_geometry() -> tuple[np.ndarray, np.ndarray, list[str]]:
    """Observations on 61 resolution-1 cell centres: the #280 geometry.

    Each centre is also the centre of a resolution-4 candidate, so 61 candidates sit at 0 to
    ~2.5e-12 km from an observation. With a budget of 16 the choice among them is decided by
    whatever breaks that tie. Returns the collocated resolution-4 cells alongside.
    """
    import h3

    cells = sorted(h3.grid_disk(h3.latlng_to_cell(5.0, 20.0, 1), 4))
    centres = np.array([h3.cell_to_latlng(cell) for cell in cells])
    collocated = sorted(h3.cell_to_center_child(cell, 4) for cell in cells)
    return centres[:, 0], centres[:, 1], collocated


def _as_cells(points: np.ndarray, resolution: int = 4) -> list[str]:
    import h3

    lat = np.degrees(np.arcsin(np.clip(points[:, 2], -1.0, 1.0)))
    lon = np.degrees(np.arctan2(points[:, 1], points[:, 0]))
    return [h3.latlng_to_cell(float(a), float(o), resolution) for a, o in zip(lat, lon, strict=True)]


def _min_spacing_km(cells: list[str]) -> float:
    import h3

    centres = np.array([h3.cell_to_latlng(cell) for cell in cells])
    points = to_unit_sphere(centres[:, 0], centres[:, 1])
    gaps = np.arccos(np.clip(points @ points.T, -1.0, 1.0)) + np.diag(np.full(len(points), np.inf))
    return float(gaps.min()) * EARTH_RADIUS_KM


def test_tied_candidates_beyond_the_budget_stay_collocated_with_the_data():
    """Settling the tie must not trade away coverage: every point chosen is still on a site."""
    lat, lon, collocated = _collocated_geometry()
    chosen = _as_cells(h3_inducing_points(lat, lon, 16, reach_km=1500.0))
    assert len(chosen) == len(set(chosen)) == 16
    assert set(chosen) <= set(collocated)


@pytest.mark.parametrize("noise_seed", [0, 1, 2, 3])
def test_sub_micrometre_distance_noise_cannot_change_the_chosen_cells(monkeypatch, noise_seed):
    """#280: the same config, data and seed chose different bases on macOS and on Linux.

    The 61 collocated candidates differ only at ~1e-12 km, below what libm agrees on across
    platforms, so ranking on raw distance let float noise pick the 16. Perturbing every distance
    by up to 1e-10 km stands in for another platform's arithmetic; the chosen cells, and their
    order (which indexes the inducing field), must not move.
    """
    import genomeos.geo.h3util as h3util

    lat, lon, _ = _collocated_geometry()
    expected = h3_inducing_points(lat, lon, 16, reach_km=1500.0)

    exact = h3util._haversine_km
    rng = np.random.default_rng(noise_seed)

    def noisy(*args):
        distance = np.asarray(exact(*args), dtype=float)
        return distance + rng.uniform(-1e-10, 1e-10, size=distance.shape)

    monkeypatch.setattr(h3util, "_haversine_km", noisy)
    assert np.array_equal(h3_inducing_points(lat, lon, 16, reach_km=1500.0), expected)


def test_tied_candidates_are_chosen_for_spacing_not_by_index_order():
    """A tie settled by H3 index is the Arctic-block rule again, applied to a smaller set.

    Index order is a property of the numbering, not of the ground, so its spacing is whatever it
    happens to be. Maximin picks each cell as far as possible from those already made; on this
    geometry that roughly doubles the index block's minimum spacing (1,562 vs 794 km).
    """
    lat, lon, collocated = _collocated_geometry()
    chosen = _as_cells(h3_inducing_points(lat, lon, 16, reach_km=1500.0))
    index_block = collocated[:16]
    assert set(chosen) != set(index_block)
    assert _min_spacing_km(chosen) > 1.5 * _min_spacing_km(index_block)


def test_clearly_nearer_candidates_are_kept_before_any_tie_is_settled():
    """With room for every collocated cell, all of them are kept: nearest-first still rules."""
    lat, lon, collocated = _collocated_geometry()
    chosen = _as_cells(h3_inducing_points(lat, lon, 70, reach_km=1500.0))
    assert len(chosen) == 70
    assert set(collocated) <= set(chosen)


def test_more_budget_buys_finer_spacing():
    observations = _observations(n=150)
    lat, lon = observations["lat"].to_numpy(), observations["lon"].to_numpy()
    assert len(h3_inducing_points(lat, lon, 300, 1500.0)) > len(
        h3_inducing_points(lat, lon, 80, 1500.0)
    )


def test_h3_is_the_default_placement():
    """It aligns with §6's artifact grid and does not depend on a seed."""
    assert FitConfig().inducing_placement == "h3"


def test_an_unknown_placement_is_refused():
    with pytest.raises(ValueError, match="inducing_placement"):
        FitConfig(inducing_placement="poisson-disc")


def test_too_many_inducing_points_for_the_data_is_refused():
    """M approaching N is not a sparse approximation, and it does not converge.

    M=800 against N=857 gave ESS 80 after 97 minutes of sampling; M=400 converges in minutes.
    """
    observations = _observations(n=50)
    with pytest.raises(ValueError, match="too close to the"):
        fit_surface(observations, FitConfig(approximation="inducing", n_inducing=45))


def test_a_saved_fit_predicts_identically_to_the_original(fit, tmp_path):
    """The point of persisting a fit is to avoid refitting, so the reloaded model has to give the
    same answer — a round trip that merely produces *plausible* predictions would silently change
    every figure and validation number made after it."""
    lat = np.array([9.0, 20.0, -4.0])
    lon = np.array([0.0, 78.0, 22.0])
    before = fit.predict(lat=lat, lon=lon)

    path = save_fit(fit, tmp_path / "surface.pkl")
    reloaded = load_fit(path)
    after = reloaded.predict(lat=lat, lon=lon)

    for column in ("post_median", "post_sd", "q025", "q975"):
        np.testing.assert_allclose(before[column], after[column])
    assert reloaded.correlation_range_km == fit.correlation_range_km
    np.testing.assert_allclose(
        reloaded.prior_frequency_sd_at(lat, lon),
        fit.prior_frequency_sd_at(lat, lon),
        rtol=0,
        atol=1e-10,
    )
    assert reloaded.design_levels == fit.design_levels


def test_footprint_metadata_survives_save_and_load(fit, tmp_path):
    metadata = ObservationSupportMetadata(
        convention="footprint_probability_mean_v1",
        weighting="population_weighted",
        location_model="independent_location_per_trial",
        support_version="reviewed-support-v7",
        points_per_observation=32,
    )
    footprint_fit = replace(fit, footprint_metadata=metadata)

    reloaded = load_fit(save_fit(footprint_fit, tmp_path / "footprint-surface.pkl"))

    assert reloaded.footprint_metadata == metadata


def test_owned_legacy_fit_is_reconstructed_without_refit_or_rewrite(fit, tmp_path):
    import cloudpickle

    legacy = SimpleNamespace(**fit.__dict__, prior_frequency_sd=9.9e99)
    path = tmp_path / "legacy.pkl"
    with path.open("wb") as stream:
        cloudpickle.dump({"format": 1, "fit": legacy}, stream)
    before_hash = hashlib.sha256(path.read_bytes()).hexdigest()
    query = np.array([[9.0, 0.0], [20.0, 78.0]])
    expected_post = fit.predict(query[:, 0], query[:, 1])
    expected_prior = fit.prior_frequency_sd_at(query[:, 0], query[:, 1])

    migrated = load_fit(path)

    assert hashlib.sha256(path.read_bytes()).hexdigest() == before_hash
    assert not hasattr(migrated, "prior_frequency_sd")
    np.testing.assert_allclose(
        migrated.predict(query[:, 0], query[:, 1])[["post_median", "post_sd"]],
        expected_post[["post_median", "post_sd"]],
    )
    np.testing.assert_allclose(
        migrated.prior_frequency_sd_at(query[:, 0], query[:, 1]),
        expected_prior,
        rtol=0,
        atol=1e-10,
    )


def test_legacy_fit_refuses_missing_fields_invalid_config_and_predictive_nodes(fit, tmp_path):
    import cloudpickle

    cases = []
    missing = fit.__dict__.copy()
    del missing["_scale"]
    cases.append((SimpleNamespace(**missing), "missing required fields"))
    cases.append((SimpleNamespace(**{**fit.__dict__, "config": "not-a-config"}), "configuration"))
    cases.append((SimpleNamespace(**{**fit.__dict__, "_model": pm.Model()}), "predictive nodes"))
    for index, (legacy, match) in enumerate(cases):
        path = tmp_path / f"invalid-{index}.pkl"
        with path.open("wb") as stream:
            cloudpickle.dump({"format": 1, "fit": legacy}, stream)
        with pytest.raises(ValueError, match=match):
            load_fit(path)


def test_boolean_fit_format_is_not_misread_as_legacy_format_one(fit, tmp_path):
    import cloudpickle

    path = tmp_path / "boolean-format.pkl"
    with path.open("wb") as stream:
        cloudpickle.dump({"format": True, "fit": fit}, stream)
    with pytest.raises(ValueError, match="supported format"):
        load_fit(path)
def test_observation_parameters_follow_real_posterior_ids_and_query_identity(fit):
    queries = SurveyQueries(
        observation_ids=("unseen-a", "unseen-b", "unseen-c"),
        cohort_ids=("new-shared", "new-shared", "new-other"),
        sampling_designs=("population_random", "healthy_reference", "healthy_reference"),
        lat=(0.0, 0.0, 5.0),
        lon=(-180.0, 180.0, 8.0),
    )
    parameters = fit.predict_new_cohort_parameters(queries)
    expected_ids = tuple(
        (int(chain), int(draw))
        for chain in sorted(fit.idata.posterior.coords["chain"].to_numpy())
        for draw in sorted(fit.idata.posterior.coords["draw"].to_numpy())
    )
    assert parameters.draw_ids == expected_ids

    order = (2, 0, 1)
    permuted_queries = SurveyQueries(
        observation_ids=tuple(queries.observation_ids[index] for index in order),
        cohort_ids=tuple(queries.cohort_ids[index] for index in order),
        sampling_designs=tuple(queries.sampling_designs[index] for index in order),
        lat=tuple(queries.lat[index] for index in order),
        lon=tuple(queries.lon[index] for index in order),
    )
    permuted = fit.predict_new_cohort_parameters(permuted_queries)
    inverse = [permuted.queries.observation_ids.index(value) for value in queries.observation_ids]
    assert permuted.draw_ids == parameters.draw_ids
    np.testing.assert_array_equal(parameters.mean_draws, permuted.mean_draws[:, inverse])
    np.testing.assert_array_equal(parameters.concentration, permuted.concentration[:, inverse])

    predictive = CountPredictive(
        parameters.mean_draws, concentration=parameters.concentration
    )
    diagnostics = predictive_diagnostics(predictive, ac=[0, 1, 2], an=[10, 12, 20])
    assert not diagnostics.isna().any().any()
    assert np.isfinite(diagnostics.select_dtypes(include="number").to_numpy()).all()


def test_new_observation_parameters_survive_save_load_exactly(fit, tmp_path):
    queries = SurveyQueries(
        observation_ids=("cache-a", "cache-b"),
        cohort_ids=("new-cache", "new-cache"),
        sampling_designs=("population_random", "healthy_reference"),
        lat=(0.0, 5.0),
        lon=(-8.0, 8.0),
    )
    before = fit.predict_new_cohort_parameters(queries)
    live_values = fit.idata.posterior["concentration"].data
    live_dtype = fit.idata.posterior["concentration"].dtype
    groups = fit.idata.groups
    save_fit(fit, tmp_path / "observation-surface.pkl")
    assert fit.idata.posterior["concentration"].data is live_values
    assert fit.idata.posterior["concentration"].dtype == live_dtype

    reloaded = load_fit(tmp_path / "observation-surface.pkl")
    assert reloaded.idata.groups == groups
    for original_node in fit.idata.subtree:
        xr.testing.assert_identical(
            original_node.dataset, reloaded.idata[original_node.path].dataset
        )
    np.savez(
        tmp_path / "before.npz",
        mean_draws=before.mean_draws,
        concentration=before.concentration,
        draw_ids=np.asarray(before.draw_ids, dtype=np.int64),
    )
    script = """
import sys
from pathlib import Path
import numpy as np
from genomeos.surfaces.fit import load_fit
from genomeos.surfaces.observation import ObservationModelMetadata, SurveyQueries

directory = Path(sys.argv[1])
fitted = load_fit(directory / "observation-surface.pkl")
expected_metadata = ObservationModelMetadata(
    convention="new_cohort_count_v1",
    fitted_designs=("population_random", "healthy_reference"),
    training_cohort_ids=("cohort-0", "cohort-1", "cohort-2", "cohort-3"),
    cohort_effect_applied=True,
    nugget_applied=False,
    likelihood="beta_binomial",
)
assert fitted.prediction_metadata == expected_metadata
queries = SurveyQueries(
    observation_ids=("cache-a", "cache-b"),
    cohort_ids=("new-cache", "new-cache"),
    sampling_designs=("population_random", "healthy_reference"),
    lat=(0.0, 5.0),
    lon=(-8.0, 8.0),
)
parameters = fitted.predict_new_cohort_parameters(queries)
np.savez(
    directory / "after.npz",
    mean_draws=parameters.mean_draws,
    concentration=parameters.concentration,
    draw_ids=np.asarray(parameters.draw_ids, dtype=np.int64),
)
"""
    subprocess.run([sys.executable, "-c", script, str(tmp_path)], check=True)
    after = np.load(tmp_path / "after.npz")

    np.testing.assert_array_equal(after["draw_ids"], np.asarray(before.draw_ids))
    np.testing.assert_array_equal(after["mean_draws"], before.mean_draws)
    np.testing.assert_array_equal(after["concentration"], before.concentration)


def test_save_fit_materializes_legacy_inference_data_containers(fit, tmp_path):
    class LegacyInferenceData:
        def __init__(self, posterior):
            self.posterior = posterior

        def copy(self):
            return LegacyInferenceData(self.posterior.copy(deep=True))

        def groups(self):
            return ("posterior",)

    posterior = xr.Dataset(
        {"parameter": (("chain", "draw"), np.array([[1.25, 2.5]]))},
        coords={"chain": [7], "draw": [11, 13]},
        attrs={"source": "controlled legacy container"},
    )
    legacy_fit = replace(fit, idata=LegacyInferenceData(posterior))
    reloaded = load_fit(save_fit(legacy_fit, tmp_path / "legacy-container.pkl"))

    xr.testing.assert_identical(reloaded.idata.posterior, posterior)
def test_loading_something_that_is_not_a_fit_is_refused(tmp_path):
    """A cache file is environment-coupled and can be stale after a PyMC upgrade. Refusing beats
    returning a half-initialised object that fails later, somewhere less obvious."""
    import cloudpickle

    path = tmp_path / "wrong.pkl"
    with path.open("wb") as stream:
        cloudpickle.dump({"format": 999, "fit": None}, stream)
    with pytest.raises(ValueError, match="not a surface fit"):
        load_fit(path)


def test_predict_draws_exposes_the_samples_behind_the_summary(fit):
    """The burden path sums over cells within a draw, so it needs draws, not summaries (#112).

    Also pins the contract that the draws and the summary describe the same thing: if these
    diverge, national totals and the map would be telling different stories about one fit.
    """
    lat = np.array([9.0, 20.0, -4.0])
    lon = np.array([0.0, 78.0, 22.0])
    draws = fit.predict_draws(lat=lat, lon=lon)

    assert draws.ndim == 2
    assert draws.shape[1] == len(lat)
    assert ((draws >= 0.0) & (draws <= 1.0)).all(), "allele frequency must lie in [0, 1]"
    np.testing.assert_allclose(
        np.median(draws, axis=0), fit.predict(lat=lat, lon=lon)["post_median"], rtol=1e-6
    )


def test_predict_draws_refuses_mismatched_coordinates(fit):
    with pytest.raises(ValueError, match="same length"):
        fit.predict_draws(lat=np.array([1.0, 2.0]), lon=np.array([1.0]))


def test_a_convergence_failure_names_the_parameter_that_starved():
    """Which parameter failed changes the diagnosis, so the message must say.

    A starved `concentration` or `cohort_sd` is a reparameterisation problem and cheap to fix; a
    starved `z_u` is the spatial field itself failing. Without the name every failure reads as
    "buy more draws", which sent one investigation down the wrong path entirely (#111).
    """
    with pytest.raises(ConvergenceError, match=r"worst: \w+"):
        fit_surface(_observations(n=30), FitConfig(draws=5, tune=5, chains=4))


def test_the_lengthscale_prior_is_configurable_and_defaults_unchanged():
    """Tightening this prior is a claim about the biology, so it must be made per variant.

    The default spans roughly 220-3,400 km at 95%. The top of that range describes a field that
    is nearly constant globally, which is indistinguishable from `intercept` — a ridge the chains
    can slide along rather than mix, which is what G6PD does (#116). Leaving the default alone
    matters: HbS identifies its range from the data and needs no help.
    """
    assert FitConfig().lengthscale_sigma == 0.7
    assert FitConfig(lengthscale_sigma=0.4).lengthscale_sigma == 0.4
    with pytest.raises(ValueError, match="lengthscale_sigma"):
        FitConfig(lengthscale_sigma=0.0)


def test_a_cohort_per_observation_is_not_estimated_as_a_cohort_effect():
    """One cohort level per observation is not the study-level effect §7.1d wants.

    It is an observation-level overdispersion term, competing with the beta-binomial
    `concentration` to explain the same residual and not jointly identifiable with it. Worse, an
    unidentified per-observation term is free to absorb the spatial signal the GP exists to
    explain. Screening HLA alleles from AFND — which publishes one study per population, so
    `cohort_id == population_id` — `cohort_sd` was the worst-mixing parameter in four of five
    convergence failures.
    """
    obs = _observations(n=30)
    obs["cohort_id"] = [f"c{i}" for i in range(len(obs))]  # one cohort per observation
    with pytest.warns(UserWarning, match="within-cohort replication"):
        fit = fit_surface(obs, FitConfig(draws=400, tune=600, chains=4))
    assert fit.beta_cohort_applied is False
    assert "cohort_sd" not in fit.idata.posterior
    assert fit.prediction_metadata.cohort_effect_applied is False
    assert fit.prediction_metadata.training_cohort_ids == tuple(sorted(obs["cohort_id"]))


def test_grouped_cohorts_are_still_estimated():
    """The term is dropped only when it cannot be identified, not in general: MAP data has 419
    cohorts for 1,071 surveys and the effect is real there."""
    fit = fit_surface(_observations(n=30), FAST_CONFIG)
    assert fit.beta_cohort_applied is True
    assert "cohort_sd" in fit.idata.posterior


def test_the_lengthscale_prior_is_derived_from_the_data_by_default():
    """Hand-setting this does not survive 767 alleles (#122).

    The anchors come from where the observations are: three nearest-neighbour spacings below
    (fewer cannot show correlation decaying at all) and the domain extent over 2*K above (a
    Matern-5/2 decorrelates at ~2*rho, so this asks the field to vary at least K times across the
    data). Verified against real corpora: HbS 680 km and G6PD 547 km fall inside their derived
    priors, while the degenerate HLA fits at 3,143 and 4,111 km fall above theirs.
    """
    assert FitConfig().lengthscale_prior == "derived"
    obs = _observations(n=40)
    mu, sigma, low, high = derive_lengthscale_prior(obs["lat"].to_numpy(), obs["lon"].to_numpy())
    assert 0.0 < low < high, "the anchors must bracket, in order"
    assert sigma > 0.0
    median_km = float(np.exp(mu) * EARTH_RADIUS_KM)
    assert low < median_km < high, "the prior centres between its own anchors"


def test_sparse_data_cannot_drive_the_prior_past_a_physical_ceiling():
    """The anchors are read off the data, and sparse data misreads them.

    Five points spread across 30 degrees put the median nearest-neighbour spacing near 1,500 km,
    which drove an earlier version of this to a 47,000 km range — longer than the planet.
    `MIN_OBSERVATIONS` in the batch is 5, so that case is reachable rather than hypothetical.
    """
    lat = np.array([0.0, 5.0, 10.0, -5.0, 20.0])
    lon = np.array([0.0, 5.0, -10.0, 15.0, 30.0])
    _, _, low, high = derive_lengthscale_prior(lat, lon)
    assert high <= MAX_LENGTHSCALE_ANCHOR_KM
    assert low < high


def test_a_fixed_prior_remains_available_for_reproducing_a_published_surface():
    """An artifact is only interpretable against the prior that produced it, and a derived prior
    differs per variant — so the fixed path has to stay reachable."""
    config = FitConfig(lengthscale_prior="fixed", lengthscale_mu=-2.0, lengthscale_sigma=0.4)
    assert config.lengthscale_prior == "fixed"
    with pytest.raises(ValueError, match="unknown lengthscale_prior"):
        FitConfig(lengthscale_prior="vibes")


def test_the_fit_records_the_prior_it_was_given(fit):
    """A fitted range means nothing without the prior behind it."""
    low, high = fit.lengthscale_prior_km
    assert low < fit.correlation_range_km < high or np.isnan(low)
def test_target_accept_is_configurable_and_defaults_unchanged():
    """Raising it is opt-in, so the surfaces already published are untouched (#111).

    Cross-validation folds need a smaller step size than the full fit does — four of ten missed
    the ESS floor of 200, at 61-143 — but a fold's need is not a reason to resample every
    variant. The default asserted here is PyMC's own, so changing it later has to be deliberate
    rather than a side effect.
    """
    assert FitConfig().target_accept == 0.8
    assert FitConfig(target_accept=0.95).target_accept == 0.95


@pytest.mark.parametrize("bad", [0.0, 1.0, -0.5, 1.2])
def test_a_target_accept_outside_the_unit_interval_is_refused(bad):
    with pytest.raises(ValueError, match="target_accept"):
        FitConfig(target_accept=bad)


def test_the_configured_sampler_options_are_the_ones_passed_to_pm_sample():
    """Guards *our* side of the call only, and deliberately claims nothing more.

    Mocking `pm.sample` can confirm what this module passes; it cannot confirm what PyMC then
    does with it, and it would keep passing if PyMC changed underneath. That distinction is not
    academic — reasoning from PyMC's source instead of measuring is exactly what produced the
    wrong `chain_method` diagnosis in #120. `scripts/env_report.py` is what answers the other
    half, by spying on `sample_jax_nuts` in whatever environment you actually have.

    So: `nuts` is asserted because it is the non-deprecated channel on the pinned 6.3.1, not
    because this test could tell if that stopped being true.
    """
    captured: dict[str, object] = {}

    class _Reached(RuntimeError):
        """Stops the fit as soon as the kwargs are in hand; sampling itself is not the point."""

    def _capture(**kwargs):
        captured.update(kwargs)
        raise _Reached

    with mock.patch("pymc.sample", side_effect=_capture), pytest.raises(_Reached):
        fit_surface(_observations(n=20), FitConfig(target_accept=0.95, draws=5, tune=5))

    assert captured["target_accept"] == 0.95
    assert captured["nuts"] == {"chain_method": "vectorized"}


def _footprint_support(observations, *, ids=None):
    return uniform_area_disc_support(
        tuple(observations["source_record_id"] if ids is None else ids),
        observations["lat"].to_numpy(),
        observations["lon"].to_numpy(),
        observations["radius_km"].to_numpy(),
        radial_order=2,
        angular_order=4,
        support_version="synthetic-disc-v1",
    )


def test_fit_refuses_footprint_support_bound_to_a_different_row_order():
    observations = _observations(n=20)
    support = _footprint_support(
        observations,
        ids=tuple(reversed(observations["source_record_id"].tolist())),
    )

    with pytest.raises(ValueError, match="observation IDs.*row order"):
        fit_surface(
            observations,
            FitConfig(draws=5, tune=5, chains=2),
            observation_support=support,
        )


@pytest.mark.parametrize("approximation", ["hsgp", "inducing"])
def test_fit_builds_one_vectorized_footprint_graph_and_records_metadata(approximation):
    observations = _observations(n=20)
    support = _footprint_support(observations)
    posterior = xr.Dataset(
        {"lengthscale": (("chain", "draw"), np.array([[0.1]]))},
        coords={"chain": [0], "draw": [0]},
    )
    config = FitConfig(
        draws=5,
        tune=5,
        chains=2,
        approximation=approximation,
        inducing_placement="kmeans",
        n_inducing=5,
    )

    with (
        mock.patch("pymc.sample", return_value=SimpleNamespace(posterior=posterior)),
        mock.patch("genomeos.surfaces.fit._check_convergence"),
    ):
        fitted = fit_surface(observations, config, observation_support=support)

    assert fitted._model["x_obs"].get_value().shape == (20 * 8, 3)
    assert fitted._model["footprint_weights"].get_value().shape == (20, 8)
    assert fitted._model["p"].eval().shape == (20,)
    assert fitted.footprint_metadata == support.metadata


def test_point_fit_keeps_the_existing_observation_axis_and_no_footprint_metadata():
    observations = _observations(n=20)
    posterior = xr.Dataset(
        {"lengthscale": (("chain", "draw"), np.array([[0.1]]))},
        coords={"chain": [0], "draw": [0]},
    )

    with (
        mock.patch("pymc.sample", return_value=SimpleNamespace(posterior=posterior)),
        mock.patch("genomeos.surfaces.fit._check_convergence"),
    ):
        fitted = fit_surface(observations, FitConfig(draws=5, tune=5, chains=2))

    assert fitted._model["x_obs"].get_value().shape == (20, 3)
    assert "footprint_weights" not in fitted._model.named_vars
    assert fitted.footprint_metadata is None


def test_a_non_default_target_accept_still_produces_a_fit():
    """The external numpyro path must accept the argument, not just PyMC's own sampler.

    Deliberately the known-good `FAST_CONFIG` with one field changed, so a failure here is the
    argument and not a sampling budget that was never enough in the first place.
    """
    config = replace(FAST_CONFIG, target_accept=0.95)
    fit = fit_surface(_observations(), config)
    assert fit.config.target_accept == 0.95
