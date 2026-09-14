"""
GPU equivalent of ``ssaft.utils.kde_at_points`` using a Triton
cell-list kernel.

This module is fully additive — it does not modify the C++ implementation;
it swaps it in only for the duration of a context manager:

    from ssaft._kde_gpu import gpu_kde
    with gpu_kde(device='cuda'):
        ds.downsample_vector(he_path=..., sdata=...)   # uses GPU internally
    # back to C++ outside the with-block

Numerical equivalence vs C++ ``kde_at_points``:
    max row-L1 relative diff < 2e-6 (verified on M=5M, N=5k, n_genes=280).

Supports both dim==2 and dim==3 (3D KDE). Note that the 3D cell-list array
size is W*H*D*4 bytes; for very large/anisotropic domains consider using
``force_2d=True`` to collapse z when 2D projection is acceptable.
"""
from __future__ import annotations

import contextlib
import math
import warnings
from typing import Optional

import numpy as np

try:
    import torch
    import triton
    import triton.language as tl
    _HAS_TRITON = True
except ImportError:
    _HAS_TRITON = False


if _HAS_TRITON:
    @triton.jit
    def _kde_cell_kernel(
        qx_ptr, qy_ptr,
        sx_ptr, sy_ptr, sg_ptr,
        cell_start_ptr,
        out_ptr,
        N, n_genes, W, H, Rp,
        x_min, y_min,
        inv_sd, two_h2, inv_norm, Rw2,
        BLOCK_T: tl.constexpr, EPA: tl.constexpr,
    ):
        pid = tl.program_id(0)
        if pid >= N:
            return
        qx = tl.load(qx_ptr + pid)
        qy = tl.load(qy_ptr + pid)
        qcx = tl.cast(tl.floor((qx - x_min) * inv_sd), tl.int32)
        qcy = tl.cast(tl.floor((qy - y_min) * inv_sd), tl.int32)
        out_row = out_ptr + pid * n_genes

        for cdy in range(-Rp, Rp + 1):
            cy = qcy + cdy
            if (cy >= 0) and (cy < H):
                for cdx in range(-Rp, Rp + 1):
                    cx = qcx + cdx
                    if (cx >= 0) and (cx < W):
                        cid = cy * W + cx
                        s = tl.load(cell_start_ptr + cid)
                        ee = tl.load(cell_start_ptr + cid + 1)
                        nT = ee - s
                        for c0 in range(0, nT, BLOCK_T):
                            offs = c0 + tl.arange(0, BLOCK_T)
                            mask = offs < nT
                            idx = s + offs
                            tx = tl.load(sx_ptr + idx, mask=mask, other=0.0)
                            ty = tl.load(sy_ptr + idx, mask=mask, other=0.0)
                            tg = tl.load(sg_ptr + idx, mask=mask, other=0)
                            dx = tx - qx
                            dy = ty - qy
                            r2 = dx * dx + dy * dy
                            keep = mask & (r2 <= Rw2) & (tg >= 0) & (tg < n_genes)
                            if EPA:
                                # 1 - (r/H)^2 on the ball, zero outside; Rw2 = H^2
                                w = (1.0 - r2 / Rw2) * inv_norm
                            else:
                                w = tl.exp(-r2 / two_h2) * inv_norm
                            tl.atomic_add(out_row + tg,
                                          tl.cast(w, tl.float32),
                                          mask=keep)

    @triton.jit
    def _kde_cell_kernel_3d(
        qx_ptr, qy_ptr, qz_ptr,
        sx_ptr, sy_ptr, sz_ptr, sg_ptr,
        cell_start_ptr,
        out_ptr,
        N, n_genes, W, H, D, Rp,
        x_min, y_min, z_min,
        inv_sd, two_h2, inv_norm, Rw2,
        BLOCK_T: tl.constexpr, EPA: tl.constexpr,
    ):
        pid = tl.program_id(0)
        if pid >= N:
            return
        qx = tl.load(qx_ptr + pid)
        qy = tl.load(qy_ptr + pid)
        qz = tl.load(qz_ptr + pid)
        qcx = tl.cast(tl.floor((qx - x_min) * inv_sd), tl.int32)
        qcy = tl.cast(tl.floor((qy - y_min) * inv_sd), tl.int32)
        qcz = tl.cast(tl.floor((qz - z_min) * inv_sd), tl.int32)
        WH = W * H
        out_row = out_ptr + pid * n_genes

        for cdz in range(-Rp, Rp + 1):
            cz = qcz + cdz
            if (cz >= 0) and (cz < D):
                for cdy in range(-Rp, Rp + 1):
                    cy = qcy + cdy
                    if (cy >= 0) and (cy < H):
                        for cdx in range(-Rp, Rp + 1):
                            cx = qcx + cdx
                            if (cx >= 0) and (cx < W):
                                cid = cz * WH + cy * W + cx
                                s = tl.load(cell_start_ptr + cid)
                                ee = tl.load(cell_start_ptr + cid + 1)
                                nT = ee - s
                                for c0 in range(0, nT, BLOCK_T):
                                    offs = c0 + tl.arange(0, BLOCK_T)
                                    mask = offs < nT
                                    idx = s + offs
                                    tx = tl.load(sx_ptr + idx, mask=mask, other=0.0)
                                    ty = tl.load(sy_ptr + idx, mask=mask, other=0.0)
                                    tz = tl.load(sz_ptr + idx, mask=mask, other=0.0)
                                    tg = tl.load(sg_ptr + idx, mask=mask, other=0)
                                    dx = tx - qx
                                    dy = ty - qy
                                    dz = tz - qz
                                    r2 = dx * dx + dy * dy + dz * dz
                                    keep = mask & (r2 <= Rw2) & (tg >= 0) & (tg < n_genes)
                                    if EPA:
                                        w = (1.0 - r2 / Rw2) * inv_norm
                                    else:
                                        w = tl.exp(-r2 / two_h2) * inv_norm
                                    tl.atomic_add(out_row + tg,
                                                  tl.cast(w, tl.float32),
                                                  mask=keep)


