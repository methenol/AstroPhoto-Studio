# AstroPhoto Studio — Seestar raw FITS → finished astrophoto

An end-to-end pipeline that turns the raw `.fit` subs saved by a ZWO Seestar
(S50 / S50 Pro / S30) into a finished image. It
handles the whole chain: frame grading, cloud/tree/obstruction rejection,
registration with alt-az field rotation, local normalisation, sigma-clipped
Bayer-drizzle integration, AI denoising, gradient removal, deconvolution,
star separation, narrowband palettes, stretching and export to a
full-resolution JPEG + 16-bit TIFF. It includes a web UI and a CLI.

Nothing is tuned for a particular object. Every decision comes from the
FITS headers (`BAYERPAT`, `BIAS`, `FILTER`, `EXPTIME`, …) and from statistics
of the data. The `LP` dual-band filter automatically gets an Ha/OIII (HOO)
workflow, and the `IRCUT` broadband filter gets a natural-colour RGB workflow.

## Quick start

```bash
source .venv/bin/activate
pip install -r requirements.txt          # or: uv pip install -r requirements.txt

# Web UI  →  http://127.0.0.1:8000
python -m webui.server                   # --images /path/to/Seestar/MyWorks  --port 8080  --host 0.0.0.0

# or headless, one command:
python -m astrophoto run "images/IC 5070_sub"
python -m astrophoto run DIR --palette hoo --saturation 1.8 --scale 1.5 --upscale 2 --device cuda
python -m astrophoto analyse DIR          # just the frame-quality report
python -m astrophoto devices              # show GPUs PyTorch can use
```

Point the UI or CLI at any folder of Seestar subs, for example the
`<Object>_sub` folders the Seestar writes. JPG thumbnails and non-light
frames are ignored. Results are cached in `output/<folder>-<hash>/`:
`stack.fits`, the two half stacks, `denoised.fits`, the coverage and
rejection maps, and `exports/`.

### NVIDIA GPUs (Windows / Linux)

The AI denoiser runs on NVIDIA CUDA, Apple Metal (MPS) or CPU. The default
PyTorch wheel on Windows/Linux is often CPU-only, so install the CUDA build:

```bash
python -m venv .venv && .venv\Scripts\activate      # Windows  (Linux: source .venv/bin/activate)
pip install torch --index-url https://download.pytorch.org/whl/cu124
pip install -r requirements.txt
python -m astrophoto devices          # should list your RTX card
```

On CUDA the denoiser uses mixed precision (bf16 on RTX 30/40/50, fp16 on
older cards). It sizes the training batch and the inference tiles to the
card's VRAM: 8 GB cards work fine, and 4–6 GB cards use smaller tiles. Pick a
specific GPU with `--device cuda:1`, or with `ASTROPHOTO_DEVICE=cuda:1`. The
UI also has a device selector. Everything outside the denoiser (NumPy,
OpenCV, SEP) runs on the CPU and is platform-independent.

## What happens to your data

