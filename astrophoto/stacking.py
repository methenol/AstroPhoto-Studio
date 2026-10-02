"""Streaming, memory-bounded integration.

Pass 1  weighted mean of globally normalised frames (reference for pass 2)
Pass 2  *local normalisation*: each frame's smooth sky difference against the
        pass-1 mean is modelled with a robust 2-D polynomial and removed, which
        equalises gradients that rotate with the alt-az field.  Weighted mean and
        variance of the normalised frames are accumulated.
Pass 3  weighted sigma-clipped integration against pass-2 statistics.  Frames
        are alternately accumulated into two independent half-stacks (A/B) whose
        noise is independent – the training pair for Noise2Noise denoising.

Two resampling modes:
  * ``demosaic``   edge-aware debayer + Lanczos warp
  * ``drizzle``    CFA/Bayer drizzle: each colour's sparse samples and its sampling
                   mask are warped separately and combined as a normalised
                   convolution – no demosaic interpolation, better colour
                   resolution, needs a reasonable number of dithered frames.
PSF groups (``psf_groups`` > 1) split pass 3 further by seeing: frames are
ranked by FWHM and cut into groups of equal total weight, each accumulated
per parity.  These sub-stacks are the multi-exposure input of the ImageMM
restoration (astrophoto/imagemm.py): every group has its own PSF.  The halves
and the full stack are their sums, so nothing else changes.

Optional output ``scale`` (e.g. 1.5, 2) produces an up-sampled (drizzle-like)
integration that exploits the sub-pixel dithering/rotation between frames.
"""
from __future__ import annotations

import os
from collections import deque
from concurrent.futures import ThreadPoolExecutor

import cv2
import numpy as np

from .frames import FrameInfo, cfa_channel_map, cfa_masks, demosaic, fix_defects, read_frame


def _bounded_map(fn, items, workers):
    """Like executor.map but keeps at most ``2*workers`` results in flight (bounded memory)."""
    with ThreadPoolExecutor(max_workers=workers) as ex:
        q = deque()
        it = iter(items)
        for item in it:
            q.append(ex.submit(fn, item))
            if len(q) >= workers + 1:
                break
        while q:
            yield q.popleft().result()
            nxt = next(it, None)
            if nxt is not None:
                q.append(ex.submit(fn, nxt))


def _scaled_transform(M: np.ndarray, s: float) -> np.ndarray:
    """Map frame pixel coords -> output grid scaled by ``s`` (pixel-centre convention)."""
    A = np.asarray(M, np.float64).copy()
    out = A * s
    out[:, 2] += 0.5 * s - 0.5
    return out


def _poly_terms(x, y, deg):
    return [x ** i * y ** j for i in range(deg + 1) for j in range(deg + 1 - i)]


def fit_smooth_surface(img: np.ndarray, valid: np.ndarray, deg: int = 2, sub: int = 4,
                       block: int = 16) -> np.ndarray:
    """Robust low-order polynomial fit of a (H, W, C) residual image.

    Returns coefficient array (C, n_terms) in normalised [-1, 1] coordinates.
    """
    h, w, c = img.shape
    small = img[::sub, ::sub]
    vs = valid[::sub, ::sub]
    hb, wb = small.shape[0] // block, small.shape[1] // block
    small = small[: hb * block, : wb * block]
    vs = vs[: hb * block, : wb * block]
    arr = np.where(vs[..., None], small, np.nan).reshape(hb, block, wb, block, c)
    arr = arr.transpose(0, 2, 4, 1, 3).reshape(hb, wb, c, block * block)
    frac = np.isfinite(arr[..., 0, :]).mean(-1)
    with np.errstate(all="ignore"):
        med = np.nanmedian(arr, axis=-1)  # (hb, wb, c)
    yy, xx = np.mgrid[0:hb, 0:wb]
    cy = ((yy + 0.5) * block * sub) / h * 2 - 1
    cx = ((xx + 0.5) * block * sub) / w * 2 - 1
    ok = frac > 0.5
    coefs = np.zeros((c, len(_poly_terms(0, 0, deg))), np.float64)
    if ok.sum() < 3 * len(coefs[0]):
        for ch in range(c):
            coefs[ch, 0] = np.nanmedian(med[..., ch]) if ok.any() else 0.0
        return coefs
    X = np.stack(_poly_terms(cx[ok], cy[ok], deg), axis=1)
    for ch in range(c):
        z = med[..., ch][ok]
        keep = np.isfinite(z)
        for _ in range(4):
            beta, *_ = np.linalg.lstsq(X[keep], z[keep], rcond=None)
            r = z - X @ beta
            s = 1.4826 * np.median(np.abs(r[keep])) + 1e-9
            keep = np.abs(r) < 3 * s
        coefs[ch] = beta
    return coefs


