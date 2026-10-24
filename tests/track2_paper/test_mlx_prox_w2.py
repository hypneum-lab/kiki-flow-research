import numpy as np
import pytest

from kiki_flow_core.track2_paper.mlx_wasserstein import mlx_prox_w2, mlx_sinkhorn_cost
from kiki_flow_core.wasserstein_ops import prox_w2, sinkhorn_cost


def _cost_matrix(support: np.ndarray) -> np.ndarray:
    diff = support[:, None, :] - support[None, :, :]
    return (diff**2).sum(axis=-1)


def test_mlx_sinkhorn_matches_pot_within_tolerance():
    rng = np.random.default_rng(0)
    n = 32
    a = rng.dirichlet(np.ones(n)).astype(np.float32)
    b = rng.dirichlet(np.ones(n)).astype(np.float32)
    support = np.linspace(-2, 2, n).reshape(-1, 1).astype(np.float32)
    cost = _cost_matrix(support)
    mlx_val = mlx_sinkhorn_cost(a, b, cost, epsilon=0.05, n_iter=300)
    pot_val = sinkhorn_cost(a, b, cost, epsilon=0.05, n_iter=300)
    # 1 percent tolerance on the regularized cost
    assert abs(mlx_val - pot_val) / max(abs(pot_val), 1e-9) < 0.05  # noqa: PLR2004


def test_mlx_prox_w2_returns_simplex():
    support = np.linspace(-2, 2, 16).reshape(-1, 1).astype(np.float32)
    x = support[:, 0]
    distribution = np.exp(-0.5 * ((x + 0.8) / 0.5) ** 2)
    distribution = distribution / distribution.sum()
    reference = np.exp(-0.5 * ((x - 0.8) / 0.5) ** 2)
    reference = reference / reference.sum()
    result = mlx_prox_w2(
        distribution.astype(np.float32),
        reference=reference.astype(np.float32),
        epsilon=0.05,
        support=support,
        n_iter=50,
    )
    # Valid probability distribution: sums to 1, non-negative, finite
    assert abs(result.sum() - 1.0) < 1e-4  # noqa: PLR2004
    assert (result >= 0).all()
    assert np.isfinite(result).all()


def test_mlx_prox_w2_both_backends_produce_valid_simplex():
    """Both MLX and POT variants should produce valid probability distributions.

    We do NOT assert the two backends converge to the same point because the
    POT reference implementation is known to be sensitive to its hyper-params
    (step size, n_iter) and sometimes pushes mass to a boundary corner. MLX
    and POT agree on the Sinkhorn cost (covered by the other test) but can
    differ on the proximal step trajectory.
    """
    support = np.linspace(-2, 2, 16).reshape(-1, 1).astype(np.float32)
    x = support[:, 0]
    distribution = np.exp(-0.5 * ((x + 0.8) / 0.5) ** 2)
    distribution = distribution / distribution.sum()
    reference = np.exp(-0.5 * ((x - 0.8) / 0.5) ** 2)
    reference = reference / reference.sum()

    mlx_out = mlx_prox_w2(
        distribution.astype(np.float32),
        reference=reference.astype(np.float32),
        epsilon=0.05,
        support=support,
        n_iter=50,
    )
    pot_out = prox_w2(
        distribution.astype(np.float64),
        reference=reference.astype(np.float64),
        epsilon=0.05,
        support=support.astype(np.float64),
        n_iter=50,
    )
    tol_mass = 1e-3
    tol_neg = -1e-6
    for out in (mlx_out, pot_out):
        assert abs(out.sum() - 1.0) < tol_mass
        assert (out >= tol_neg).all()
        assert np.isfinite(out).all()


@pytest.mark.slow
@pytest.mark.skip(
    reason=(
        "obsolete premise: since ffee5d9 prox_w2 is a numpy Dykstra "
        "scaling (no POT gradient loop), so it no longer mirrors the "
        "MLX projected-gradient solver and the speed race is meaningless"
    )
)
def test_mlx_prox_w2_faster_than_pot_at_scale():
    import time  # noqa: PLC0415

    support = np.linspace(-2, 2, 64).reshape(-1, 1).astype(np.float32)
    x = support[:, 0]
    distribution = np.exp(-0.5 * ((x + 1.0) / 0.4) ** 2)
    distribution = distribution / distribution.sum()
    reference = np.exp(-0.5 * ((x - 1.0) / 0.4) ** 2)
    reference = reference / reference.sum()

    # Warm up both backends
    _ = mlx_prox_w2(
        distribution.astype(np.float32),
        reference=reference.astype(np.float32),
        epsilon=0.01,
        support=support,
        n_iter=20,
    )
    _ = prox_w2(
        distribution.astype(np.float64),
        reference=reference.astype(np.float64),
        epsilon=0.01,
        support=support.astype(np.float64),
        n_iter=20,
    )

    t0 = time.perf_counter()
    mlx_prox_w2(
        distribution.astype(np.float32),
        reference=reference.astype(np.float32),
        epsilon=0.01,
        support=support,
        n_iter=100,
    )
    t_mlx = time.perf_counter() - t0

    t0 = time.perf_counter()
    prox_w2(
        distribution.astype(np.float64),
        reference=reference.astype(np.float64),
        epsilon=0.01,
        support=support.astype(np.float64),
        n_iter=100,
    )
    t_pot = time.perf_counter() - t0

    # The expectation is that MLX is at least as fast as POT on 64x64;
    # we use 1.5x as a lenient CI threshold given Metal warm-up jitter.
    assert t_mlx < t_pot * 1.5, f"mlx={t_mlx:.3f}s vs pot={t_pot:.3f}s"
