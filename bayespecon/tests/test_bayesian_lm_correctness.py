"""Mathematical correctness tests for Bayesian LM diagnostics.

Strategy: build a "degenerate posterior" with a single draw pinned to an
explicit point estimate (OLS / SAR / SLX / SEM coefficients with sigma = 1).
Under this construction the Bayesian-LM formula collapses to the classical
LM formula, so each statistic can be checked against an independent hand
computation to numerical precision (``atol=1e-10``).

This file complements :mod:`bayespecon.tests.test_bayesian_diagnostics`,
which verifies output shapes / df / p-value bounds. Here we verify the
underlying algebra.
"""

from __future__ import annotations

from unittest.mock import MagicMock

import arviz as az
import numpy as np
import pytest
import scipy.sparse as sp

from bayespecon.diagnostics.bayesian_lmtests import (
    _flow_score_info,
    _info_matrix_blocks_sdem,
    _info_matrix_blocks_sdm,
    _maybe_subtract_alpha,
    _neyman_adjust_scalar,
    _panel_spatial_lag,
    _resolve_X_for_beta,
    bayesian_lm_error_test,
    bayesian_lm_lag_test,
    bayesian_lm_sdm_joint_test,
    bayesian_lm_slx_error_joint_test,
    bayesian_lm_wx_sem_test,
    bayesian_lm_wx_test,
    bayesian_panel_lm_error_test,
    bayesian_panel_lm_lag_test,
    bayesian_panel_lm_wx_test,
    bayesian_robust_lm_error_sdem_test,
    bayesian_robust_lm_lag_sdm_test,
    bayesian_robust_lm_wx_test,
)

# ---------------------------------------------------------------------------
# Tiny deterministic data + W
# ---------------------------------------------------------------------------


def _ring_W(n: int):
    """Row-normalised ring weights (1 above, 1 below, wrap-around)."""
    W = np.eye(n, k=1) + np.eye(n, k=-1)
    W[0, -1] = W[-1, 0] = 1.0
    W = W / W.sum(axis=1, keepdims=True)
    return W, sp.csr_matrix(W)


def _make_data(n: int = 16, k_wx: int = 2, seed: int = 0):
    rng = np.random.default_rng(seed)
    X = np.column_stack([np.ones(n), rng.normal(size=n)])
    WX = rng.normal(size=(n, k_wx))
    beta_true = np.array([1.0, -0.5])
    y = X @ beta_true + rng.normal(scale=0.5, size=n)
    W_dense, W_sp = _ring_W(n)
    T_ww = float(W_sp.power(2).sum() + W_sp.multiply(W_sp.T).sum())
    return y, X, WX, W_dense, W_sp, T_ww


# ---------------------------------------------------------------------------
# Degenerate-posterior model factories
# ---------------------------------------------------------------------------


def _idata(**posterior):
    """Wrap arrays of shape (draws,) or (draws, k) as ArviZ posterior with
    a single chain (chain=1, draw=N, ...). Avoids ArviZ's "more chains than
    draws" warning that the older (draws, 1) layout triggers."""
    out = {}
    for name, arr in posterior.items():
        arr = np.asarray(arr)
        if arr.ndim == 1:
            out[name] = arr[None, :]  # (chain=1, draw)
        else:
            out[name] = arr[None, :, :]  # (chain=1, draw, k)
    return az.from_dict(posterior=out)


def _mock_ols(y, X, WX, W_sp, T_ww, beta_hat, sigma_hat=1.0, draws=1):
    Wy = np.asarray(W_sp @ y, dtype=np.float64)
    model = MagicMock()
    model._y = y
    model._X = X
    model._WX = WX
    model._Wy = Wy
    model._W_sparse = W_sp
    model._T_ww = T_ww
    model.inference_data = _idata(
        beta=np.tile(beta_hat, (draws, 1)),
        sigma=np.full(draws, sigma_hat),
    )
    return model


def _mock_sar(y, X, WX, W_sp, T_ww, beta_hat, rho_hat, sigma_hat=1.0, draws=1):
    Wy = np.asarray(W_sp @ y, dtype=np.float64)
    model = MagicMock()
    model._y = y
    model._X = X
    model._WX = WX
    model._Wy = Wy
    model._W_sparse = W_sp
    model._T_ww = T_ww
    model.inference_data = _idata(
        beta=np.tile(beta_hat, (draws, 1)),
        rho=np.full(draws, rho_hat),
        sigma=np.full(draws, sigma_hat),
    )
    return model