def eval_surface(coefs: np.ndarray, h: int, w: int, deg: int = 2) -> np.ndarray:
    """Evaluate polynomial coefficients on a full (h, w) grid (via low-res + resize)."""
    lh, lw = max(8, h // 16), max(8, w // 16)
    y = (np.arange(lh) + 0.5) / lh * 2 - 1
    x = (np.arange(lw) + 0.5) / lw * 2 - 1
    xx, yy = np.meshgrid(x, y)
    terms = np.stack(_poly_terms(xx, yy, deg), axis=-1)  # lh, lw, T
    low = terms @ coefs.T  # lh, lw, C
    return cv2.resize(low.astype(np.float32), (w, h), interpolation=cv2.INTER_CUBIC).reshape(h, w, -1)


def _block_median(img: np.ndarray, valid: np.ndarray, block: int, sub: int = 2) -> np.ndarray:
    """Robust (median) level of every ``block`` x ``block`` cell of a (H, W, C) image, NaN where
    under half of the cell is valid.  Returns (H // block, W // block, C)."""
    h, w, c = img.shape
    hb, wb = h // block, w // block
    b = block // sub
    small = img[: hb * block: sub, : wb * block: sub]
    vs = valid[: hb * block: sub, : wb * block: sub]
    arr = np.where(vs[..., None], small, np.nan).reshape(hb, b, wb, b, c).transpose(0, 2, 4, 1, 3).reshape(hb, wb, c, b * b)
    with np.errstate(all="ignore"):
        med = np.nanmedian(arr, axis=-1)
    med[vs.reshape(hb, b, wb, b).mean((1, 3)) < 0.5] = np.nan
    return med.astype(np.float32)


def _smooth_fill(m: np.ndarray, sigma: float = 1.0) -> np.ndarray:
    """Gaussian smoothing of a low-resolution map with NaN holes (normalised convolution)."""
    ok = np.isfinite(m).astype(np.float32)
    num = np.stack([cv2.GaussianBlur(np.nan_to_num(m[..., c]), (0, 0), sigma) for c in range(m.shape[-1])], -1)
    den = cv2.GaussianBlur(ok.min(-1) if ok.ndim == 3 else ok, (0, 0), sigma)
    return np.where(den[..., None] > 1e-3, num / np.maximum(den[..., None], 1e-3), 0).astype(np.float32)


class Integrator:
    def __init__(self, infos: list[FrameInfo], analysis: dict, defects: np.ndarray | None,
                 mode: str = "auto", scale: float = 1.0, sigma_low: float = 4.0,
                 sigma_high: float = 3.0, local_norm: bool = True, workers: int | None = None,
                 progress=None, cancel=None, psf_groups: int = 0, unit_sink=None):
        frames = analysis["frames"]
        self.items = [(info, fr) for info, fr in zip(infos, frames) if fr["accepted"] and fr["weight"] > 0]
        if not self.items:
            raise RuntimeError("No frames accepted for stacking")
        self.defects = defects
        self.pattern = infos[0].bayer
        self.bias = infos[0].bias
        self.W0, self.H0 = infos[0].width, infos[0].height
        self.scale = float(scale)
        self.W, self.H = int(round(self.W0 * scale)), int(round(self.H0 * scale))
        if mode == "auto":
            mode = "drizzle" if (len(self.items) >= 15 and scale > 1.01) else "demosaic"
        self.mode = mode
        self.sigma_low, self.sigma_high = sigma_low, sigma_high
        self.local_norm = local_norm and len(self.items) >= 3
        # each in-flight frame holds values+weights at output resolution; keep RAM bounded
        # (values + weights + warp temporaries ~ 2.5x a frame), bounded by a RAM budget
        # threads (OpenCV warps and NumPy release the interpreter lock): every core but one, as
        # many frames in flight as fit in half the machine's RAM (ASTROPHOTO_STACK_RAM_GB overrides)
        from .resources import workers_for
        frame_bytes = self.W * self.H * 3 * 4 * 2 * 2.5
        self.workers = workers or workers_for(frame_bytes, "ASTROPHOTO_STACK_RAM_GB")
        self.progress = progress or (lambda *a: None)
        self.cancel = cancel or (lambda: False)
        self.grid = analysis["grid"]
        self._masks = cfa_masks(self.pattern, (self.H0, self.W0)) if mode == "drizzle" else None
        self.groups, self.group_info = self._psf_groups(int(psf_groups))
        self.unit_sink = unit_sink
        self.offsets: dict[int, np.ndarray] = {}
        self.gradients: dict[int, np.ndarray] = {}     # per-frame large-scale background correction (low-res)
        self.norm_block = max(16, int(round(32 * self.scale)))
        self.norm_info: dict = {}

    def _psf_groups(self, n_groups: int):
        """Assign every frame to a seeing class: equal total weight per class, sharpest first."""
        n = len(self.items)
        n_groups = min(n_groups, n // 6)
        if n_groups < 2:
            return np.zeros(n, int), []
        fw = np.array([fr.get("fwhm", np.nan) for _, fr in self.items], float)
        fw = np.where(np.isfinite(fw), fw, np.nanmax(fw) if np.isfinite(fw).any() else 1.0)
        wt = np.array([fr["weight"] for _, fr in self.items], float)
        order = np.argsort(fw, kind="stable")
        mid = (np.cumsum(wt[order]) - 0.5 * wt[order]) / wt.sum()
        groups = np.empty(n, int)
        groups[order] = np.minimum((mid * n_groups).astype(int), n_groups - 1)
        info = [{"n_frames": int((groups == g).sum()), "weight": float(wt[groups == g].sum() / wt.sum()),
                 "fwhm_median": float(np.median(fw[groups == g])),
                 "fwhm_range": [float(fw[groups == g].min()), float(fw[groups == g].max())]}
                for g in range(n_groups)]
        return groups, info

    # ------------------------------------------------------------------ frames
    def _warp(self, idx: int):
        info, fr = self.items[idx]
        raw = read_frame(info)
        raw = fix_defects(raw, self.defects)
        size = (self.W, self.H)
        maps = self._distortion_maps(fr)
        if maps is not None:
            m1, m2 = maps

            def warp(img, interp):
                return cv2.remap(img, m1, m2, interp, borderMode=cv2.BORDER_CONSTANT, borderValue=0)
        else:
            M = _scaled_transform(fr["transform"], self.scale)

            def warp(img, interp):
                return cv2.warpAffine(img, M, size, flags=interp, borderValue=0)
        ones = np.ones((self.H0, self.W0), np.float32)
        if self.mode == "drizzle":
            # all three colours in two 3-channel warps: sparse samples and their masks
            num = warp(raw[..., None] * self._masks, cv2.INTER_LINEAR)
            den = warp(self._masks, cv2.INTER_LINEAR)
            # the masks sum to one, so their warped sum is the frame's footprint;
            # a pixel only counts where the frame fully covers it (no ragged edges)
            cov = den.sum(-1) > 0.999
            ok = (den > 1e-3) & cov[..., None]
            # in place: values where the weight is zero are never used (weight 0)
            vals = num
            np.divide(num, np.maximum(den, np.float32(1e-3)), out=vals)
            wts = den
            wts *= ok
        else:
            rgb = demosaic(raw, self.pattern)
            # not clipped at 0: a calibrated sub's sky can sit below its noise (DWARF 3 Duo-Band), and
            # cutting off the negative half of the noise biases each pixel by an amount that follows its
            # own noise (dark, flat) and the sky level (cloud) - a pattern no number of subs averages out
            vals = warp(rgb, cv2.INTER_LANCZOS4)
            cov = warp(ones, cv2.INTER_LINEAR) > 0.999
            wts = np.repeat(cov[..., None].astype(np.float32), 3, axis=2)
        # obstruction mask (tile grid in reference coordinates) -> smooth full-res weight
        tm = fr.get("tile_mask")
        if tm is not None and (tm < 1).any():
            m = cv2.resize(tm.astype(np.float32), (self.W, self.H), interpolation=cv2.INTER_LINEAR)
            wts *= np.clip((m - 0.25) / 0.5, 0, 1)[..., None]
        t = fr.get("transparency", 1.0)
        if not np.isfinite(t) or t <= 0.05:
            t = 1.0
        vals /= t
        return vals, wts, float(fr["weight"])

    def _distortion_maps(self, fr):
        """Inverse maps (output pixel -> source pixel): exact similarity + interpolated distortion.

        The polynomial model is split into the (exact, per-pixel) inverse similarity
        transform plus a small, smooth residual that is evaluated on a coarse grid
        and bilinearly up-sampled (error << 0.01 px).
        """
        dist = fr.get("distortion")
        if dist is None:
            return None
        from .analysis import poly_terms
        A = np.vstack([np.asarray(fr["transform"], np.float64), [0, 0, 1]])
        Ai = np.linalg.inv(A)[:2]
        # reference-pixel coordinates of every output pixel centre (separable, float32,
        # built with in-place broadcasting – no full-size float64 temporaries)
        rx = ((np.arange(self.W, dtype=np.float64) + 0.5) / self.scale - 0.5)
        ry = ((np.arange(self.H, dtype=np.float64) + 0.5) / self.scale - 0.5)
        mx = np.empty((self.H, self.W), np.float32)
        my = np.empty((self.H, self.W), np.float32)
        mx[:] = (Ai[0, 0] * rx + Ai[0, 2]).astype(np.float32)[None, :]
        mx += (Ai[0, 1] * ry).astype(np.float32)[:, None]
        my[:] = (Ai[1, 0] * rx + Ai[1, 2]).astype(np.float32)[None, :]
        my += (Ai[1, 1] * ry).astype(np.float32)[:, None]
        # residual on a coarse grid whose cells line up with cv2.resize's pixel-centre convention
        gh, gw = max(4, self.H // 32), max(4, self.W // 32)
        cy = (np.arange(gh) + 0.5) * self.H / gh - 0.5
        cx = (np.arange(gw) + 0.5) * self.W / gw - 0.5
        gx, gy = np.meshgrid((cx + 0.5) / self.scale - 0.5, (cy + 0.5) / self.scale - 0.5)
        T = poly_terms(gx / self.W0 * 2 - 1, gy / self.H0 * 2 - 1, dist["deg"])
        px, py = T @ dist["coefs"][0], T @ dist["coefs"][1]
        sx = Ai[0, 0] * gx + Ai[0, 1] * gy + Ai[0, 2]
        sy = Ai[1, 0] * gx + Ai[1, 1] * gy + Ai[1, 2]
        mx += cv2.resize((px - sx).astype(np.float32), (self.W, self.H), interpolation=cv2.INTER_LINEAR)
        my += cv2.resize((py - sy).astype(np.float32), (self.W, self.H), interpolation=cv2.INTER_LINEAR)
        # fixed-point maps make cv2.remap considerably faster
        return cv2.convertMaps(mx, my, cv2.CV_16SC2)

    def _normalise(self, idx, vals, wts, use_gradient: bool):
        valid = wts[..., 1] > 0
        if idx not in self.offsets:
            sub = vals[::8, ::8][valid[::8, ::8]]
            self.offsets[idx] = np.median(sub, axis=0) if len(sub) else np.zeros(3, np.float32)
        vals -= (self.offsets[idx] - self.ref_level).astype(np.float32)[None, None, :]
        if use_gradient and idx in self.gradients:
            vals -= self._background_correction(idx)
        return vals, valid

    def _background_correction(self, idx) -> np.ndarray:
        """The frame's large-scale background correction at full resolution."""
        g, b = self.gradients[idx], self.norm_block
        up = cv2.resize(g, (g.shape[1] * b, g.shape[0] * b), interpolation=cv2.INTER_LINEAR)
        return np.pad(up, ((0, self.H - up.shape[0]), (0, self.W - up.shape[1]), (0, 0)), mode="edge")

    def _local_normalisation(self, mu1: np.ndarray):
        """Cloud-proof local normalisation.

        Thin cloud lit by light pollution adds a patchy glow, 50-300 px across, that changes from
        sub to sub; a per-frame polynomial cannot follow it, and it is far below the per-pixel
        noise the clipping works against, so it went into the stack as colour blotches.  Each
        sub's deviation from the first-pass mean is measured as robust block medians (stars and
        noise cancel; the static sky is in the mean); the subs whose deviation is smallest are
        the clean ones, and every sub's large-scale background is set to theirs.  Structure
        smaller than a block is never touched, and the static sky is never in a deviation."""
        n, b = len(self.items), self.norm_block
        dev: dict[int, np.ndarray] = {}
        for k, (vals, wts, fw) in enumerate(_bounded_map(self._warp, range(n), self.workers)):
            if self.cancel():
                raise RuntimeError("cancelled")
            vals, valid = self._normalise(k, vals, wts, False)
            vals -= mu1
            dev[k] = _block_median(vals, valid, b)
            self.progress(k + 1, n, f"Local normalisation ({k + 1}/{n})")
        spread = np.array([np.nanmedian(np.abs(d - np.nanmedian(d, axis=(0, 1)))) if np.isfinite(d).any() else np.inf
                           for d in (dev[k] for k in range(n))])
        # the reference is the clearest subs - darkest sky, most transparent - NOT the ones closest
        # to the mean: under a hazy night the mean is itself hazy, and the subs nearest it carry
        # the average cloud glow into every other sub
        n_clean = max(min(n, 8), n // 4)
        frs = [fr for _, fr in self.items]
        bgv = np.array([np.mean(fr.get("background", [np.nan])) for fr in frs], float)
        trv = np.array([fr.get("transparency", np.nan) for fr in frs], float)
        bgv = np.where(np.isfinite(bgv), bgv, np.nanmax(bgv) if np.isfinite(bgv).any() else 0.0)
        trv = np.where(np.isfinite(trv), trv, np.nanmin(trv) if np.isfinite(trv).any() else 0.0)
        rank = np.argsort(np.argsort(bgv)) + np.argsort(np.argsort(-trv)) + 0.5 * np.argsort(np.argsort(spread))
        clean = np.argsort(rank, kind="stable")[:n_clean]
        w = np.array([self.items[k][1]["weight"] for k in clean], np.float64)[:, None, None, None]
        stackd = np.stack([dev[k] for k in clean])
        ok = np.isfinite(stackd)
        ref = (np.where(ok, stackd, 0) * w).sum(0) / np.maximum((ok * w).sum(0), 1e-12)
        ref = np.where(ok.any(0), ref, np.nan)
        for k in range(n):
            self.gradients[k] = _smooth_fill(dev[k] - ref, 1.0)
        self.norm_info = {"method": "block", "block_px": b, "n_reference": int(n_clean),
                          "spread_median": float(np.median(spread[np.isfinite(spread)])) if np.isfinite(spread).any() else None,
                          "spread_reference_max": float(spread[clean].max())}

    # ------------------------------------------------------------------ passes
    def run(self) -> dict:
        n = len(self.items)
        H, W = self.H, self.W
        # reference background level: the best-weighted frame
        best = int(np.argmax([fr["weight"] for _, fr in self.items]))
        v, w_, _ = self._warp(best)
        valid = w_[..., 1] > 0
        self.ref_level = np.median(v[::8, ::8][valid[::8, ::8]], axis=0).astype(np.float32)
        del v, w_

        # All per-frame arithmetic below is done in place on the frame's own buffers:
        # at 2x super-resolution every full-size temporary is ~400 MB.

        # ---- pass 1: weighted mean
        S = np.zeros((H, W, 3), np.float32)
        Wt = np.zeros((H, W, 3), np.float32)
        for k, (vals, wts, fw) in enumerate(_bounded_map(self._warp, range(n), self.workers)):
            if self.cancel():
                raise RuntimeError("cancelled")
            vals, _ = self._normalise(k, vals, wts, False)
            wts *= np.float32(fw)
            Wt += wts
            vals *= wts
            S += vals
            self.progress(k + 1, n, f"Integration pass 1/3 ({k + 1}/{n})")
        mu1 = S
        mu1 /= np.maximum(Wt, 1e-6)
        del S

        if self.local_norm:
            self._local_normalisation(mu1)

        # ---- pass 2: local normalisation + mean/variance
        S1 = np.zeros((H, W, 3), np.float32)
        S2 = np.zeros((H, W, 3), np.float32)
        Wt[:] = 0
        for k, (vals, wts, fw) in enumerate(_bounded_map(self._warp, range(n), self.workers)):
            if self.cancel():
                raise RuntimeError("cancelled")
            vals, valid = self._normalise(k, vals, wts, self.local_norm)
            vals -= mu1                                  # vals is now d = x - mu1
            wts *= np.float32(fw)
            Wt += wts
            vals *= wts                                  # w*d
            S1 += vals
            vals *= vals                                 # w^2 d^2 ...
            vals /= np.maximum(wts, np.float32(1e-12))   # ... -> w d^2
            S2 += vals
            self.progress(k + 1, n, f"Integration pass 2/3 ({k + 1}/{n})")
        Wsafe = np.maximum(Wt, 1e-6)
        S1 /= Wsafe
        mu2 = mu1
        mu2 += S1
        S2 /= Wsafe
        S1 *= S1
        S2 -= S1
        np.maximum(S2, 0, out=S2)
        sd = np.sqrt(S2, out=S2)
        del S1, Wsafe
        coverage = Wt[..., 1] / max(float(Wt[..., 1].max()), 1e-6)
        del Wt
        # robust floor for the clipping scale (few-frame pixels at the edges)
        pos = sd[::4, ::4][sd[::4, ::4] > 0]
        sd_floor = float(np.median(pos)) * 0.25 if pos.size else 1.0
        np.maximum(sd, sd_floor, out=sd)

        # ---- pass 3: sigma-clipped integration into two half stacks
        # one (sum, weight) accumulator per PSF group and parity; without groups
        # that is exactly the two half stacks
        G = int(self.groups.max()) + 1
        units = [[(np.zeros((H, W, 3), np.float32), np.zeros((H, W, 3), np.float32)) for _ in range(2)]
                 for _ in range(G)]
        rejected = np.zeros((H, W), np.uint16)
        clip = n >= 5
        r = np.empty((H, W, 3), np.float32)
        for k, (vals, wts, fw) in enumerate(_bounded_map(self._warp, range(n), self.workers)):
            if self.cancel():
                raise RuntimeError("cancelled")
            vals, valid = self._normalise(k, vals, wts, True)
            wts *= np.float32(fw)
            if clip:
                np.subtract(vals, mu2, out=r)
                r /= sd
                bad = r > self.sigma_high
                bad |= r < -self.sigma_low
                wts[bad] = 0
                rejected += bad.any(-1) & valid
            acc_s, acc_w = units[self.groups[k]][k % 2]
            acc_w += wts
            vals *= wts
            acc_s += vals
            self.progress(k + 1, n, f"Integration pass 3/3 ({k + 1}/{n})")
        del r, sd
        if G > 1 and self.unit_sink is not None:
            for g in range(G):
                for par in range(2):
                    S_, W_ = units[g][par]
                    self.unit_sink(g, par, S_, W_)
        # fold the groups into the two halves, freeing each group as it is added
        (SA, WA), (SB, WB) = units[0]
        for g in range(1, G):
            for (S_, W_), (acc_s, acc_w) in zip(units[g], ((SA, WA), (SB, WB))):
                acc_s += S_
                acc_w += W_
            units[g] = None
        del units
        S_ = W_ = acc_s = acc_w = None
        Wtot = WA + WB
        full = SA + SB
        full /= np.maximum(Wtot, 1e-6)
        np.copyto(full, mu2, where=Wtot <= 0)
        del Wtot, mu2
        half_a = SA
        half_a /= np.maximum(WA, 1e-6)
        np.copyto(half_a, full, where=WA <= 0)
        half_b = SB
        half_b /= np.maximum(WB, 1e-6)
        np.copyto(half_b, full, where=WB <= 0)
        del WA, WB
        return {
            "stack": full,
            "half_a": half_a,
            "half_b": half_b,
            "coverage": coverage.astype(np.float32),
            "rejected_frac": (rejected.astype(np.float32) / n),
            "mode": self.mode,
            "scale": self.scale,
            "n_frames": n,
            "total_exposure": float(sum(info.exptime for info, _ in self.items)),
            "psf_groups": self.group_info,
            "local_norm": self.norm_info,
        }


# ------------------------------------------------------------------ sensor pattern

def sensor_pattern(items: list, stack: np.ndarray, defects: np.ndarray | None, scale: float = 1.0,
                   n_sample: int = 300, workers: int = 8, progress=None, cancel=None) -> tuple[np.ndarray, dict]:
    """The fixed pattern the calibration left in the subs, measured from the subs themselves.

    A master dark taken at another temperature (a DWARF 3's 27 C dark against 40-43 C lights,
    scaled x1.5) and with few frames leaves a per-pixel pattern in every calibrated sub that
    does not average down: the field only drifts and rotates slowly over the sensor, so the
    stack smears it into the worm-like mottle of "walking noise", identical in both half
    stacks (the Noise2Noise denoiser keeps it as signal).

    Each sampled sub, less the stack warped back into its pixels (scaled and offset per CFA
    colour, so transparency and sky level do not matter) and less its own large-scale residual
    (cloud glow, gradients), leaves its noise plus the sensor's pattern.  The per-pixel median
    over the subs is the pattern: the sky has been removed, and what is left of stars and
    passing cloud lands on different pixels in every sub.  The estimate's own noise (a median of
    ``n_sample`` subs) becomes a fixed pattern in its turn, hence many subs (float16: ~17 MB each
    for a DWARF 3).  Returns (CFA-resolution pattern in the subs' ADU, info)."""
    if len(items) < 12:
        raise ValueError("too few subs to measure the sensor pattern")
    pick = [items[j] for j in np.unique(np.linspace(0, len(items) - 1, min(n_sample, len(items))).round().astype(int))]
    info0 = pick[0][0]
    H, W = info0.height, info0.width
    cmap = cfa_channel_map(info0.bayer, (H, W))
    sites = ((0, 0), (0, 1), (1, 0), (1, 1))

    def resid(item):
        info, fr = item
        raw = fix_defects(read_frame(info), defects)
        M = _scaled_transform(fr["transform"], scale)
        # the stack sampled at this sub's pixels (output grid -> sub pixels), invalid outside it
        model = cv2.warpAffine(stack, M, (W, H), flags=cv2.INTER_LINEAR | cv2.WARP_INVERSE_MAP,
                               borderMode=cv2.BORDER_CONSTANT, borderValue=(np.nan, np.nan, np.nan))
        m_cfa = np.take_along_axis(model, cmap[..., None].astype(np.intp), axis=2)[..., 0]
        out = np.full((H, W), np.nan, np.float32)
        for dy, dx in sites:
            y, m = raw[dy::2, dx::2], m_cfa[dy::2, dx::2]
            ok = np.isfinite(m)
            if ok.sum() < 1000:
                continue
            ys, ms = y[ok][::5], m[ok][::5]
            keep = ms < np.percentile(ms, 99)              # stars' cores: seeing and sampling differ
            A = np.stack([ms[keep], np.ones(int(keep.sum()))], 1)
            a, b = np.linalg.lstsq(A, ys[keep], rcond=None)[0]
            r = np.where(ok, y - a * np.nan_to_num(m) - b, 0).astype(np.float32)
            w = ok.astype(np.float32)
            large = cv2.GaussianBlur(r, (0, 0), 12) / np.maximum(cv2.GaussianBlur(w, (0, 0), 12), 1e-3)
            out[dy::2, dx::2] = np.where(ok, r - large, np.nan)
        return out.astype(np.float16)

    R = np.empty((len(pick), H, W), np.float16)
    with ThreadPoolExecutor(max_workers=workers) as ex:
        for k, r in enumerate(ex.map(resid, pick)):
            R[k] = r
            if progress:
                progress(k + 1, len(pick), f"Sensor pattern: sub {k + 1}/{len(pick)}")
            if cancel and cancel():
                raise RuntimeError("cancelled")
    P = np.zeros((H, W), np.float32)
    n_valid = np.zeros((H, W), np.int32)
    for y0 in range(0, H, 128):                            # nanmedian in row blocks (bounded memory)
        blk = R[:, y0:y0 + 128].astype(np.float32)
        n_valid[y0:y0 + 128] = np.isfinite(blk).sum(0)
        with np.errstate(all="ignore"):
            P[y0:y0 + 128] = np.nan_to_num(np.nanmedian(blk, axis=0))
    P[n_valid < max(8, len(pick) // 4)] = 0.0
    # how much of it is reproducible: two independent halves of the sample against each other
    half = []
    for sel in (slice(0, None, 2), slice(1, None, 2)):
        h = np.zeros((H // 4, W), np.float32)
        for y0 in range(0, H // 4, 128):
            y1 = min(y0 + 128, H // 4)
            with np.errstate(all="ignore"):
                h[y0:y1] = np.nan_to_num(np.nanmedian(R[sel, H // 2 + y0:H // 2 + y1].astype(np.float32), axis=0))
        half.append(h)
    corr = float(np.corrcoef(half[0].ravel(), half[1].ravel())[0, 1])
    rms = float(1.4826 * np.median(np.abs(P - np.median(P))))
    del R
    return P, {"n_subs": len(pick), "rms_adu": rms, "reproducibility": corr}
