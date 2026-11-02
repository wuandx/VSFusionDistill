# Environment record

Pinned versions (both machines, from the setup doc §4.1):

| component  | pin        | debug machine (this box) | training machine |
| ---------- | ---------- | ------------------------ | ---------------- |
| Python     | 3.10       | 3.10.12 (system venv)    | TBD             |
| PyTorch    | 2.1.2      | 2.1.2+cpu                | 2.1.2+cu121     |
| mmcv       | 2.1.0      | 2.1.0 (cpu wheel)        | 2.1.0 (cu121 wheel) |
| mmengine   | 0.10.7     | 0.10.7                   | TBD             |
| mmdet      | 3.3.0      | 3.3.0                    | TBD             |
| numpy      | 1.26.x     | 1.26.4                   | TBD             |
| CUDA       | ≥11.8      | none at setup; see GPU env below | TBD     |

## Debug machine — setup record (2026-10-30)

- WSL2 (Linux 6.18.54.1-microsoft-standard-WSL2), 32 cores, 62 GiB RAM,
  no `nvidia-smi` → CPU-only build installed via `env/install-debug-machine.sh`.
- Wheels: torch/torchvision CPU index (download.pytorch.org/whl/cpu);
  mmcv CPU wheel from download.openmmlab.com/mmcv/dist/cpu/torch2.1.0.
- Full freeze: `env/pip-freeze.txt` (committed).
- `python -c "import torch; torch.cuda.is_available()"` → False (expected).

## Training machine — placeholder

24 GB-class GPU required (setup doc §8).  On first setup, run the cu121
install (env/environment.yml), then append here: `nvidia-smi` output,
`pip freeze` diff vs the debug machine, and the mmdet YOLOX-S COCO
reproduction number (acceptance: within 1 AP of the official 40.6/0.5 box).

## GPU environment on this box — `.venv-gpu` (2026-10-31)

The debug machine's hardware changed: it now carries an RTX 5090 D v2,
24 455 MiB (Blackwell, sm_120), visible to WSL2 via `nvidia-smi` (the
2026-10-30 "no GPU visible" record above is outdated).  This meets the
24 GB training requirement, so an S0-lite-capable env was built here.

Why the pinned cu121 stack cannot be used on it (measured, not
assumed): `torch 2.1.2+cu121` wheels contain only sm_50..sm_90 cubins
with no PTX fallback, so on sm_120 every kernel launch raises
`CUDA error: no kernel image is available for execution on the device`.
sm_120 needs cu128, i.e. torch >= 2.7.

Deviations from the pins (deliberate, documented here):

| component  | pin        | .venv-gpu                | why |
| ---------- | ---------- | ------------------------ | --- |
| PyTorch    | 2.1.2      | 2.7.1+cu128              | first line with native sm_120 kernels; 2048² matmul 0.07 s, conv fwd+bwd OK |
| torchvision| 0.16.2     | 0.22.1+cu128             | must match torch |
| mmcv       | 2.1.0 wheel| 2.1.0 source build, CPU-only ops | OpenMMLab ships no wheels past cu121/torch2.4; mmdet 3.3.0 requires mmcv<2.2.0; no nvcc on this box |
| setuptools | —          | <81                      | mmcv 2.1.0 setup.py imports `pkg_resources` (removed in setuptools 81) |

Everything else mirrors `env/pip-freeze.txt` (mmengine 0.10.7, mmdet
3.3.0, numpy 1.26.4, ...); full freeze: `env/pip-freeze-gpu.txt`.

mmcv build recipe (source tree kept at `~/mmcv-2.1.0-src`):

    pip install "setuptools<81" ninja
    CUDA_VISIBLE_DEVICES="" MMCV_WITH_OPS=1 \
      pip install ~/mmcv-2.1.0-src --no-build-isolation

`CUDA_VISIBLE_DEVICES=""` is essential: with the GPU visible,
`torch.cuda.is_available()` is True and mmcv's setup.py then takes the
`CUDAExtension` branch, which dies on the missing `CUDA_HOME`.  Hiding
the GPU lands it in the `CppExtension` (CPU-only ops) branch.

