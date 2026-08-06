"""Tests for the latent-variable structural causal model (``causomic.causal_model``).

Covers the pure helpers (``ScaleStats``, scaling round-trips), graph/data/prior
parsing, and a small end-to-end Pyro fit + interventional query on simulated
data. Fits use a tiny number of SVI steps so the suite stays fast; assertions
target structure and shapes rather than exact learned values.
"""

import numpy as np
import pandas as pd
import pyro
import pytest
from y0.graph import NxMixedGraph

from causomic.causal_model import LVM
from causomic.causal_model.LVM import ScaleStats
from causomic.simulation import generate_structured_dag, simulate_data


# --------------------------------------------------------------------------- #
# Shared fixtures
# --------------------------------------------------------------------------- #
@pytest.fixture(scope="module")
def sim_problem():
    """A small ground-truth DAG plus a simulated wide data matrix."""
    gt, roles = generate_structured_dag(
        n_start=2, n_end=1, max_mediators=1, confounder_prob=0.0, seed=0
    )
    sim = simulate_data(gt, n=80, add_feature_var=False, add_error=True, seed=0, verbose=False)
    data = pd.DataFrame(sim["Protein_data"])
    data.columns = [str(c) for c in data.columns]
    graph = NxMixedGraph.from_edges(directed=[(str(u), str(v)) for u, v in gt.edges()])
    return {"graph": graph, "data": data, "roles": roles}


@pytest.fixture(scope="module")
def fitted_lvm(sim_problem):
    """An LVM fitted with a handful of SVI steps (Pyro backend)."""
    pyro.clear_param_store()
    lvm = LVM(backend="pyro", num_steps=15, verbose=False)
    lvm.fit(sim_problem["data"], sim_problem["graph"])
    return lvm


# --------------------------------------------------------------------------- #
# ScaleStats
# --------------------------------------------------------------------------- #
def test_scalestats_roundtrip():
    df = pd.DataFrame({"A": [1.0, 2.0, 3.0], "B": [10.0, 20.0, 30.0]})
    stats = ScaleStats(mean=df.mean(), scale=df.std())
    restored = stats.inverse(stats.transform(df))
    pd.testing.assert_frame_equal(restored, df, check_exact=False, rtol=1e-6)


def test_scalestats_zero_scale_uses_eps():
    # A constant column has scale 0; eps clipping must avoid division by zero.
    df = pd.DataFrame({"A": [5.0, 5.0, 5.0]})
    stats = ScaleStats(mean=df.mean(), scale=pd.Series({"A": 0.0}), eps=1e-6)
    z = stats.transform(df)
    assert np.isfinite(z.to_numpy()).all()


# --------------------------------------------------------------------------- #
# Construction / dunders
# --------------------------------------------------------------------------- #
def test_invalid_backend_raises():
    with pytest.raises(ValueError):
        LVM(backend="tensorflow")


def test_default_backend_is_pyro():
    assert LVM().backend == "pyro"


def test_init_defaults_and_repr():
    lvm = LVM(backend="pyro")
    assert lvm.model is None
    assert "not fitted" in str(lvm)
    assert "fitted=False" in repr(lvm)


def test_len_before_fit_raises():
    lvm = LVM(backend="pyro")
    with pytest.raises(ValueError):
        len(lvm)


# --------------------------------------------------------------------------- #
# Scaling helpers
# --------------------------------------------------------------------------- #
def test_fit_scaler_and_z_roundtrip(sim_problem):
    lvm = LVM(backend="pyro")
    lvm.fit_scaler(sim_problem["data"])
    z = lvm._to_z(sim_problem["data"])
    back = lvm._from_z(z)
    pd.testing.assert_frame_equal(back, sim_problem["data"], check_exact=False, rtol=1e-6)


def test_to_z_without_scaler_raises():
    lvm = LVM(backend="pyro")
    lvm.scaler = None
    with pytest.raises(RuntimeError):
        lvm._to_z(pd.DataFrame({"A": [1.0]}))


# --------------------------------------------------------------------------- #
# Graph parsing
# --------------------------------------------------------------------------- #
def test_parse_graph_identifies_roots_and_leaves():
    lvm = LVM(backend="pyro")
    lvm.causal_graph = NxMixedGraph.from_edges(directed=[("A", "B"), ("B", "C")])
    lvm.parse_graph()
    assert "A" in lvm.root_nodes
    assert "C" in lvm.end_nodes
    # B has a parent, so it is a descendant mapped to its parents
    assert "A" in lvm.descendant_nodes["B"]