| Stage | Technique |
|---|---|
| **Calibration** | Black level from the FITS `BIAS` header. There are no dark frames, so hot and warm pixels are found from the temporal median of unregistered subs: sky drifts between frames but sensor defects don't. A pixel is flagged when it is an isolated same-colour outlier, which protects star cores. |
| **Frame grading** | SEP star extraction on every sub measures star count, FWHM, elongation (wind or tracking trails), sky level and noise. |
| **Registration** | Asterism (triangle) matching, then RANSAC similarity refinement on every matched star. This handles the alt-az field rotation of the Seestar, which can reach about 100° over a long session. A robust **third-order polynomial distortion model** is then fitted per frame to hundreds of matched stars, which keeps edge stars round as the field rotates across the optics. |
| **Cloud / obstruction detection** | Reference-star photometry: each bright reference star that should appear in a frame is looked up, and the flux ratio is aggregated on a tile grid. Tiles whose stars dim or vanish (a tree, a roof, a passing cloud) become per-frame masks, so a partly blocked frame still contributes its clean area. |
| **Rejection & weighting** | Robust median/MAD tests on each metric, plus an unsupervised **Isolation Forest** over the multivariate metrics. Weights are signal²/noise² × sharpness. Sensitivity is adjustable, and each frame can be overridden in the UI. |
| **Integration** | Streaming three-pass integration with bounded memory (hundreds of subs fit in 16 GB of RAM). **Local normalisation** removes each frame's rotating gradient against the running mean. Weighted **sigma clipping** removes satellites, planes and cosmic rays. **Bayer drizzle** resamples each colour's samples directly, with no demosaic interpolation. Optional 1.5× or 2× output uses the dithering and rotation between frames. Frames alternate between two independent **half stacks**. |
| **AI denoise** | **Noise2Noise**: a U-Net is trained *on your own data* to map half-stack A to half-stack B. Because the noise in the two is independent, the network learns the expected clean signal for this exact sensor, sky and integration. It uses no pretrained weights, so it can't invent detail from other people's images. Training runs in a variance-stabilised (asinh) domain, inference averages 8 rotations/flips (self-ensemble), and bright star cores are handed back unchanged. |
| **Gradient removal** | Tile samples with stars masked. An iterative *lower-envelope* surface fit (polynomial or thin-plate RBF) rejects samples sitting on nebulosity or galaxies. When nebulosity dominates the field, the model order is reduced automatically. |
| **Crop** | Largest fully covered rectangle, found by an aspect-ratio search on the coverage map and centred on the deepest part of the stack. The minimum coverage is adjustable. |
| **Colour** | Background neutralisation, then **spectrophotometric colour calibration** (SPCC, as in Siril). Once the stack is plate-solved (done automatically after stacking when online), every Gaia DR3 star in the field gets a predicted colour *in your camera*: a Pickles library spectrum for its Gaia temperature, reddened by its own Gaia extinction (CCM89), integrated through your sensor's R/G/B response and your filter's transmission. The per-channel gains are the robust fit of the measured star colours to those predictions, relative to a white reference (average spiral galaxy, or G2V). Sensor and filter come from the FITS headers (camera name, model number, sensor geometry, `FILTER`), or you pick them from Siril's database. Without a plate solution it falls back to star-based white balance (the average star is white). Aperture photometry uses isolated, unsaturated stars, with the aperture sized to the *widest* colour channel. Pixels clipped in any channel are rendered neutral. |
| **AI deconvolution** (option) | A second network is trained on the same half-stack pairs to *undo the blur*. This is a Noise2Noise adaptation of ZS-DeconvNet. The network takes the denoised half A. Its output, blurred by **PSFs measured from your own stars (one per colour channel)**, must predict the raw half B (χ² with the measured per-pixel noise). The only way to lower that loss is to recover the true, sharper sky. A Hessian penalty and a physical **sky-floor prior** (no flux below the local sky) prevent the dark rings and noise that classic deconvolution produces. In held-out tests on M 27, IC 5070 and M 31, star FWHM fell by 2–2.5× with no ringing, against 1.1× for the old masked Richardson–Lucy (see `experiments/README.md`). Saturated stars are handed back to the denoised image. Richardson–Lucy with TV regularisation remains as the fallback when too few stars are available. |
| **Restoration: ImageMM** (default) | **ImageMM** (Sukurdeep et al. 2025, arXiv:2501.03002), as published. One non-negative, background-subtracted sky image is fitted to **every individual sub at once**. Each sub has its own PSF measured from its stars, photon-transfer variances and masks. The fit uses majorization-minimization, with Huber-robust weights (removes satellite trails) and the paper's update clipping and stopping rule. Biggs–Andrews acceleration is on, which gives the converged result in half the time. The sky background is driven to zero instead of being denoised. The subs are prepared by linear demosaicing and star-refined registration (RMS at the centroid-noise level), with per-colour photometric scales and background models. On held-out subs of M 27 it beats both the stack and the deconvolution networks in every channel, and sky noise falls by three orders of magnitude (`experiments/README.md`). Options: 2× super-resolution (the paper's Algorithm 2), Moffat PSFs, seeing groups, a Noise2Noise pass. The first run prepares the subs once (about 30 min for 270 subs); the full-field restoration time is measured below. |
| **Star separation** | An **AI star remover trained on your own image** (like StarNet, with no pretrained weights). Its training pairs are made from the dataset: the classic starless image as the background, plus stars rendered with the image's own measured star profile per colour channel (halo and any dark ring included), star colours and brightnesses, up to saturated cores. The network then removes the real stars, including faint ones below the detection limit and stars on nebulosity, where inpainting smears. **Star reduction** at 1 gives the fully starless image. Until the remover is trained, the classic method is used: stars detected on a background mesh scaled to the PSF, with a concentration index that keeps galaxy nuclei and nebula knots out of the star layer, and push-pull inpainting with matched grain. |
| **Star colour & halos** | Refractors bring blue/violet (and the OIII band) to a slightly different focus, so bright stars get coloured rings. Halo light above the local background is desaturated in linear data. The star layer uses a luminance-only stretch, true linear star colour and an "unscreen" recombination, which gives white cores with no coloured blooming, dark donuts or tints over bright backgrounds. |
| **Stretch** | Four algorithms, as in Siril: **Generalized Hyperbolic Stretch** (default), **arcsinh**, **histogram transformation** (midtones transfer function, as in an autostretch) and **logarithmic**. For each one the strength is solved automatically so that the starless background lands on a target level. The stretch is colour-preserving, with luminance-preserving gamut mapping so that saturated highlights never darken. |
| **Narrowband (LP filter)** | Ha comes from the red pixels and OIII from the green and blue pixels. Ha **leakage into OIII is estimated from the data** (lower envelope of OIII/Ha over high-SNR Ha pixels) and removed. OIII is then linearly fitted to Ha, both are stretched with one curve, and they are combined as **Foraxx** (dynamic), HOO or warm HOO. **Synthetic luminance** (LRGB-style) takes lightness from the best-SNR all-channel stretch, so red-dominant Ha regions keep their full brightness. |
| **Finishing** | Post-stretch starlet shrinkage on luminance, OKLab chroma noise reduction, wavelet local contrast, perceptual (OKLab) vibrance with background protection, SCNR, curves and masked sharpening. |