Consequence and mitigation: the compiled `_ext` has CPU kernels
only, so `mmcv.ops.nms` raises on CUDA tensors.  The training path uses
no compiled mmcv op (YOLOX losses / SimOTA are pure torch; our paired
transforms use `mmcv.transforms` only); inference-time NMS goes through
`aodet/cuda_compat.py::install_nms_cpu_fallback()` — self-detecting
(wired into `tools/test.py`; no-op wherever CUDA NMS already works).
Verified: imports clean, CPU `batched_nms` correct, shimmed GPU-tensor
NMS returns results on `cuda:0` with the same keep set.  Full test
suite on this env: see `doc/logs/2026-10-30-f2-codebase-w1-w3.md`.

Second torch-version flip handled: torch >= 2.6 defaults
`torch.load(weights_only=True)`; mmengine 0.10.7 passes no override and
its checkpoints embed `HistoryBuffer`/numpy objects in `meta`.  The
predicted resume case fired on 2026-11-02: resuming e10_m3_tau4 from
epoch_10 died twice on `numpy.core.multiarray._reconstruct`, and the
class-level `add_safe_globals([HistoryBuffer])` from fa2777c proved
insufficient (numpy globals inside its pickled state stay denied;
measured).  Durable fix (2026-11-02, same day): `aodet/torch_load_compat
.py::trusted_torch_load()` — a scoped monkeypatch defaulting
`weights_only=False` for these trusted local artifacts, shared by
`tools/train.py` (wraps `runner.train()`, so resume and load-from are
covered) and `tools/test.py`; an explicit `weights_only` argument always
wins, and `TORCH_FORCE_WEIGHTS_ONLY_LOAD=1` disables the wrapper for
operators who want the sandbox enforced.  `tests/test_torch_load_compat
.py` keeps a save-then-resume smoke through the exact `CheckpointLoader`
path (6/6 green on torch 2.7.1, version-gated negative control below
2.6).  Resuming still needs `--cfg-options resume=True` — mmengine only
auto-resumes when `cfg.resume` is truthy.  Full incident:
`doc/logs/2026-11-02-tau4-resume-weights-only.md`.

The pinned CPU/debug `.venv` is untouched and remains the reproducibility
baseline; the cu121 `env/environment.yml` stays for any true 24 GB
Ampere/Ada training machine where the pins work as-is.

Running S0-lite on this box (the two configs fit the 24 GB card in
parallel, ~4 GB B0 + ~9 GB cross-attn):

    export PATH="$PWD/.venv-gpu/bin:$PATH"
    RESULTS=results/results_b0.csv bash tools/run_seeds.sh \
        configs/f2/s0_b0_sonar_only_yoloxs.py 0 &
    RESULTS=results/results_xattn.csv bash tools/run_seeds.sh \
        configs/f2/s0_cross_attn_yoloxs.py 0 &

(Separate `RESULTS` files avoid the two collectors racing on
`results/results.csv`; merge afterwards.)  Rough wall-clock with both
running: B0 ~1.7 h, cross-attn ~3.5 h, plus the D0–D∞ scan.

## Second box — environment built from scratch, 2026-11-02

This is **not** a correction of the records above: it is a *different
machine*.  Everything above (32 cores, 62 GiB RAM, and the 2026-10-31
`.venv-gpu` on an **RTX 5090 D v2, 24 455 MiB**) describes the other box,
which is unchanged and still has that card.  The two are easy to confuse
because they run the same OS generation:

| | this box | box in the records above |
| --- | --- | --- |
| host | `DESKTOP-5GMC542` | (not recorded) |
| CPU | i7-14700KF, 14C / 28T | 32 cores |
| RAM | 15 GiB | 62 GiB |
| GPU | RTX 5060 Ti, 16 311 MiB, cc 12.0, driver 610.88 | RTX 5090 D v2, 24 455 MiB |
| WSL | Ubuntu 22.04.5, kernel 6.18.54.1-microsoft-standard-WSL2 | same generation |

Both are Blackwell (sm_120), so the cu128 / torch >= 2.7 conclusion holds
on either — but the freezes, timings and pass counts below are **per-box**
and were re-derived here, not copied.  In particular 16 311 MiB is *below*
the 24 GB the training-machine section asks for, so the "two S0-lite
configs in parallel, ~4 GB + ~9 GB" plan above does not transfer as-is:
13 GB of 15.9 GB usable is thin once the desktop compositor takes its
share, and it needs measuring on this box before anyone relies on it.