# --------------------------------------------------------------------------- #
# End-to-end fit
# --------------------------------------------------------------------------- #
def test_fit_populates_model_state(fitted_lvm, sim_problem):
    assert fitted_lvm.model is not None
    assert len(fitted_lvm) == len(sim_problem["data"])
    assert fitted_lvm.root_nodes is not None
    assert fitted_lvm.descendant_nodes is not None
    # a guide is built and missing values are imputed during fitting
    assert fitted_lvm.guide is not None
    assert fitted_lvm.imputed_data is not None
    assert "fitted=True" in repr(fitted_lvm)


def test_intervention_produces_samples(fitted_lvm, sim_problem):
    roles = sim_problem["roles"]
    data = sim_problem["data"]
    target = str(roles["start"][0])
    outcome = [str(roles["end"][0])]
    baseline = float(data[target].mean())

    fitted_lvm.intervention(
        {target: baseline - 2.0},
        outcome_node=outcome,
        compare_value=baseline,
        predictive_samples=25,
    )
    assert fitted_lvm.intervention_samples is not None
    assert fitted_lvm.posterior_samples is not None
    assert np.asarray(fitted_lvm.intervention_samples).shape[0] > 0


# --------------------------------------------------------------------------- #
# Parameter-store isolation between fits
# --------------------------------------------------------------------------- #
def _subgraph_without(graph, node):
    """A strict subgraph of ``graph`` with every edge touching ``node`` removed."""
    kept = [(str(u), str(v)) for u, v in graph.directed.edges() if node not in (str(u), str(v))]
    nodes = sorted({name for edge in kept for name in edge})
    return NxMixedGraph.from_edges(directed=kept), nodes


def test_sequential_fits_do_not_share_parameters(sim_problem):
    """Two Pyro fits in one process must not collide in the global param store.

    AutoContinuous guides (``guide="lowrank"``) pack every latent into a single
    flat parameter named after the guide class. Without a per-fit namespace the
    second fit silently received the first fit's tensors and died unpacking them
    whenever the two models had different latent dimensions.
    """
    pyro.clear_param_store()
    data = sim_problem["data"]
    graph = sim_problem["graph"]
    small_graph, small_nodes = _subgraph_without(graph, str(sim_problem["roles"]["start"][-1]))
    assert len(small_nodes) < len(data.columns)  # so the latent dimensions differ

    first = LVM(backend="pyro", num_steps=5, verbose=False, guide="lowrank")
    first.fit(data, graph)

    second = LVM(backend="pyro", num_steps=5, verbose=False, guide="lowrank")
    second.fit(data[small_nodes], small_graph)

    assert first.guide_param_prefix != second.guide_param_prefix

    # The earlier fit is still usable: namespacing leaves its parameters in place.
    target = str(sim_problem["roles"]["start"][0])
    first.intervention(
        {target: -1.0},
        outcome_node=[str(sim_problem["roles"]["end"][0])],
        compare_value=0.0,
        predictive_samples=10,
    )
    assert np.isfinite(np.asarray(first.intervention_samples)).all()


def test_repeated_fits_are_independent(sim_problem):
    """Identical data and seed must give identical parameters, whatever ran before.

    Site-keyed guides (``normal``, ``delta``) never raised on a param-store
    collision -- the second fit just resumed from the first fit's optimum, which
    made results depend on fit order.
    """
    pyro.clear_param_store()
    kwargs = dict(backend="pyro", num_steps=8, seed=7, verbose=False, guide="normal")

    first = LVM(**kwargs)
    first.fit(sim_problem["data"], sim_problem["graph"])

    second = LVM(**kwargs)
    second.fit(sim_problem["data"], sim_problem["graph"])

    pd.testing.assert_frame_equal(first.coefficients, second.coefficients)


# --------------------------------------------------------------------------- #
# Stochastic-edge model variant
# --------------------------------------------------------------------------- #
def test_stochastic_edges_fit(sim_problem):
    pyro.clear_param_store()
    lvm = LVM(backend="pyro", num_steps=10, verbose=False, stochastic_edges=True)
    lvm.fit(sim_problem["data"], sim_problem["graph"])
    assert lvm.model is not None


# --------------------------------------------------------------------------- #
# NumPyro backend (fit only; the intervention path has known latent bugs)
# --------------------------------------------------------------------------- #
def test_numpyro_fit(sim_problem):
    lvm = LVM(
        backend="numpyro",
        num_samples=20,
        warmup_steps=20,
        num_chains=1,
        verbose=False,
    )
    lvm.fit(sim_problem["data"], sim_problem["graph"])
    assert lvm.model is not None
    assert len(lvm) == len(sim_problem["data"])