def _build_cell_list(lx_g, ly_g, gi_g, sampling_distance, x_min, y_min, W, H):
    inv_sd = 1.0 / sampling_distance
    tx = torch.floor((lx_g - x_min) * inv_sd).to(torch.int64)
    ty = torch.floor((ly_g - y_min) * inv_sd).to(torch.int64)
    in_range = (tx >= 0) & (tx < W) & (ty >= 0) & (ty < H)
    sentinel = W * H
    cell_id = torch.where(in_range, ty * W + tx,
                          torch.tensor(sentinel, device=tx.device))
    sort_idx = torch.argsort(cell_id)
    sorted_cid = cell_id[sort_idx]
    arange = torch.arange(W * H + 1, device=lx_g.device, dtype=torch.int64)
    cell_start = torch.searchsorted(sorted_cid, arange).to(torch.int32)
    return (lx_g[sort_idx].contiguous(),
            ly_g[sort_idx].contiguous(),
            gi_g[sort_idx].to(torch.int32).contiguous(),
            cell_start.contiguous())


def _build_cell_list_3d(lx_g, ly_g, lz_g, gi_g, sampling_distance,
                        x_min, y_min, z_min, W, H, D):
    inv_sd = 1.0 / sampling_distance
    tx = torch.floor((lx_g - x_min) * inv_sd).to(torch.int64)
    ty = torch.floor((ly_g - y_min) * inv_sd).to(torch.int64)
    tz = torch.floor((lz_g - z_min) * inv_sd).to(torch.int64)
    in_range = ((tx >= 0) & (tx < W) &
                (ty >= 0) & (ty < H) &
                (tz >= 0) & (tz < D))
    n_cells = W * H * D
    sentinel = n_cells
    cell_id = torch.where(in_range,
                          tz * (H * W) + ty * W + tx,
                          torch.tensor(sentinel, device=tx.device))
    sort_idx = torch.argsort(cell_id)
    sorted_cid = cell_id[sort_idx]
    arange = torch.arange(n_cells + 1, device=lx_g.device, dtype=torch.int64)
    cell_start = torch.searchsorted(sorted_cid, arange).to(torch.int32)
    return (lx_g[sort_idx].contiguous(),
            ly_g[sort_idx].contiguous(),
            lz_g[sort_idx].contiguous(),
            gi_g[sort_idx].to(torch.int32).contiguous(),
            cell_start.contiguous())