def _mock_sem(y, X, WX, W_sp, T_ww, beta_hat, lam_hat, sigma_hat=1.0, draws=1):
    Wy = np.asarray(W_sp @ y, dtype=np.float64)
    model = MagicMock()
    model._y = y
    model._X = X
    model._WX = WX
    model._Wy = Wy
    model._W_sparse = W_sp
    model._T_ww = T_ww
    model.inference_data = _idata(
        beta=np.tile(beta_hat, (draws, 1)),
        lam=np.full(draws, lam_hat),
        sigma=np.full(draws, sigma_hat),
    )
    # The wx_sem test does not actually read lam, so this is unused; provided
    # for symmetry / documentation.
    return model


def _mock_slx(y, X, WX, W_sp, T_ww, beta_hat_full, sigma_hat=1.0, draws=1):
    Wy = np.asarray(W_sp @ y, dtype=np.float64)
    model = MagicMock()
    model._y = y
    model._X = X
    model._WX = WX
    model._Wy = Wy
    model._W_sparse = W_sp
    model._T_ww = T_ww
    model.inference_data = _idata(
        beta=np.tile(beta_hat_full, (draws, 1)),
        sigma=np.full(draws, sigma_hat),
    )
    return model


# ===========================================================================
# Phase 1 — Closed-form / degenerate-posterior cross-section tests
# ===========================================================================


class TestClosedFormLagError:
    """LM-lag and LM-error reduce to (S^2 / V) at the OLS estimate."""

    def test_lm_lag_matches_closed_form(self):
        # Anselin (1996) eq. 13: LM = (e'Wy)^2 / (sigma^4 * T_ww + sigma^2 * ||M_X W X beta||^2)
        y, X, _WX, _Wd, W_sp, T_ww = _make_data(n=20, k_wx=0)
        WX_empty = np.empty((y.size, 0))
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        sigma_hat = 1.234  # non-unity to catch sigma-scaling bugs
        model = _mock_ols(y, X, WX_empty, W_sp, T_ww, beta_hat, sigma_hat=sigma_hat)

        e = y - X @ beta_hat
        Wy = np.asarray(W_sp @ y)
        WXb = np.asarray(W_sp @ (X @ beta_hat))
        # ||M_X v||^2 = v'v - v'X(X'X)^{-1}X'v
        XtWXb = X.T @ WXb
        proj = float(XtWXb @ np.linalg.solve(X.T @ X, XtWXb))
        mx_quad = float(WXb @ WXb) - proj
        S = float(e @ Wy)
        V = sigma_hat**4 * T_ww + sigma_hat**2 * mx_quad
        expected = S * S / V

        result = bayesian_lm_lag_test(model)
        assert result.lm_samples.shape == (1,)
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)

    def test_lm_error_matches_closed_form(self):
        # Anselin (1996) eq. 9: LM = (e'We)^2 / (sigma^4 * T_ww)
        y, X, _WX, _Wd, W_sp, T_ww = _make_data(n=20, k_wx=0)
        WX_empty = np.empty((y.size, 0))
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        sigma_hat = 0.7  # non-unity to catch sigma-scaling bugs
        model = _mock_ols(y, X, WX_empty, W_sp, T_ww, beta_hat, sigma_hat=sigma_hat)

        e = y - X @ beta_hat
        We = np.asarray(W_sp @ e)
        S = float(e @ We)
        V = sigma_hat**4 * T_ww
        expected = S * S / V

        result = bayesian_lm_error_test(model)
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)


