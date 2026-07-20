# Chemical kinetics miniapp

`reproducer.cpp` is a standalone translation unit for the primordial chemistry
collapse-grid reproducer. Run the commands below from this directory.

## Repository layout

- `apps/` contains the thin Mojo GPU executable entry points.
- `src/gpu/` owns the shared grid-wide host lifecycle and GPU kernels.
- `tests/gpu/` and `tests/integration/` contain GPU and cross-policy tests.
- `tools/` contains code generation and numerical probes.
- `benchmarks/` contains machine-specific measurement jobs.
- `docs/performance/` contains optimization hypotheses, ideas, and results;
  `DESIGN.md` remains the canonical implementation roadmap.

Both Mojo GPU executables use the same grid-wide runner. The data-parallel and
structured chemistry kernels are adapters selected at compile time, so buffer
management, timestep reduction, failure handling, copy-back, and final-state
comparison have one implementation.

## Table of results

| ROCm version | runtime (s) | target | sgpr_count | vgpr_count | sgpr_spill_count | vgpr_spill_count | agpr_count | private_segment_fixed_size |
|---|---:|---|---:|---:|---:|---:|---:|---:|
| 6.0.0 | FAILED | gfx90a | 106 | 128 | 2864 | 2340 | 0 | 7448 |
| 6.1.3 | FAILED | gfx90a | 106 | 128 | 2868 | 2375 | 0 | 7440 |
| 6.2.4 | 324.48 | gfx90a | 106 | 128 | 2076 | 2254 | 0 | 7336 |
| 6.3.1 | 341.79 | gfx90a | 106 | 128 | 2112 | 2286 | 0 | 7328 |
| 6.4.2 | 340.22 | gfx90a | 106 | 128 | 2024 | 2357 | 0 | 7360 |
| 7.0.2 | 307.75 | gfx90a | 106 | 128 | 2037 | 2280 | 0 | 7344 |
| 7.1.1 | 333.63 | gfx90a | 106 | 128 | 2037 | 2280 | 0 | 7344 |
| 7.2.0 | 328.39 | gfx90a | 104 | 128 | 1544 | 2082 | 0 | 7344 |

## Build

CPU build:

```bash
c++ -std=c++20 -O3 -I. reproducer.cpp -o reproducer
```

Mojo CPU build:

```bash
pixi run mojo build reproducer.mojo -o reproducer_mojo -Xlinker -lm
```

Mojo GPU builds (on a CUDA-capable machine):

```bash
pixi run build-gpu
pixi run build-structured-gpu
```

The Pixi tasks generate the structured chemistry DAG sources and build the
entry points under `apps/` with `src/gpu/` on the Mojo import path.

Compile the focused GPU tests on the GPU machine with:

```bash
pixi run build-test-structured-dag
pixi run build-test-structured-trial
pixi run build-test-warp-lu
```

CUDA build with the default project settings:

```bash
nvcc -x cu -std=c++20 -O3 -arch=sm_90 --expt-relaxed-constexpr --fmad=false --maxrregcount=255 -DPRIMORDIAL_ROS2S_ENABLE_CUDA -DPRIMORDIAL_ROS2S_CUDA_THREADS_PER_BLOCK=128 -I. reproducer.cpp -o reproducer_cuda
```

Pure-CUDA port of the Hopper structured kernel:

```bash
python3 tools/slice_dag.py
nvcc -x cu -std=c++20 -O3 -arch=sm_90 --expt-relaxed-constexpr --fmad=false --maxrregcount=255 -DPRIMORDIAL_ROS2S_ENABLE_CUDA -DPRIMORDIAL_ROS2S_CUDA_STRUCTURED -DPRIMORDIAL_ROS2S_CUDA_THREADS_PER_BLOCK=128 -I. reproducer.cpp -o reproducer_cuda_structured
```

This variant preserves the Mojo structured kernel's 32-cell, 256-thread CTA,
two-wave chemistry DAG, shared-memory staging, four 8-lane LU groups per
warp, and tile-wide adaptive controller. It uses 230,576 bytes of dynamic
shared memory and therefore targets Hopper-class GPUs with the 227 KiB
opt-in shared-memory configuration. Output identifies the policy as
`gridwide-structured-cta32`.