def kde_at_points_gpu(
    query_x, query_y, query_z,
    loc_x, loc_y, loc_z,
    gene_indices, n_genes,
    sampling_distance, bandwidth, prune_coefficient,
    dim, ncores=None,
    device='cuda', kernel='epanechnikov',
):
    """
    GPU equivalent of ``ssaft.utils.kde_at_points`` (2D and 3D).

    Same positional signature; ``ncores`` is accepted but ignored.
    Returns a ``float32`` numpy.ndarray of shape (N, n_genes).

    :param query_x: x coordinates of query points.
    :type query_x: array-like
    :param query_y: y coordinates of query points.
    :type query_y: array-like
    :param query_z: z coordinates of query points (used only for ``dim == 3``).
    :type query_z: array-like
    :param loc_x: x coordinates of transcript locations.
    :type loc_x: array-like
    :param loc_y: y coordinates of transcript locations.
    :type loc_y: array-like
    :param loc_z: z coordinates of transcript locations (used only for ``dim == 3``).
    :type loc_z: array-like
    :param gene_indices: per-transcript gene index.
    :type gene_indices: array-like
    :param n_genes: number of genes (output column count).
    :type n_genes: int
    :param sampling_distance: cell-list grid spacing.
    :type sampling_distance: float
    :param bandwidth: Gaussian KDE bandwidth.
    :type bandwidth: float
    :param prune_coefficient: kernel truncation radius in units of bandwidth
        (gaussian only -- the Epanechnikov's radius is its own support).
    :param kernel: ``'epanechnikov'`` (default) or ``'gaussian'``.
    :type prune_coefficient: float
    :param dim: spatial dimensionality (2 or 3).
    :type dim: int
    :param ncores: accepted for signature parity with the C++ path; ignored.
    :type ncores: int or None
    :param device: torch device string.
    :type device: str
    """
    if not _HAS_TRITON:
        raise ImportError("kde_at_points_gpu requires torch + triton.")
    if dim not in (2, 3):
        raise NotImplementedError(
            f"kde_at_points_gpu supports dim=2 or 3, got dim={dim}.")

    # ``bandwidth`` is gaussian-equivalent for both kernels; the Epanechnikov's own
    # scale is the support radius it reaches zero at, and prune_coefficient does not
    # apply to it (see ssaft._count.epanechnikov_support).
    epa = str(kernel).lower().startswith('epa')
    if epa:
        from ._count import epanechnikov_support
        Rw = epanechnikov_support(bandwidth, dim)
        norm = {1: (4.0 / 3.0) * Rw,
                2: (math.pi / 2.0) * Rw ** 2,
                3: (8.0 * math.pi / 15.0) * Rw ** 3}[int(dim)]
    elif str(kernel).lower().startswith('gauss'):
        Rw = bandwidth * prune_coefficient
        norm = (2.0 * math.pi * bandwidth * bandwidth) ** (0.5 * dim)
    else:
        raise ValueError(f"unknown kernel {kernel!r}; use 'gaussian' or 'epanechnikov'")
    Rw2 = Rw * Rw
    two_h2 = 2.0 * bandwidth * bandwidth
    inv_norm = 1.0 / norm
    inv_sd = 1.0 / sampling_distance
    Rp = int(math.floor(Rw / sampling_distance + 1e-12))

    lx_g = torch.as_tensor(loc_x, dtype=torch.float64, device=device).contiguous()
    ly_g = torch.as_tensor(loc_y, dtype=torch.float64, device=device).contiguous()
    gi_g = torch.as_tensor(np.asarray(gene_indices, dtype=np.int64),
                           device=device).contiguous()
    qx_g = torch.as_tensor(query_x, dtype=torch.float64, device=device).contiguous()
    qy_g = torch.as_tensor(query_y, dtype=torch.float64, device=device).contiguous()

    N = qx_g.shape[0]
    if N == 0:
        return np.zeros((0, n_genes), dtype=np.float32)

    x_min = float(min(lx_g.min().item(), qx_g.min().item())) - Rw - sampling_distance
    y_min = float(min(ly_g.min().item(), qy_g.min().item())) - Rw - sampling_distance
    x_max = float(max(lx_g.max().item(), qx_g.max().item())) + Rw + sampling_distance
    y_max = float(max(ly_g.max().item(), qy_g.max().item())) + Rw + sampling_distance
    W = int(math.ceil((x_max - x_min) * inv_sd)) + 1
    H = int(math.ceil((y_max - y_min) * inv_sd)) + 1

    out = torch.zeros((N, n_genes), dtype=torch.float32, device=device)

    if dim == 2:
        sx, sy, sg, cell_start = _build_cell_list(
            lx_g, ly_g, gi_g, sampling_distance, x_min, y_min, W, H,
        )
        with torch.cuda.device(qx_g.device):
            _kde_cell_kernel[(N,)](
                qx_g, qy_g,
                sx, sy, sg,
                cell_start,
                out,
                N, n_genes, W, H, Rp,
                x_min, y_min,
                inv_sd, two_h2, inv_norm, Rw2,
                BLOCK_T=32, EPA=1 if epa else 0,
            )
    else:
        lz_g = torch.as_tensor(loc_z, dtype=torch.float64, device=device).contiguous()
        qz_g = torch.as_tensor(query_z, dtype=torch.float64, device=device).contiguous()
        z_min = float(min(lz_g.min().item(), qz_g.min().item())) - Rw - sampling_distance
        z_max = float(max(lz_g.max().item(), qz_g.max().item())) + Rw + sampling_distance
        D = int(math.ceil((z_max - z_min) * inv_sd)) + 1

        n_cells = W * H * D
        cell_bytes = (n_cells + 1) * 4
        if cell_bytes > (8 << 30):
            raise RuntimeError(
                f"3D cell list too large: W={W}, H={H}, D={D} → "
                f"{cell_bytes / (1 << 30):.1f} GiB. "
                f"Tile the input or use force_2d=True.")

        sx, sy, sz, sg, cell_start = _build_cell_list_3d(
            lx_g, ly_g, lz_g, gi_g, sampling_distance,
            x_min, y_min, z_min, W, H, D,
        )
        with torch.cuda.device(qx_g.device):
            _kde_cell_kernel_3d[(N,)](
                qx_g, qy_g, qz_g,
                sx, sy, sz, sg,
                cell_start,
                out,
                N, n_genes, W, H, D, Rp,
                x_min, y_min, z_min,
                inv_sd, two_h2, inv_norm, Rw2,
                BLOCK_T=32, EPA=1 if epa else 0,
            )
    return out.cpu().numpy()


