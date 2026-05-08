## fft-mixed-precision-fix
- session: claude --resume "fft-mixed-precision-fix"
- status: library-and-workspace-shipped, awaiting-merge
- worktree: ~/Code/PyAutoLabs-wt/fft-mixed-precision-fix
- library-pr: https://github.com/PyAutoLabs/PyAutoArray/pull/302
- workspace-pr: https://github.com/PyAutoLabs/autogalaxy_workspace_test/pull/38
- repos:
  - PyAutoArray: feature/fft-mixed-precision-fix
  - autogalaxy_workspace_test: feature/fft-mixed-precision-fix
- notes: |
    Made use_mixed_precision actually emit complex64 FFT in
    Convolver.convolved_image_from (light-profile / MGE path). Headline
    result on RTX 2060: GPU vmap per-call drops 17.4 -> 8.9 ms (49%
    faster on the production sampler hot path).
    Convolved_mapping_matrix_from intentionally kept its fp64 kernel
    multiply -- full fp32 there drifted delaunay_mge regression by 1.9%
    log-likelihood (K=780 source mesh). Codified that asymmetry in code
    comments + Settings docstring + new jax_assertion in workspace PR.
    Library-first merge gate: PR #302 must merge before #38 (workspace
    test runs against the new fp32 dtype contract).
    Pre-existing bug noted (out of scope here): autolens_workspace_developer
    /jax_profiling/jit/imaging/mge.py hardcodes EXPECTED_LOG_LIKELIHOOD_HST
    = 27379.39 but canonical main now produces 27542.08. Worth re-baselining
    in a follow-up.

    Follow-up prompt at PyAutoPrompt/autoarray/nnls_gpu_bottleneck.md
    captures the deferred GPU-NNLS work (jaxnnls is PDIP with MAX_ITER=50;
    Cholesky fast-path was rejected because empirical positivity hit-rate
    during sampling is low and lax.cond under vmap evaluates both branches).

## smoke-test-optimization
- issue: https://github.com/rhayes777/PyAutoFit/issues/1183
- session: claude --resume "profile-smoke-test-runtime"
- status: profiling-and-optimization
- location: cli-in-progress
- branch: main
- repos: all on main (previous PRs merged)
- summary: |
    Done: profiled imaging scripts, achieved 80-96% runtime reductions
    Next: investigate cosmology distance calc, profile interferometer scripts

### Completed optimizations
- `PYAUTO_WORKSPACE_SMALL_DATASETS=1` — caps grids/masks to 15x15, forces over_sample_size=2, skips radial bins (PyAutoArray)
- `PYAUTO_DISABLE_JAX=1` — forces use_jax=False in Analysis.__init__ (PyAutoFit)
- `PYAUTO_FAST_PLOTS=1` — skips tight_layout + savefig + critical curve/caustic overlays (PyAutoArray/Galaxy/Lens)
- Skip print_vram_use(), model.info, result_info, pre/post-fit I/O in test_mode >= 2 (PyAutoFit)
- Moved test_mode to autoconf (fixes PyAutoArray CI — no autofit dependency)

### Profiled scripts
- `imaging/simulator.py`: ~100s → 3.6s (96% reduction)
- `interferometer/simulator.py`: ~100s → 4.4s
- `imaging/modeling.py`: ~100s → 19.5s (80% reduction)

### Remaining work — next session
- Investigate cosmology distance calc (176 calls for 2-plane lens) in subplot_fit_imaging
- Investigate repeated ray-tracing in subplot panels
- Profile interferometer/modeling.py and other scripts
- Consider caching cosmology distances per redshift pair

## psf-oversampling
- issue: https://github.com/PyAutoLabs/PyAutoArray/issues/299
- session: claude --resume "psf-oversampling"
- status: parked
- parked: 2026-05-06
- classification: library (then workspace follow-up)
- suggested-branch: feature/psf-oversampling
- summary: |
    Parked — no resources claimed. Task worktree was created during /start_library
    but removed without edits; local feature/psf-oversampling branches deleted
    from PyAutoArray and PyAutoGalaxy. Both repos are free for other tasks.

    Affected repos (when resumed):
      - PyAutoArray (library, primary)
      - PyAutoGalaxy (library)
      - autolens_workspace_test (workspace follow-up)
      - autolens_workspace (workspace follow-up)

    To resume: run /start_library — it will recreate the worktree and the
    feature/psf-oversampling branches off origin/main. Then start with
    Phase 1 (over_sample_util helpers) per the agreed phasing below.

    Phasing (smaller tasks, agreed mid-session):
      1. over_sample_util: Mask2D upscale-by-N + fine->native sum-reduce helpers + tests
      2. Convolver: add convolve_over_sample_size kwarg (default 1, no behaviour change) + test
      3. Convolver: bin-down branch in all four conv paths, gated > 1 + brute-force test
      4. Imaging dataset: kwargs + 2 construction-time guards (adaptive over-sample, sparse)
      5. GridsDataset: expose oversampled grids when > 1
      6. OperateImage + FitImaging caller threading (PyAutoGalaxy)
      7. Inversion mapping audit + assertion (mapping.py / abstract.py)
      8. End-to-end library integration test
      (workspace) extend convolution.py + new convolution_oversampled.py + simulator.py
