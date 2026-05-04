"""Original Rodas5 custom kernel using numba-cuda without cuSOLVERDx."""

from __future__ import annotations

import functools
import math

import numpy as np
from numba import cuda

from solvers import _rodas5ck_common as ck


@functools.cache
def _make_kernel(ode_fn, jac_fn, n_vars: int):
    @cuda.jit
    def kernel(
        y0,
        times,
        params,
        dt0,
        rtol,
        atol,
        max_steps,
        hist,
        accepted_out,
        rejected_out,
        loop_out,
        y,
        u,
        k1,
        k2,
        k3,
        k4,
        k5,
        k6,
        k7,
        k8,
        jac,
        lu_mat,
        piv_arr,
    ):
        i = cuda.grid(1)
        if i >= y0.shape[0]:
            return

        for j in range(n_vars):
            y[i, j] = y0[i, j]
            hist[i, 0, j] = y0[i, j]

        n_save = times.shape[0]
        t = times[0]
        tf = times[n_save - 1]
        dt = dt0
        save_idx = 1
        n_steps = 0
        accepted_steps = 0
        rejected_steps = 0

        while save_idx < n_save and t < tf and n_steps < max_steps:
            next_target = times[save_idx]
            dt_use = dt
            if dt_use > next_target - t:
                dt_use = next_target - t
            if dt_use < 1e-30:
                dt_use = 1e-30
            inv_dt = 1.0 / dt_use
            t_end = t + dt_use

            jac_fn(y, t, params, jac, i)

            dtgamma_inv = 1.0 / (dt_use * ck.GAMMA)
            for row in range(n_vars):
                for col in range(n_vars):
                    if row == col:
                        lu_mat[i, row, col] = np.float32(dtgamma_inv - jac[i, row, col])
                    else:
                        lu_mat[i, row, col] = np.float32(-jac[i, row, col])

            for k_lu in range(n_vars):
                piv_k = k_lu
                max_v = math.fabs(lu_mat[i, k_lu, k_lu])
                for m in range(k_lu + 1, n_vars):
                    v = math.fabs(lu_mat[i, m, k_lu])
                    if v > max_v:
                        max_v = v
                        piv_k = m
                piv_arr[i, k_lu] = piv_k
                if piv_k != k_lu:
                    for col in range(n_vars):
                        tmp = lu_mat[i, k_lu, col]
                        lu_mat[i, k_lu, col] = lu_mat[i, piv_k, col]
                        lu_mat[i, piv_k, col] = tmp
                for m in range(k_lu + 1, n_vars):
                    fac = lu_mat[i, m, k_lu] / lu_mat[i, k_lu, k_lu]
                    lu_mat[i, m, k_lu] = fac
                    for col in range(k_lu + 1, n_vars):
                        lu_mat[i, m, col] -= fac * lu_mat[i, k_lu, col]

            ode_fn(y, t, params, k1, i)
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k1[i, k_lu]
                    k1[i, k_lu] = k1[i, piv_k]
                    k1[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k1[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k1[i, col])
                k1[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k1[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k1[i, col])
                k1[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            for j in range(n_vars):
                u[i, j] = y[i, j] + ck.A21 * k1[i, j]
            ode_fn(u, t + ck.C2 * dt_use, params, k2, i)
            for j in range(n_vars):
                k2[i, j] += ck.C21 * k1[i, j] * inv_dt
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k2[i, k_lu]
                    k2[i, k_lu] = k2[i, piv_k]
                    k2[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k2[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k2[i, col])
                k2[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k2[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k2[i, col])
                k2[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            for j in range(n_vars):
                u[i, j] = y[i, j] + (ck.A31 * k1[i, j] + ck.A32 * k2[i, j])
            ode_fn(u, t + ck.C3 * dt_use, params, k3, i)
            for j in range(n_vars):
                k3[i, j] += (ck.C31 * k1[i, j] + ck.C32 * k2[i, j]) * inv_dt
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k3[i, k_lu]
                    k3[i, k_lu] = k3[i, piv_k]
                    k3[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k3[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k3[i, col])
                k3[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k3[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k3[i, col])
                k3[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            for j in range(n_vars):
                u[i, j] = y[i, j] + (
                    ck.A41 * k1[i, j] + ck.A42 * k2[i, j] + ck.A43 * k3[i, j]
                )
            ode_fn(u, t + ck.C4 * dt_use, params, k4, i)
            for j in range(n_vars):
                k4[i, j] += (
                    ck.C41 * k1[i, j] + ck.C42 * k2[i, j] + ck.C43 * k3[i, j]
                ) * inv_dt
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k4[i, k_lu]
                    k4[i, k_lu] = k4[i, piv_k]
                    k4[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k4[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k4[i, col])
                k4[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k4[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k4[i, col])
                k4[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            for j in range(n_vars):
                u[i, j] = y[i, j] + (
                    ck.A51 * k1[i, j]
                    + ck.A52 * k2[i, j]
                    + ck.A53 * k3[i, j]
                    + ck.A54 * k4[i, j]
                )
            ode_fn(u, t + ck.C5 * dt_use, params, k5, i)
            for j in range(n_vars):
                k5[i, j] += (
                    ck.C51 * k1[i, j]
                    + ck.C52 * k2[i, j]
                    + ck.C53 * k3[i, j]
                    + ck.C54 * k4[i, j]
                ) * inv_dt
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k5[i, k_lu]
                    k5[i, k_lu] = k5[i, piv_k]
                    k5[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k5[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k5[i, col])
                k5[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k5[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k5[i, col])
                k5[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            for j in range(n_vars):
                u[i, j] = y[i, j] + (
                    ck.A61 * k1[i, j]
                    + ck.A62 * k2[i, j]
                    + ck.A63 * k3[i, j]
                    + ck.A64 * k4[i, j]
                    + ck.A65 * k5[i, j]
                )
            ode_fn(u, t_end, params, k6, i)
            for j in range(n_vars):
                k6[i, j] += (
                    ck.C61 * k1[i, j]
                    + ck.C62 * k2[i, j]
                    + ck.C63 * k3[i, j]
                    + ck.C64 * k4[i, j]
                    + ck.C65 * k5[i, j]
                ) * inv_dt
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k6[i, k_lu]
                    k6[i, k_lu] = k6[i, piv_k]
                    k6[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k6[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k6[i, col])
                k6[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k6[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k6[i, col])
                k6[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            for j in range(n_vars):
                u[i, j] += k6[i, j]

            ode_fn(u, t_end, params, k7, i)
            for j in range(n_vars):
                k7[i, j] += (
                    ck.C71 * k1[i, j]
                    + ck.C72 * k2[i, j]
                    + ck.C73 * k3[i, j]
                    + ck.C74 * k4[i, j]
                    + ck.C75 * k5[i, j]
                    + ck.C76 * k6[i, j]
                ) * inv_dt
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k7[i, k_lu]
                    k7[i, k_lu] = k7[i, piv_k]
                    k7[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k7[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k7[i, col])
                k7[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k7[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k7[i, col])
                k7[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            for j in range(n_vars):
                u[i, j] += k7[i, j]

            ode_fn(u, t_end, params, k8, i)
            for j in range(n_vars):
                k8[i, j] += (
                    ck.C81 * k1[i, j]
                    + ck.C82 * k2[i, j]
                    + ck.C83 * k3[i, j]
                    + ck.C84 * k4[i, j]
                    + ck.C85 * k5[i, j]
                    + ck.C86 * k6[i, j]
                    + ck.C87 * k7[i, j]
                ) * inv_dt
            for k_lu in range(n_vars):
                piv_k = piv_arr[i, k_lu]
                if piv_k != k_lu:
                    tmp = k8[i, k_lu]
                    k8[i, k_lu] = k8[i, piv_k]
                    k8[i, piv_k] = tmp
            for k_lu in range(1, n_vars):
                rhs_k = np.float32(k8[i, k_lu])
                for col in range(k_lu):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k8[i, col])
                k8[i, k_lu] = np.float64(rhs_k)
            for k_lu in range(n_vars - 1, -1, -1):
                rhs_k = np.float32(k8[i, k_lu])
                for col in range(k_lu + 1, n_vars):
                    rhs_k -= lu_mat[i, k_lu, col] * np.float32(k8[i, col])
                k8[i, k_lu] = np.float64(rhs_k / lu_mat[i, k_lu, k_lu])

            err_sum = 0.0
            for j in range(n_vars):
                y_new_j = u[i, j] + k8[i, j]
                scale = atol + rtol * max(math.fabs(y[i, j]), math.fabs(y_new_j))
                ratio = k8[i, j] / scale
                err_sum += ratio * ratio
            err_norm = math.sqrt(err_sum / n_vars)
            accept = err_norm <= 1.0 and not math.isnan(err_norm)

            t_new = t
            if accept:
                t_new = t + dt_use
                for j in range(n_vars):
                    y[i, j] = u[i, j] + k8[i, j]
                accepted_steps += 1
            else:
                rejected_steps += 1

            reached = accept and (
                abs(t_new - next_target) <= 1e-12 * max(1.0, abs(next_target))
            )
            if reached:
                for j in range(n_vars):
                    hist[i, save_idx, j] = y[i, j]
                save_idx += 1

            if math.isnan(err_norm) or err_norm > 1e18:
                safe_err = 1e18
            elif err_norm == 0.0:
                safe_err = 1e-18
            else:
                safe_err = err_norm
            factor = ck.SAFETY * safe_err ** (-1.0 / 6.0)
            if factor < ck.FACTOR_MIN:
                factor = ck.FACTOR_MIN
            elif factor > ck.FACTOR_MAX:
                factor = ck.FACTOR_MAX
            dt = dt_use * factor
            t = t_new
            n_steps += 1

        accepted_out[i] = accepted_steps
        rejected_out[i] = rejected_steps
        loop_out[i] = n_steps

    return kernel


def solve(
    ode_fn,
    jac_fn,
    y0,
    t_span,
    params,
    *,
    batch_size=None,
    rtol=1e-8,
    atol=1e-10,
    first_step=None,
    max_steps=100000,
    return_stats=False,
):
    del batch_size
    y0_arr, times, params_arr, dt0 = ck.normalize_inputs(y0, t_span, params, first_step)
    n, n_vars = y0_arr.shape

    hist_dev = cuda.device_array((n, times.shape[0], n_vars), dtype=np.float64)
    accepted_dev = cuda.device_array(n, dtype=np.int32)
    rejected_dev = cuda.device_array(n, dtype=np.int32)
    loop_dev = cuda.device_array(n, dtype=np.int32)

    flat_work = [cuda.device_array((n, n_vars), dtype=np.float64) for _ in range(10)]
    jac_dev = cuda.device_array((n, n_vars, n_vars), dtype=np.float64)
    lu_dev = cuda.device_array((n, n_vars, n_vars), dtype=np.float32)
    piv_dev = cuda.device_array((n, n_vars), dtype=np.int32)

    threads = 128
    blocks = (n + threads - 1) // threads
    _make_kernel(ode_fn, jac_fn, n_vars)[blocks, threads](
        cuda.to_device(y0_arr),
        cuda.to_device(times),
        cuda.to_device(params_arr),
        np.float64(dt0),
        np.float64(rtol),
        np.float64(atol),
        np.int32(max_steps),
        hist_dev,
        accepted_dev,
        rejected_dev,
        loop_dev,
        *flat_work,
        jac_dev,
        lu_dev,
        piv_dev,
    )
    cuda.synchronize()

    solution = hist_dev.copy_to_host()
    if not return_stats:
        return solution
    accepted_steps = accepted_dev.copy_to_host()
    rejected_steps = rejected_dev.copy_to_host()
    loop_steps = loop_dev.copy_to_host()
    return solution, ck.numpy_stats(accepted_steps, rejected_steps, loop_steps)