@contextlib.contextmanager
def gpu_kde(device: str = 'cuda', fallback_3d_to_cpu: bool = False,
            force_2d: bool = False):
    """
    Inside this with-block, every call to ``ssaft.utils.kde_at_points``
    is routed to the GPU implementation. All higher-level APIs that internally
    call ``kde_at_points`` (downsample_vector, downsample_vector_component,
    _compute_normalized_vectors, etc.) automatically use GPU.

    The C++ implementation is restored on exit; nothing is modified permanently.

    Parameters
    ----------
    device : str
        Torch device string (e.g. ``'cuda'``, ``'cuda:0'``, ``'cuda:1'``).
    fallback_3d_to_cpu : bool
        If True, 3D inputs are routed to the original C++ implementation.
        Default False — the GPU kernel now supports 3D natively. Set True
        if you hit GPU memory limits on very large 3D domains and prefer
        CPU over reducing the chunk size.
    force_2d : bool
        If True, 3D inputs are projected to 2D (z is zeroed) and run on
        the 2D GPU kernel. Default False. Useful for thin-slice data
        (e.g. Xenium z-stack within a single section) when you want a
        lighter cell-list footprint than full 3D.

    Example
    -------
    >>> from ssaft._kde_gpu import gpu_kde
    >>> with gpu_kde(device='cuda:0'):                # native 3D on GPU
    ...     stats = ds.downsample_vector(he_path=..., sdata=...)
    >>> with gpu_kde(device='cuda:0', force_2d=True): # collapse z for speed/memory
    ...     stats = ds.downsample_vector(he_path=..., sdata=...)
    """
    if not _HAS_TRITON:
        raise ImportError("gpu_kde requires torch + triton.")

    from . import utils as _utils
    original = _utils.kde_at_points
    warned_fallback = {'flag': False}

    def _wrapped(query_x, query_y, query_z,
                 loc_x, loc_y, loc_z,
                 gene_indices, n_genes,
                 sampling_distance, bandwidth, prune_coefficient,
                 dim, ncores=None):
        if int(dim) != 2:
            if force_2d:
                qz0 = np.zeros_like(np.asarray(query_z, dtype=np.float64))
                lz0 = np.zeros_like(np.asarray(loc_z, dtype=np.float64))
                return kde_at_points_gpu(
                    query_x, query_y, qz0,
                    loc_x, loc_y, lz0,
                    gene_indices, n_genes,
                    sampling_distance, bandwidth, prune_coefficient,
                    2, device=device,
                )
            if fallback_3d_to_cpu:
                if not warned_fallback['flag']:
                    warnings.warn(
                        f"gpu_kde: dim={int(dim)} routed to C++ kde_at_points "
                        f"(CPU) per fallback_3d_to_cpu=True.",
                        RuntimeWarning, stacklevel=2,
                    )
                    warned_fallback['flag'] = True
                return original(
                    query_x, query_y, query_z,
                    loc_x, loc_y, loc_z,
                    gene_indices, n_genes,
                    sampling_distance, bandwidth, prune_coefficient,
                    int(dim), int(ncores) if ncores is not None else 1,
                )
        return kde_at_points_gpu(
            query_x, query_y, query_z,
            loc_x, loc_y, loc_z,
            gene_indices, n_genes,
            sampling_distance, bandwidth, prune_coefficient,
            int(dim), device=device,
        )

    _utils.kde_at_points = _wrapped
    try:
        yield
    finally:
        _utils.kde_at_points = original