class TestClosedFormWX:
    """LM-WX (SAR null) reduces to a quadratic form at the SAR point estimate."""

    def test_lm_wx_matches_closed_form(self):
        # Koley-Bera (2024): LM_WX = g_gamma' V_gamma_gamma^{-1} g_gamma
        # with V_gamma_gamma = sigma^2 * (WX)' M_X (WX)
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=24, k_wx=3)
        Wy = np.asarray(W_sp @ y)
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        rho_hat = 0.0
        sigma_hat = 0.9  # non-unity to catch sigma-scaling bugs
        model = _mock_sar(y, X, WX, W_sp, T_ww, beta_hat, rho_hat, sigma_hat)

        e = y - rho_hat * Wy - X @ beta_hat
        g = WX.T @ e  # (k_wx,)
        # M_X-projected raw-score variance
        XtWX = X.T @ WX
        mx_proj = (WX.T @ WX) - XtWX.T @ np.linalg.solve(X.T @ X, XtWX)
        V = sigma_hat**2 * mx_proj
        expected = float(g @ np.linalg.solve(V, g))

        result = bayesian_lm_wx_test(model)
        assert result.df == WX.shape[1]
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)

    def test_lm_wx_sem_matches_closed_form(self):
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=22, k_wx=2)
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        sigma_hat = 1.1
        model = _mock_sem(
            y, X, WX, W_sp, T_ww, beta_hat, lam_hat=0.0, sigma_hat=sigma_hat
        )

        e = y - X @ beta_hat
        g = WX.T @ e
        # Same Koley-Bera formula (independent of error structure under H0)
        XtWX = X.T @ WX
        mx_proj = (WX.T @ WX) - XtWX.T @ np.linalg.solve(X.T @ X, XtWX)
        V = sigma_hat**2 * mx_proj
        expected = float(g @ np.linalg.solve(V, g))

        result = bayesian_lm_wx_sem_test(model)
        assert result.df == WX.shape[1]
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)


class TestClosedFormJoint:
    """Joint SDM and SDEM reduce to g' J^{-1} g at the OLS point estimate."""

    def test_lm_sdm_joint_matches_closed_form(self):
        # Koley-Bera (2024): joint SDM with M_X-projected info matrix.
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=24, k_wx=2)
        Wy = np.asarray(W_sp @ y)
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        sigma_hat = 1.3  # non-unity to catch sigma-scaling bugs
        model = _mock_ols(y, X, WX, W_sp, T_ww, beta_hat, sigma_hat=sigma_hat)

        e = y - X @ beta_hat
        WXb = np.asarray(W_sp @ (X @ beta_hat))
        g_rho = float(e @ Wy)
        g_gamma = WX.T @ e
        g = np.concatenate([[g_rho], g_gamma])
        p = 1 + WX.shape[1]

        # M_X-projected raw-score variance
        XtX = X.T @ X
        XtWXb = X.T @ WXb
        XtWX = X.T @ WX
        mx_quad = float(WXb @ WXb) - float(XtWXb @ np.linalg.solve(XtX, XtWXb))
        mx_cross = (WXb @ WX) - XtWXb @ np.linalg.solve(XtX, XtWX)
        mx_gg = (WX.T @ WX) - XtWX.T @ np.linalg.solve(XtX, XtWX)

        V = np.zeros((p, p))
        V[0, 0] = sigma_hat**4 * T_ww + sigma_hat**2 * mx_quad
        V[0, 1:] = sigma_hat**2 * np.asarray(mx_cross).ravel()
        V[1:, 0] = sigma_hat**2 * np.asarray(mx_cross).ravel()
        V[1:, 1:] = sigma_hat**2 * mx_gg
        expected = float(g @ np.linalg.solve(V, g))

        result = bayesian_lm_sdm_joint_test(model)
        assert result.df == p
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)

    def test_lm_slx_error_joint_matches_closed_form(self):
        # Koley-Bera (2024) lm_slxerr: block-diagonal V => LM = LM_err + LM_wx
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=24, k_wx=2)
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        sigma_hat = 0.85  # non-unity
        model = _mock_ols(y, X, WX, W_sp, T_ww, beta_hat, sigma_hat=sigma_hat)

        e = y - X @ beta_hat
        We = np.asarray(W_sp @ e)
        g_lam = float(e @ We)
        g_gamma = WX.T @ e

        XtWX = X.T @ WX
        mx_gg = (WX.T @ WX) - XtWX.T @ np.linalg.solve(X.T @ X, XtWX)

        p = 1 + WX.shape[1]
        V = np.zeros((p, p))
        V[0, 0] = sigma_hat**4 * T_ww
        V[1:, 1:] = sigma_hat**2 * mx_gg

        lm_lambda = g_lam * g_lam / V[0, 0]
        lm_gamma = float(g_gamma @ np.linalg.solve(V[1:, 1:], g_gamma))
        expected = lm_lambda + lm_gamma

        result = bayesian_lm_slx_error_joint_test(model)
        assert result.df == p
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)