HIP build with the default project settings:

```bash
hipcc -x hip -std=c++20 -O3 --offload-arch=gfx90a -DPRIMORDIAL_ROS2S_ENABLE_HIP -DPRIMORDIAL_ROS2S_CUDA_THREADS_PER_BLOCK=128 -I. reproducer.cpp -o reproducer_hip
```

## Run

Run the CPU reproducer:

```bash
./reproducer
```

Run the Mojo CPU reproducer:

```bash
./reproducer_mojo --grid 1 --no-compare-final-state
```

Compare C++ and Mojo transcendental functions over sampled Float64 inputs:

```bash
pixi run probe-transcendentals
```

This probe samples across the full Float64 exponent range, edge cases, focused
neighborhoods, and random bit patterns. It is not an exhaustive enumeration of
all legal Float64 values.

Run the CUDA reproducer:

```bash
./reproducer_cuda
```

The CUDA/HIP driver uses a grid-wide outer physical timestep. A preparation
kernel applies the scheduled perturbation and publishes each eligible cell's
free-fall timestep; the host selects the global minimum, and the advance
kernel integrates every participating cell over that same interval. Each GPU
thread still owns an independent ROS2S controller, including its own error
estimate, accepted/rejected substeps, and retry history. Output identifies
this policy as `gridwide-independent`.

Run the HIP reproducer:

```bash
./reproducer_hip
```

# Extra options

Show the available options:

```bash
./reproducer --help
```

By default, every backend uses a `64^3` cell grid and enables deterministic
density perturbations. The CPU run compares against
`final_states_grid64_cpu.bin`. CUDA/HIP do not select a reference by default
because their `gridwide-independent` policy is not compatible with the legacy
local-timestep CPU reference. Use `--compare-final-state FILE` with a reference
generated for the same policy. To explicitly run without comparison:

```bash
./reproducer --no-compare-final-state
./reproducer_cuda --no-compare-final-state
./reproducer_hip --no-compare-final-state
```

To run a smaller case:

```bash
./reproducer --grid 1 --no-compare-final-state
./reproducer_cuda --grid 1 --no-compare-final-state
./reproducer_hip --grid 1 --no-compare-final-state
```

For a `--grid 1` run, the program prints the final representative cell state
directly. For larger grids, it writes a packed binary final-state file named
`final_states_grid<N>_<backend>.bin`, for example
`final_states_grid64_cpu.bin`, `final_states_grid64_cuda.bin`, or
`final_states_grid64_hip.bin`. If that output file already exists, the old file
is moved aside with an `.old.<suffix>` name.

## Output

The main progress and summary fields are:

- `grid`: the requested cubic grid size and total cell count.
- `perturbations`: whether deterministic density perturbations were enabled.
- `completed global collapse steps`: the number of global collapse iterations
  completed before every cell stopped or a failure occurred.
- `cell completed steps`, `cell physical time`, and `cell density driver`: for
  multi-cell runs these are printed as `[min, median, max]`; for one-cell runs
  the representative cell values are printed directly.
- `wall time`: elapsed host wall-clock time for the integration loop.
- `ROS2S internal steps`, `rhs calls`, `jacobian calls`, `decompositions`,
  `linear solves`, and `accepted/rejected`: integrator work counters. Multi-cell
  runs print `[min, median, max]`; one-cell runs print totals.

If final-state comparison is enabled, the program also prints:

- `final-state comparison file`: the reference file used.
- `final-state comparison: PASS`: the run matched the reference within the
  built-in tolerances.
- `final-state comparison: FAIL`: at least one checked field exceeded tolerance.
  The first failure is printed, and detailed failures are written to
  `final_state_comparison_failures_<backend>.csv`.

The process exits with status `0` on successful integration and, when enabled,
successful final-state comparison. It exits nonzero if integration fails,
argument parsing fails, an output file cannot be written, or comparison fails.