`.venv-gpu` did not exist here at all (no `.venv*` in the working tree),
so the env was built from nothing along the §"mmcv build recipe" above,
verbatim.  Deviations and measurements:

| step | what was done | note |
| ---- | ------------- | ---- |
| toolchain | `build-essential python3.10-dev python3.10-venv` (gcc/g++ 11.4.0) | none of it was installed; mmcv needs a compiler |
| torch/torchvision | 2.7.1+cu128 / 0.22.1+cu128 | same pins as the 2026-10-31 build |
| mmcv | 2.1.0 source, `CUDA_VISIBLE_DEVICES="" MMCV_WITH_OPS=1`, CPU-only ops | built from `~/mmcv-2.1.0-src` (sdist sha256 d387bcab…), 7 m 22 s, `MAX_JOBS=10`, wheel 29 MB |
| setuptools | 80.9.0 (<81) | recipe requirement, as before |

Wheel sources (measured, this box): `download.pytorch.org/whl/cu128`
peaks at 4.5 MB/s here; `mirrors.aliyun.com/pytorch-wheels/cu128` at
16 MB/s for the same 1.04 GB `torch-2.7.1+cu128` file.  PyPI proper is
slower still (1.1 MB/s from `files.pythonhosted.org`, 12–29 MB/s from
the aliyun PyPI mirror).

Incident worth recording: pip produced **no log output for 10+ minutes**
on `nvidia_cudnn_cu12` (726.9 MB).  With `--progress-bar off` pip prints
nothing between starting a file and finishing it, so that only bounds it
at "slower than ~1.2 MB/s" — it was not proven to be a hard stall, and
the 0 B/s reading I based that on was an artefact of polling the wrong
veth (`eth0`; this box carries traffic on another interface).  What is
certain is the contrast: `curl` on the same URL, then a local wheelhouse,
got the whole 2.7 GB down in 39 s.  So: resolve the wheel URLs, `curl`
them into a local wheelhouse (2.7 GB of CUDA runtime + 208 MB of
everything else, 39 s at ~70 MB/s aggregate — `xargs -P 4`, not one
connection), then `pip install --no-index --find-links …`.  Installed
with `--no-deps` against the pin list, since mmdet 3.3.0's `mmcv<2.2.0`
requirement cannot be satisfied from an index that has no mmcv wheel.

Verification on the rebuilt env (2026-11-02):

- `torch.cuda.is_available()` → True; `RTX 5060 Ti`, cc 12.0, 36 SMs,
  15.9 GiB; `arch_list` includes `sm_120` and `compute_120`.
- Real kernels, not just the capability check: conv fwd+bwd on
  `(2,3,256,256)` OK; 4096² fp32 matmul 9.8 ms → 14.0 TFLOPS.  Not
  comparable with the 2026-10-31 "2048² in 0.07 s" figure: other card,
  other size, and that number was taken cold in a fresh process.
- `mmcv.ops` 155 symbols import; CPU `nms` correct; CUDA-tensor `nms`
  raises `implementation for device cuda:0 not found` — the expected
  CPU-only-`_ext` state, not a regression.
- `install_nms_cpu_fallback()` verified through the real code path
  (`mmdet.models.dense_heads.yolox_head.batched_nms`): CUDA and CPU
  agree on keep set `[0, 2]`, coordinates match to 1e-5, results come
  back on `cuda:0`.  Note the shim patches the *head's* `batched_nms`,
  not `mmcv.ops.nms`, so calling `mmcv.ops.nms` directly on CUDA
  tensors still raises after installing it — that is by design.
- `pytest tests/ -q` → **216 passed**, 21 warnings, 883 s.
- `pip freeze` (after dropping the `direct_url.json` files left by the
  local-wheelhouse install) matches `env/pip-freeze-gpu.txt` line for
  line — that freeze came off the *other* box, so an exact match here is
  the evidence that the rebuild is faithful, not just plausible.  The one
  intended difference is that mmcv records as `mmcv==2.1.0` instead of
  `file:///tmp/mmcv_build/mmcv-2.1.0`.