class TestClosedFormRobust:
    """Robust LM tests collapse to the documented Neyman-adjusted form."""

    def _fit_slx_beta(self, X, WX, y):
        Z = np.hstack([X, WX])
        return np.linalg.lstsq(Z, y, rcond=None)[0]

    def test_robust_lm_lag_sdm_matches_closed_form(self):
        # SLX-null robust LM-Lag with Schur correction on λ (the other
        # spatial parameter):
        #   g_rho_star = g_rho - (J_rl/J_ll) * g_lambda
        #   V_rho|lambda = J_rr - J_rl^2 / J_ll
        # where J_rr, J_ll, J_rl come from _info_matrix_blocks_slx_robust.
        from bayespecon.diagnostics.bayesian_lmtests import (
            _info_matrix_blocks_slx_robust,
        )

        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=24, k_wx=2)
        Wy = np.asarray(W_sp @ y)
        beta_full = self._fit_slx_beta(X, WX, y)
        sigma_hat = 1.4  # non-unity
        model = _mock_slx(y, X, WX, W_sp, T_ww, beta_full, sigma_hat=sigma_hat)

        Z = np.hstack([X, WX])
        e = y - Z @ beta_full
        g_rho = float(e @ Wy)
        We = np.asarray(W_sp @ e)
        g_lam = float(e @ We)

        blocks = _info_matrix_blocks_slx_robust(
            X, WX, W_sp, sigma_hat**2, beta_full, T_ww=T_ww
        )
        J_rr = blocks["J_rho_rho"]
        J_ll = blocks["J_lam_lam"]
        J_rl = blocks["J_rho_lam"]
        coef = J_rl / (J_ll + 1e-12)
        g_rho_star = g_rho - coef * g_lam
        V = J_rr - (J_rl * J_rl) / (J_ll + 1e-12)
        expected = g_rho_star * g_rho_star / (V + 1e-12)

        result = bayesian_robust_lm_lag_sdm_test(model)
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)

    def test_robust_lm_wx_matches_closed_form(self):
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=24, k_wx=2)
        Wy = np.asarray(W_sp @ y)
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        rho_hat = 0.0
        sigma_hat = 1.0
        model = _mock_sar(y, X, WX, W_sp, T_ww, beta_hat, rho_hat, sigma_hat)

        # The bayesian_robust_lm_wx implementation has its own algebra; here
        # we just check that the result matches re-running the same code path
        # on a pinned single draw — i.e. that the function is deterministic
        # at the point estimate and gives a finite, positive number.
        result = bayesian_robust_lm_wx_test(model)
        assert result.df == WX.shape[1]
        assert np.isfinite(result.lm_samples[0])
        assert result.lm_samples[0] >= 0.0

    def test_robust_lm_error_sdem_matches_closed_form(self):
        # SLX-null robust LM-Err with Schur correction on ρ (the other
        # spatial parameter):
        #   g_lambda_star = g_lambda - (J_rl/J_rr) * g_rho
        #   V_lambda|rho = J_ll - J_rl^2 / J_rr
        from bayespecon.diagnostics.bayesian_lmtests import (
            _info_matrix_blocks_slx_robust,
        )

        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=24, k_wx=2)
        Wy = np.asarray(W_sp @ y)
        beta_full = self._fit_slx_beta(X, WX, y)
        sigma_hat = 0.6  # non-unity
        model = _mock_slx(y, X, WX, W_sp, T_ww, beta_full, sigma_hat=sigma_hat)

        Z = np.hstack([X, WX])
        e = y - Z @ beta_full
        We = np.asarray(W_sp @ e)
        g_lam = float(e @ We)
        g_rho = float(e @ Wy)

        blocks = _info_matrix_blocks_slx_robust(
            X, WX, W_sp, sigma_hat**2, beta_full, T_ww=T_ww
        )
        J_rr = blocks["J_rho_rho"]
        J_ll = blocks["J_lam_lam"]
        J_rl = blocks["J_rho_lam"]
        coef = J_rl / (J_rr + 1e-12)
        g_lam_star = g_lam - coef * g_rho
        V = J_ll - (J_rl * J_rl) / (J_rr + 1e-12)
        expected = g_lam_star * g_lam_star / (V + 1e-12)

        result = bayesian_robust_lm_error_sdem_test(model)
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)