def gpu_available(device: str = 'cuda') -> bool:
    """Return True iff torch+triton+CUDA are usable on the requested device.

    :param device: torch device string to test (e.g. ``'cuda'`` or ``'cuda:1'``).
    :type device: str
    """
    if not _HAS_TRITON:
        return False
    try:
        if not torch.cuda.is_available():
            return False
        if device.startswith('cuda:'):
            idx = int(device.split(':', 1)[1])
            return idx < torch.cuda.device_count()
        return True
    except Exception:
        return False


@contextlib.contextmanager
def auto_kde_context(device: str = 'cuda', **gpu_kwargs):
    """Auto-dispatch context manager.

    - If a usable CUDA device is found, behaves like ``gpu_kde(device, **gpu_kwargs)``
      (i.e. temporarily swaps ``ssaft.utils.kde_at_points`` for the Triton kernel).
    - Otherwise yields without patching, so the original C++ CPU implementation
      is used.

    Nesting is safe: an outer ``gpu_kde``/``auto_kde_context`` already in
    effect is preserved by ``gpu_kde``'s save-and-restore protocol.

    :param device: torch device string to dispatch on.
    :type device: str
    :param gpu_kwargs: forwarded to :func:`gpu_kde` when a CUDA device is used.
    """
    if gpu_available(device):
        with gpu_kde(device=device, **gpu_kwargs):
            yield
    else:
        yield