## Super-resolution

Every Seestar sub lands on the sky slightly shifted and rotated (tracking drift and alt-az
field rotation), so a stack samples the sky on a finer grid than any single frame. With
**Super-resolution 1.5× / 2×** (web UI: *Integration & compute options*; CLI: `--scale 2`),
the Bayer-drizzle integrator resamples every colour sample straight onto the finer grid.
There is no demosaic step and no invented detail: the extra resolution comes from the data.

Measured on 100 subs of M 27: star FWHM went from **7.7″ at 1× to 6.5″ at 2×**, about 16% sharper,
with better colour resolution because each colour channel is sampled directly. At 2× the pixel scale
(1.15″/px) already samples the seeing-limited stars properly, so going beyond 2× gains nothing.
The deconvolution stage then works on the finer grid.

Costs: about 4× the stacking time and 4× larger stack and export files. It needs roughly 50+ subs to
fill the finer grid evenly. Stacking parallelism is limited automatically to fit about 3 GB of RAM;
raise it with `ASTROPHOTO_STACK_RAM_GB=6` on bigger machines. The export **Upscale** option is only
interpolation. Use Super-resolution for real detail.

## Colour calibration from the stars' physics

With **Colour calibration: auto** (the default), the pipeline does not assume that the average
star is white. It predicts each catalogue star's colour through your own camera and filter, then
solves the gains that make the image agree with those predictions:

- **Stars**: every Gaia DR3 star in the plate-solved field that has a GSP-Phot temperature. Each
  star gets a Pickles (1998) spectrum, dwarf or giant from its absolute magnitude, reddened by its
  own extinction A_G with the Cardelli, Clayton & Mathis (1989) law.