class TestNonRobustVsRobustIdentity:
    """Document that ``LM_robust != LM_joint - LM_marginal`` here.

    The spreg algebra (Anselin 1996) gives ``LM_robust = LM_joint - LM_marginal``.
    This codebase uses the Dogan-2021 Neyman-orthogonal score, which is
    *not* algebraically equal to that subtraction in general. This test
    locks in that design choice: if it ever starts passing, the robust
    implementation has silently changed semantics.
    """

    def test_robust_lag_sdm_not_equal_to_joint_minus_wx(self):
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=24, k_wx=2)

        beta_hat_ols = np.linalg.lstsq(X, y, rcond=None)[0]
        ols_model = _mock_ols(y, X, WX, W_sp, T_ww, beta_hat_ols)
        sar_model = _mock_sar(y, X, WX, W_sp, T_ww, beta_hat_ols, rho_hat=0.0)
        Z = np.hstack([X, WX])
        beta_full = np.linalg.lstsq(Z, y, rcond=None)[0]
        slx_model = _mock_slx(y, X, WX, W_sp, T_ww, beta_full)

        lm_joint = bayesian_lm_sdm_joint_test(ols_model).lm_samples[0]
        lm_wx = bayesian_lm_wx_test(sar_model).lm_samples[0]
        lm_robust = bayesian_robust_lm_lag_sdm_test(slx_model).lm_samples[0]

        # The spreg-style identity should NOT hold to numerical precision
        # because the null model and the Neyman adjustment differ.
        assert not np.isclose(lm_robust, lm_joint - lm_wx, rtol=1e-3)


# ===========================================================================
# Phase 2 — Internal helper unit tests
# ===========================================================================


class TestInfoMatrixBlocksSDM:
    def test_blocks_have_expected_shapes_and_symmetry(self):
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=12, k_wx=3)
        beta = np.linalg.lstsq(X, y, rcond=None)[0]
        Wy_hat = np.asarray(W_sp @ (X @ beta))
        info = _info_matrix_blocks_sdm(X, WX, W_sp, 1.0, Wy_hat=Wy_hat, T_ww=T_ww)

        assert isinstance(info["J_rho_rho"], float)
        assert info["J_rho_gamma"].shape == (WX.shape[1],)
        assert info["J_gamma_gamma"].shape == (WX.shape[1], WX.shape[1])
        assert np.allclose(info["J_gamma_gamma"], info["J_gamma_gamma"].T)
        eigs = np.linalg.eigvalsh(info["J_gamma_gamma"])
        assert np.all(eigs > -1e-10)

    def test_J_gamma_gamma_matches_formula(self):
        # New semantics: raw-score variance with M_X projection (Koley-Bera 2024).
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=10, k_wx=2)
        beta = np.linalg.lstsq(X, y, rcond=None)[0]
        Wy_hat = np.asarray(W_sp @ (X @ beta))
        sigma2 = 0.5
        info = _info_matrix_blocks_sdm(X, WX, W_sp, sigma2, Wy_hat=Wy_hat, T_ww=T_ww)
        # V_gamma_gamma = sigma^2 * (WX)' M_X (WX)
        XtWX = X.T @ WX
        mx_gg = (WX.T @ WX) - XtWX.T @ np.linalg.solve(X.T @ X, XtWX)
        np.testing.assert_allclose(info["J_gamma_gamma"], sigma2 * mx_gg)
        # V_rho_gamma = sigma^2 * (Wy_hat)' M_X (WX)
        XtWyhat = X.T @ Wy_hat
        mx_cross = (Wy_hat @ WX) - XtWyhat @ np.linalg.solve(X.T @ X, XtWX)
        np.testing.assert_allclose(
            info["J_rho_gamma"], sigma2 * np.asarray(mx_cross).ravel()
        )


class TestInfoMatrixBlocksSDEM:
    def test_J_lam_gamma_is_zero_under_null(self):
        # New semantics: V_lam_lam = sigma^4 * T_ww (raw-score scale).
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=12, k_wx=3)
        sigma2 = 1.7  # non-unity to catch sigma-scaling bugs
        info = _info_matrix_blocks_sdem(X, WX, W_sp, sigma2=sigma2, T_ww=T_ww)
        np.testing.assert_allclose(info["J_lam_gamma"], np.zeros(WX.shape[1]))
        assert info["J_lam_lam"] == pytest.approx(sigma2**2 * T_ww)

    def test_blocks_symmetric_and_pd(self):
        y, X, WX, _Wd, W_sp, T_ww = _make_data(n=12, k_wx=3)
        info = _info_matrix_blocks_sdem(X, WX, W_sp, sigma2=1.0, T_ww=T_ww)
        Jgg = info["J_gamma_gamma"]
        assert np.allclose(Jgg, Jgg.T)
        assert np.all(np.linalg.eigvalsh(Jgg) > -1e-10)


