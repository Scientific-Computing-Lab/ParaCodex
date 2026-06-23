# Performance Tuning - CUDA to OMP Migration

**Directory:** `{kernel_dir}/`  
**Files:** {file_listing}  
**Profile:** `{profile_log_path}`
**Do not change data strategy from used in the code**

**Required:**
- **NVIDIA GPU:** If running on an NVIDIA GPU, the compiler defined in the provided makefile must be used as the compiler. The provided Makefile already sets the right compiler — **do NOT change the compiler in the Makefile**.

## EARLY EXIT CHECK
If current runtime is within 5% of expected optimal (based on nsys kernel times):
- Document current metrics in optimization_plan.md
- Skip optimization - code is already well-tuned
- Focus only on micro-optimizations (const, restrict, cache locals)

## Context: CUDA to OMP Migration
The code was migrated from CUDA to OMP. Key differences affect optimization:
- CUDA kernels → OMP target teams loop
- cudaMemcpy → OMP map clauses or omp_target_memcpy
- __syncthreads() → May have been split into multiple target regions
- Shared memory → Converted to private or eliminated
- atomicAdd → OMP atomic

**Common migration bottlenecks:**
1. Excessive data transfers (lost explicit CUDA control)
2. Over-decomposed kernels (from __syncthreads() elimination)
3. Missing collapse on nested loops (CUDA had 2D/3D grids)
4. Suboptimal thread mapping (CUDA grid-stride → OMP loop)

## Workflow

### 1. Verify Baseline
```bash
cd {kernel_dir}
{clean_cmd_str}
timeout 300 {correctness_run_cmd} > current_output.txt 2>&1
diff baseline_output.txt current_output.txt | grep -E "Verification|SUCCESSFUL|FAILED"
```

If results differ, fix Step 2 first.
If there are any errors, fix them before continuing.

### 2. Analyze Profile and Create Plan

2.1. Read profile data:
```bash
# Try to find kernel information (OpenMP kernels may not appear in standard sections)
cat {profile_log_path} | grep -A20 "cuda_gpu_kern_sum" || echo "No cuda_gpu_kern_sum found - kernels may not be offloading to GPU"
cat {profile_log_path} | grep -A10 "cuda_api_sum"
cat {profile_log_path} | grep -A10 "cuda_gpu_mem_time_sum"
# Also check for any GPU activity
cat {profile_log_path} | grep -i "gpu\|kernel\|target" | head -20
```

2.2. Check GPU capability:
```bash
nvidia-smi --query-gpu=name,compute_cap --format=csv
```
Roughly estimate the GPU saturation threshold

2.3. Compare with original CUDA performance (if available):
- CUDA kernel time: [X]ms
- OMP target teams loop time: [Y]ms
- Ratio: [Y/X]
- If >2x slower: Major optimization opportunity

---

3. Create optimization_plan.md in {kernel_dir}:
```markdown
# Performance Analysis - CUDA to OMP Migration

## Current Metrics
- Runtime: [X]s
- Main kernel: [name], [Y]% GPU, [Z] instances
- Memory transfer: [%] time, [MB] total
- Kernel launches: [count]

## Bottleneck Hypothesis (pick 1–2)
- [ ] Transfers too high (CUDA avoided transfers in loop)
- [ ] Too many kernels / target regions (launch overhead)
- [ ] Missing collapse vs CUDA grid dimensionality
- [ ] Hot kernel needs micro-opts

## Actions (1–3 max)
1. [ACTION]: [what] - [why] - expected [gain]
2. [ACTION]: ...
```

### Fusion Rules

**Fuse when:**
- CUDA had single kernel for operations
- Adjacent independent, same bounds
- Producer-consumer in CUDA
- Multi-vector ops in one CUDA kernel

**Don't fuse:**
- Different bounds
- CUDA had separate kernels with cudaDeviceSynchronize()
- __syncthreads() required synchronization

### 3. Execute Optimization Plan
- Apply changes and document in optimization_plan.md

### 4. Optimization Actions (short)
- **Transfers high**: hoist data; use `omp_target_alloc` + `is_device_ptr` for persistent arrays; avoid per-iteration mapping
- **Too many target regions**: fuse adjacent target loops; inline helper kernels when safe
- **Grid shape mismatch**: add `collapse(N)` to mirror CUDA grid dimensionality
- **Kernel micro-opts**: `const`, `restrict`, cache locals, reduce recomputation

### 5. Final Summary
Update optimization_plan.md:
```markdown
# Final Performance Summary - CUDA to OMP Migration

### Baseline (from CUDA)
- CUDA Runtime: [X]s (if available)
- CUDA Main kernel: [Y] launches, [Z]ms total

### OMP Before Optimization
- Runtime: [X]s
- Slowdown vs CUDA: [X]x
- Main kernel: [Y] instances, [Z]ms total

### OMP After Optimization
- Runtime: [X]s
- Slowdown vs CUDA: [X]x (target <1.5x)
- Speedup vs initial OMP: [X]x
- Main kernel: [Y] instances, [Z]ms total

### Optimizations Applied
1. [X] [ACTION]: [description] → [±X%] [recovered CUDA pattern Y]
2. [X] [ACTION]: REVERTED (slower)

### CUDA→OMP Recovery Status
- [X] Restored 2D/3D grid mapping with collapse
- [X] Matched CUDA kernel fusion structure
- [X] Eliminated excessive transfers (matched CUDA pattern)
- [ ] Still missing: [any CUDA optimizations that couldn't be recovered]

### Micro-optimizations Applied
1. [X] [MICRO-OPT]: [description] → [±X%]
2. [X] [MICRO-OPT]: REVERTED (slower)

### Key Insights
- [Most impactful optimization - relate to CUDA pattern]
- [Remaining bottlenecks vs CUDA]
- [OMP limitations compared to CUDA]
```

## Optimization Checklist (short)
- [ ] Transfers dominate: hoist data; `omp_target_alloc` + `is_device_ptr`; avoid per-iter mapping
- [ ] Too many kernels/regions: fuse adjacent target loops; inline helper kernels when safe
- [ ] Missing CUDA grid shape: add `collapse(N)`
- [ ] Hot kernel: `const`, `restrict`, cache locals, reduce recomputation (and `simd` where safe)

## Profiling
```bash
{clean_cmd_str}
# Fallback: {build_cmd_str} run > {profile_log_path} 2>&1
# Check for kernel information (OpenMP kernels may appear in cuda_gpu_kern_sum or with different names)
grep -E "cuda_gpu_kern|CUDA GPU Kernel|GPU activities" {profile_log_path} | head -10 || echo "No kernel information found - check if code is offloading to GPU"
```

### Deliverables
- optimization_plan.md - Complete analysis including CUDA comparison
- Optimized source code
- Final profile: {profile_log_path}

**REMINDER: OpenMP Clause Syntax**
OpenMP clauses (`is_device_ptr`, `use_device_addr`, `map`) require bare pointer variables.
Extract struct members to local variables before the pragma:
```c
double *d_arr = data.arr;  // Extract first
#pragma omp target teams loop is_device_ptr(d_arr)  // Use local var
```

## RULES - BREAKING A RULE = FAILURE
- NO GIT COMMANDS.
- DO NOT READ/WRITE OUTSIDE THE WORKING DIRECTORY.
- DO NOT EDIT MAKEFILES.
- ALWAYS CLEAN BEFORE BUILD.
- PRESERVE CORRECTNESS - diff against baseline after each change
- YOU MAY MODIFY THE MAKEFILE TO ADD ANYTHING YOU NEED TO RUN THE CODE.
```