- **Camera and filter**: quantum-efficiency and transmission curves from
  [Siril's SPCC database](https://gitlab.com/free-astro/siril-spcc-database) (GPL-3.0). They are
  downloaded on first use to `output/spcc_db/` and are not bundled with this project.
  - The sensor is detected from the `INSTRUME` header (camera name or model number, e.g. ASI2600
    → IMX571) or from the sensor geometry (width × height × pixel size).
  - The filter is detected from `FILTER`.
  - When detection is ambiguous or unknown, pick the sensor or filter in *Linear → Colour
    calibration*. The pipeline then falls back to star-based white balance and says why.
- **Fit**: aperture photometry of the isolated, unsaturated stars, and a sigma-clipped median of
  predicted ÷ measured colour.
  - The processing info reports the number of stars used, the scatter, and the sensor and filter
    chosen.
  - On M 31 (Seestar, IMX585, IRCUT): 792 stars, 0.09 mag scatter.

Siril predicts star colours from each star's Gaia XP spectrum. The Gaia archive serves those
spectra one star at a time (minutes for a few hundred stars), while temperature and extinction
come with the catalogue query that plate solving already makes.

## AI star remover

**Train AI star remover** (Pipeline panel, and part of *Run everything*) takes about 2–3 minutes
on an Apple-silicon GPU. It trains a U-Net to remove stars from this dataset (details in the
*Star separation* row above). Once it is trained, *Star removal: auto* uses it for star
separation. The **Star reduction** slider then works in two ranges:

- up to 0.5 it shrinks the stars;
- from 0.5 to 1 it also fades them out, and 1 is the starless image.

A new restack or restoration makes the trained remover stale, and it has to be trained again.

## Explore: what else is in your image

The **Explore** tab identifies everything catalogued in the field. It plate-solves the stack
against **Gaia DR3**:

- Star triangles are matched to the catalogue (astroalign), trying both mirror orientations.
- A TAN-SIP world-coordinate solution is then fitted to thousands of matched stars
  (`astropy.wcs.utils.fit_wcs_from_points`), at about 0.3″ rms on M 27.
- Positions are propagated from Gaia's 2016.0 epoch to the night of observation.

It then looks up every **SIMBAD** object in the field. The results show in three views:
**Overlay** (markers on the processed image), **Side by side** (image next to a star map, with
pan and zoom linked) or **Star map**.

Hover over any star or object for a pop-out. It shows:

- the object's type, with a short explanation
- brightness compared with the naked-eye limit
- colour and surface temperature, noting when interstellar dust has reddened it
- distance from the Gaia parallax, which is also how many years ago its light left it
- luminosity relative to the Sun, corrected for dust
- motion across the sky
- for galaxies: redshift, lookback time and physical size (Planck 2018 cosmology)

Links go to SIMBAD, Wikipedia and Gaia. The side panel gives the field's constellation,
size, orientation and depth, and a searchable list of named objects, galaxies, nebulae and
variable or double stars. Click a list entry to fly to it.

Plate solving needs an internet connection once per stack; the catalogues are cached in
the session folder (`explore/`).

## Experiments (Optuna)

The **Experiments** tab tunes the pipeline with [Optuna](https://optuna.org) studies. For
each study you choose:

- an experiment: ImageMM restoration, the Noise2Noise denoiser, the N2N restoration
  network, or registration & integration
- a dataset: a stacked real session, or a **synthetic** one generated in the tab
- which parameters to tune, and over what ranges
- one or two objectives
- a sampler: multivariate TPE, NSGA-II, random or grid

Each study runs as its own background process, so several can run at once on different
GPUs. While it runs you see the optimisation history, Pareto front, fANOVA parameter
importances, slice plots, a trials table with a preview of every result in one shared
stretch, and the log. Trial 0 is the pipeline's current settings, so every result is shown
as a change from the baseline. Stop a study, continue it with more trials, or apply its
best trial to the pipeline: from the study itself, or with **From experiment** in
*Integration & compute options*.

How results are scored:

- **Real data** is scored on held-out data only, never on data the method saw:
  - restorations: the odd subs, predicted through each one's own PSF
  - the denoiser: the independent half-stack, on held-out bands
- **Synthetic datasets** are Seestar-format raw subs of an analytic sky (stars, nebulae,
  galaxies) with the same held-out scores, plus comparison against the exact truth: error,
  SSIM, faint-emission error and star photometry. Each sub has its own dither, field
  rotation, Moffat seeing, transparency, sky gradient, shot and read noise, hot pixels,
  satellite trails and cosmic rays.

Details: [experiments/README.md](experiments/README.md#experiment-lab-optuna).

## Research & benchmarks

`experiments/` holds the harness used to choose the ML models. It scores every
denoiser and deconvolver on held-out data against the independent half-stack, so
no ground truth is needed. It covers U-Net variants, NAFNet, ZS-N2N,
non-local means, Richardson–Lucy, DPIR plug-and-play and the N2N deconvolution
network. The results and the arXiv papers behind each choice are in
[experiments/README.md](experiments/README.md).

## Tips

- **Presets** in the Process tab are starting points: *Balanced*, *Vivid nebula*,
  *Galaxy / broadband*, *Natural colour* and so on.
- Processing sliders re-render a fast preview in about a second. The heavy
  stages (analysis, stacking, denoise) only re-run when you press their buttons.
- If you change frame selection or sensitivity in the Frames tab, run
  **Register & integrate** again, then **AI denoise & deconvolve**.
- For very short sessions (fewer than about 15 subs) the stacker switches from
  drizzle to demosaic automatically. The denoiser still works, but has less to learn from.
- Export writes a JSON sidecar with every parameter, so a result can be reproduced.