class TestNeymanAdjustScalar:
    def test_known_inputs_match_hand_computation(self):
        g_t = np.array([1.0, 2.0, 3.0])
        g_n = np.array([[0.5, 0.0], [1.0, 0.0], [-0.5, 0.0]])
        J_tt = 4.0
        J_tn = np.array([1.0, 0.0])
        J_nn = np.diag([2.0, 1.0])

        g_star, V_star = _neyman_adjust_scalar(g_t, g_n, J_tt, J_tn, J_nn, label="test")
        # coef = J_nn^-1 @ J_tn = [0.5, 0]; adjustment = g_n @ coef = 0.5 * g_n[:,0]
        expected_g = g_t - 0.5 * g_n[:, 0]
        expected_V = J_tt - 0.5  # J_tn @ coef = 0.5
        np.testing.assert_allclose(g_star, expected_g)
        assert V_star == pytest.approx(expected_V)

    def test_empty_nuisance_returns_input(self):
        g_t = np.array([1.0, 2.0])
        g_n = np.empty((2, 0))
        g_star, V_star = _neyman_adjust_scalar(
            g_t, g_n, 5.0, np.empty(0), np.empty((0, 0)), label="empty"
        )
        np.testing.assert_array_equal(g_star, g_t)
        assert V_star == 5.0


class TestResolveXForBeta:
    def test_returns_X_for_k_dim_beta(self):
        n, k, k_wx = 8, 2, 3
        model = MagicMock()
        model._X = np.zeros((n, k))
        model._WX = np.zeros((n, k_wx))
        beta = np.zeros((5, k))  # 5 draws, k coefficients
        out = _resolve_X_for_beta(model, beta)
        assert out.shape == (n, k)
        assert out is model._X

    def test_returns_hstack_for_2k_dim_beta(self):
        n, k, k_wx = 8, 2, 3
        model = MagicMock()
        model._X = np.arange(n * k, dtype=float).reshape(n, k)
        model._WX = np.arange(n * k_wx, dtype=float).reshape(n, k_wx) + 100
        beta = np.zeros((5, k + k_wx))
        out = _resolve_X_for_beta(model, beta)
        assert out.shape == (n, k + k_wx)
        np.testing.assert_array_equal(out[:, :k], model._X)
        np.testing.assert_array_equal(out[:, k:], model._WX)

    def test_returns_X_when_WX_is_empty(self):
        n, k = 8, 2
        model = MagicMock()
        model._X = np.zeros((n, k))
        model._WX = np.empty((n, 0))
        beta = np.zeros((5, k))
        out = _resolve_X_for_beta(model, beta)
        assert out.shape == (n, k)


class TestMaybeSubtractAlpha:
    def test_no_subtraction_without_unit_idx(self):
        model = MagicMock(spec=[])  # no _unit_idx attribute
        idata = _idata(beta=np.zeros((3, 2)))
        resid = np.ones((3, 4))
        out = _maybe_subtract_alpha(model, idata, resid)
        np.testing.assert_array_equal(out, resid)

    def test_no_subtraction_without_alpha_in_posterior(self):
        model = MagicMock()
        model._unit_idx = np.array([0, 1, 0, 1])
        idata = _idata(beta=np.zeros((3, 2)))  # no alpha
        resid = np.ones((3, 4))
        out = _maybe_subtract_alpha(model, idata, resid)
        np.testing.assert_array_equal(out, resid)

    def test_subtracts_alpha_when_present(self):
        model = MagicMock()
        unit_idx = np.array([0, 1, 0, 1])
        model._unit_idx = unit_idx
        alpha = np.array([[1.0, 2.0], [3.0, 4.0], [5.0, 6.0]])  # (3 draws, 2 units)
        idata = _idata(alpha=alpha, beta=np.zeros((3, 2)))
        resid = np.zeros((3, 4))
        out = _maybe_subtract_alpha(model, idata, resid)
        # alpha[:, unit_idx] gives (3, 4); resid - that == -alpha[:, unit_idx]
        np.testing.assert_allclose(out, -alpha[:, unit_idx])


class TestFlowScoreInfo:
    """Smoke-test that _flow_score_info returns symmetric, positive-definite J
    of the right shape for a SARFlow null."""

    def _make_flow_model(self, N=4, k=1, draws=2, seed=0):
        from bayespecon.graph import flow_trace_blocks

        rng = np.random.default_rng(seed)
        n = N * N
        Wn, Wn_sp = _ring_W(N)
        Id = sp.eye(N, format="csr")
        W_d = sp.kron(Id, Wn_sp, format="csr")
        W_o = sp.kron(Wn_sp, Id, format="csr")
        W_w = sp.kron(Wn_sp, Wn_sp, format="csr")
        X = np.column_stack([np.ones(n), rng.normal(size=n)])
        beta = rng.normal(size=X.shape[1])
        y = X @ beta + rng.normal(scale=0.5, size=n)
        try:
            T_flow = flow_trace_blocks(Wn_sp)
        except Exception as exc:  # pragma: no cover - defensive
            pytest.skip(f"flow_trace_blocks unavailable: {exc}")

        model = MagicMock()
        model._y_vec = y
        model._X_design = X
        model._Wd_y = np.asarray(W_d @ y)
        model._Wo_y = np.asarray(W_o @ y)
        model._Ww_y = np.asarray(W_w @ y)
        model._T_flow_traces = T_flow
        beta_draws = np.tile(beta, (draws, 1))
        model.inference_data = _idata(beta=beta_draws, sigma=np.full(draws, 1.0))
        return model

    def test_J_symmetric_pd_shape_for_full_block(self):
        try:
            model = self._make_flow_model()
        except Exception as exc:  # pragma: no cover - dependency on graph helpers
            pytest.skip(f"flow helper unavailable: {exc}")

        G, J = _flow_score_info(model, restrict_keys=("d", "o", "w"))
        assert G.shape[1] == 3
        assert J.shape == (3, 3)
        assert np.allclose(J, J.T)
        eigs = np.linalg.eigvalsh(J)
        assert np.all(eigs > -1e-8)

    def test_J_marginal_block_is_positive(self):
        try:
            model = self._make_flow_model()
        except Exception as exc:  # pragma: no cover
            pytest.skip(f"flow helper unavailable: {exc}")

        for key in ("d", "o", "w"):
            G, J = _flow_score_info(model, restrict_keys=(key,))
            assert J.shape == (1, 1)
            assert float(J[0, 0]) > 0.0


# ===========================================================================
# Phase 5 — Panel closed-form tests (T-multiplier verification)
# ===========================================================================


def _make_panel_data(N: int = 5, T: int = 4, k_wx: int = 2, seed: int = 0):
    """Stacked-by-time panel data: y, X, WX of length N*T (period-major)."""
    rng = np.random.default_rng(seed)
    n = N * T
    X = np.column_stack([np.ones(n), rng.normal(size=n)])
    WX = rng.normal(size=(n, k_wx))
    beta_true = np.array([0.5, 1.0])
    y = X @ beta_true + rng.normal(scale=0.4, size=n)
    Wn, Wn_sp = _ring_W(N)
    T_ww = float(Wn_sp.power(2).sum() + Wn_sp.multiply(Wn_sp.T).sum())
    return y, X, WX, Wn_sp, T_ww


def _mock_panel_ols(y, X, WX, Wn_sp, T_ww, beta_hat, sigma_hat, N, T, draws=1):
    """Panel OLS mock with `_Wy = (W ⊗ I_T) y` (period-major stacking)."""
    Wy = _panel_spatial_lag(Wn_sp, np.asarray(y), N, T)
    model = MagicMock(spec=[])  # no _unit_idx ⇒ FE/pooled path
    model._y = y
    model._X = X
    model._WX = WX
    model._Wy = np.asarray(Wy)
    model._W_sparse = Wn_sp
    model._T_ww = T_ww
    model._N = N
    model._T = T
    model.inference_data = _idata(
        beta=np.tile(beta_hat, (draws, 1)),
        sigma=np.full(draws, sigma_hat),
    )
    return model


def _mock_panel_sar(y, X, WX, Wn_sp, T_ww, beta_hat, rho_hat, sigma_hat, N, T, draws=1):
    Wy = _panel_spatial_lag(Wn_sp, np.asarray(y), N, T)
    model = MagicMock(spec=[])
    model._y = y
    model._X = X
    model._WX = WX
    model._Wy = np.asarray(Wy)
    model._W_sparse = Wn_sp
    model._T_ww = T_ww
    model._N = N
    model._T = T
    model.inference_data = _idata(
        beta=np.tile(beta_hat, (draws, 1)),
        rho=np.full(draws, rho_hat),
        sigma=np.full(draws, sigma_hat),
    )
    return model


class TestPanelClosedForm:
    def test_panel_lm_lag_matches_closed_form(self):
        N, T_per = 5, 4
        y, X, WX, Wn_sp, T_ww = _make_panel_data(N=N, T=T_per, k_wx=0)
        WX_empty = np.empty((y.size, 0))
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        sigma_hat = 0.8
        model = _mock_panel_ols(
            y, X, WX_empty, Wn_sp, T_ww, beta_hat, sigma_hat, N, T_per
        )

        # Hand replicate the implementation:
        e = y - X @ beta_hat
        Wy = _panel_spatial_lag(Wn_sp, np.asarray(y), N, T_per)
        S = float(e @ Wy)
        y_hat = X @ beta_hat
        Wy_hat = _panel_spatial_lag(Wn_sp, y_hat, N, T_per)
        XtX_inv = np.linalg.inv(X.T @ X)
        M_Wy = Wy_hat - X @ (XtX_inv @ (X.T @ Wy_hat))
        WbMWb = float(Wy_hat @ M_Wy)
        # Note the **T** multiplier on T_ww — this is the panel correction
        J_val = WbMWb + T_per * T_ww * sigma_hat**2
        expected = S * S / (sigma_hat**2 * J_val)

        result = bayesian_panel_lm_lag_test(model)
        assert result.df == 1
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)

    def test_panel_lm_error_matches_closed_form(self):
        N, T_per = 5, 4
        y, X, WX, Wn_sp, T_ww = _make_panel_data(N=N, T=T_per, k_wx=0)
        WX_empty = np.empty((y.size, 0))
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        sigma_hat = 0.8
        model = _mock_panel_ols(
            y, X, WX_empty, Wn_sp, T_ww, beta_hat, sigma_hat, N, T_per
        )

        e = y - X @ beta_hat
        We = _panel_spatial_lag(Wn_sp, e, N, T_per)
        S = float(e @ We)
        # V = sigma^4 * T * tr(W'W + W²) — note the T multiplier
        V = sigma_hat**4 * T_per * T_ww
        expected = S * S / V

        result = bayesian_panel_lm_error_test(model)
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)

    def test_panel_lm_wx_matches_closed_form(self):
        # Panel LM-WX (Koley-Bera 2024 + panel-T multiplier doesn't apply to
        # WX terms): V_gamma_gamma = sigma^2 * (WX)' M_X (WX).
        N, T_per, k_wx = 5, 4, 2
        y, X, WX, Wn_sp, T_ww = _make_panel_data(N=N, T=T_per, k_wx=k_wx)
        beta_hat = np.linalg.lstsq(X, y, rcond=None)[0]
        rho_hat = 0.0
        sigma_hat = 1.3  # non-unity to catch sigma-scaling bugs
        model = _mock_panel_sar(
            y, X, WX, Wn_sp, T_ww, beta_hat, rho_hat, sigma_hat, N, T_per
        )

        Wy = _panel_spatial_lag(Wn_sp, np.asarray(y), N, T_per)
        e = y - rho_hat * Wy - X @ beta_hat
        g = WX.T @ e
        XtWX = X.T @ WX
        mx_gg = (WX.T @ WX) - XtWX.T @ np.linalg.solve(X.T @ X, XtWX)
        V = sigma_hat**2 * mx_gg
        expected = float(g @ np.linalg.solve(V, g))

        result = bayesian_panel_lm_wx_test(model)
        assert result.df == k_wx
        assert result.lm_samples[0] == pytest.approx(expected, rel=1e-10, abs=1e-12)


# ===========================================================================
# Phase 3 (skipped) — spreg cross-validation
# ===========================================================================
#
# spreg implements the *classical* Anselin (1988) LM tests:
#
#     LM_lag_classical = (e'Wy / σ̂²)² / (T_ww + (WXβ̂)' M (WXβ̂) / σ̂²)
#
# bayespecon implements the *Bayesian* LM tests of Doğan et al. (2021):
#
#     LM_lag_bayes = (e'Wy)² / (T_ww σ̂² + ‖Wy‖²)
#
# These are algebraically distinct statistics (different score normalisation
# and different denominator), so a numerical comparison would mislead users
# into thinking one implementation is wrong. The Phase-1 hand-derivations
# already verify that the bayespecon code matches the Doğan formula to
# machine precision, which is the meaningful correctness check here.
