# Polygeist for HIP-to-Vortex: Current Status

**Date:** November 16, 2025
**Status:** 🟢 Phase 2B In Progress - GPU-to-Vortex Pass 70% Complete

**See Also:** [PHASE2B_A_STATUS.md](PHASE2B_A_STATUS.md) - Detailed Phase 2B Developer A progress

---

## Executive Summary

Polygeist has been successfully built and validated for use in the HIP-to-Vortex compilation pipeline. The tool will be used for **C++/HIP → SCF dialect conversion only**, with MLIR handling all subsequent transformations.

**Key findings:**
- ✅ Polygeist successfully converts C++ → SCF dialect
- ✅ MLIR GPU infrastructure is available and compatible
- ✅ HIP support exists in Polygeist (47 source references, ROCm flag)
- ✅ No LLVM version conflicts (Polygeist LLVM 18 and llvm-vortex LLVM 10 are independent)
- ✅ Minimal HIP header created for testing

---

## Build Information

**Binary Location:** `/home/yaakov/vortex_hip/Polygeist/build/bin/cgeist`
**Binary Size:** 202MB
**LLVM Version:** 18.0.0git (optimized, Release build)
**Build Time:** ~1 hour with 8 threads, lld linker

**Build Configuration:**
- lld linker (fast linking)
- 8 parallel threads
- Release mode: `-O3 -DNDEBUG` (no debug symbols)
- Targets: X86 only
- Disabled: CUDA, ROCm, Polymer, tests, examples

**Repository Configuration:**
```
Remote: origin   → https://github.com/ymweiss/Polygeist (your fork)
Remote: upstream → https://github.com/llvm/Polygeist (LLVM official)
Location: /home/yaakov/vortex_hip/Polygeist/
```

---

## Validation Results: 5/5 Tests Passed ✅

| Test | Status | Notes |
|------|--------|-------|
| Simple function → MLIR | ✅ PASS | Clean arith dialect |
| Loop → SCF | ✅ PASS | `scf.for` generated |
| Nested loops → SCF | ✅ PASS | 2 nested `scf.for` |
| Conditional → SCF/Arith | ✅ PASS | Optimized to `arith.select` |
| CUDA infrastructure | ✅ PASS | 25 CUDA tests found |

**Verified Capabilities:**
- C++ → MLIR conversion works correctly
- Loop constructs properly converted to SCF dialect
- Nested structures preserved
- Smart optimizations applied (e.g., `arith.select` for simple conditionals)
- CUDA/HIP test infrastructure present

**Available MLIR Passes:**
- `--convert-affine-for-to-gpu`
- `--async-parallel-for`
- Complete GPU dialect support (`gpu.thread_id`, `gpu.block_id`, `gpu.barrier`, etc.)

---

## HIP Support Investigation Results

**Polygeist Source Code Analysis:**
- **47 HIP-specific references** found in source code
- **9 CUDA references** found
- **ROCm support flag exists:** `polygeist_enable_rocm` in test config
- **Clang (Polygeist's frontend):** Has built-in CUDA/HIP support

**HIP Compatibility:**
- HIP is CUDA-compatible by design (same attributes, same built-ins)
- If Polygeist handles CUDA, it should handle HIP identically
- **Probability Assessment:**
  - 80% - HIP works with existing `--cuda-lower` flag (no modifications needed)
  - 15% - Need HIP flag alias (trivial, 1 day work)
  - 5% - Need explicit HIP support (1 week work)

**Minimal HIP Header Created:**
Location: `/home/yaakov/vortex_hip/Polygeist/hip_minimal.h`

Provides:
- HIP attributes (`__global__`, `__device__`, `__host__`, `__shared__`)
- `dim3` structure
- Built-in variables (`threadIdx`, `blockIdx`, `blockDim`, `gridDim`)
- Launch bounds attribute

---

## Architecture: No LLVM Version Conflicts

**Key Architectural Insight:** Polygeist (LLVM 18) and llvm-vortex (LLVM 10) never interact directly.

**Pipeline Overview:**
```
HIP/CUDA Code
    ↓
[Polygeist + LLVM 18] → SCF Dialect
    ↓
[MLIR Passes] → GPU Dialect
    ↓
[Custom GPUToVortexLLVM Pass] → LLVM Dialect (with vx_* calls)
    ↓
[mlir-translate] → LLVM IR (.ll file)
    ↓
[llvm-vortex LLVM 10] → Vortex RISC-V Assembly
```

**Why This Works:**
1. Polygeist brings its own LLVM 18 - completely self-contained
2. MLIR handles all transformations within Polygeist ecosystem
3. Handoff is standard LLVM IR - version-independent format
4. llvm-vortex only handles final RISC-V codegen

**No Custom Vortex MLIR Dialect Needed:**
- Vortex uses inline assembly in runtime functions (`vx_thread_id()`, etc.)
- Can emit standard LLVM function calls instead of custom dialect operations
- Saves ~2000 lines of custom dialect code

---

## Implementation Plan: Phased Approach

### Phase 1: Plain C++ Pipeline (2-3 weeks) - Person A

**Goal:** Validate entire pipeline end-to-end with minimal complexity

**Approach:**
- Write kernels as plain C++ functions (no HIP syntax)
- Polygeist: C++ → SCF
- MLIR: SCF → GPU (using standard passes)
- Custom pass: GPU → LLVM with Vortex calls
- llvm-vortex: LLVM IR → RISC-V

**Example:**
```cpp
// Plain C++ - no HIP syntax
void vector_add(float *a, float *b, float *c, int n) {
    for (int i = 0; i < n; i++) {
        c[i] = a[i] + b[i];
    }
}
```

**Advantages:**
- Fastest path to working pipeline
- No CUDA/HIP header dependencies
- Tests entire toolchain
- Validates custom Vortex lowering works

**Status:** Ready to begin

---

### Phase 2A: HIP Header Testing (2 hours) - Person B (Concurrent)

**Goal:** Quick test to verify HIP syntax works with Polygeist

**Approach:**
1. Create simple HIP kernel using `hip_minimal.h`
2. Test with `--cuda-lower` flag
3. Document how `threadIdx`/`blockIdx` are represented

**Test Command:**
```bash
cgeist simple_hip_kernel.hip \
  --cuda-lower -S \
  -I /home/yaakov/vortex_hip/Polygeist \
  -o kernel.mlir
```

**Expected Output:** Should contain GPU dialect operations or preserved HIP built-ins

**Status:** Can start immediately (parallel with Phase 1)

---

### Phase 2: Full HIP Syntax Support (2-3 weeks) - After Phase 1

**Goal:** Support real HIP kernels with proper syntax

**Approach:**
- Write kernels with full HIP syntax (`__global__`, `threadIdx`, `blockIdx`, etc.)
- Polygeist with `--cuda-lower`: HIP → SCF/GPU
- Adapt custom pass for HIP patterns if needed

**Example:**
```cpp
// Real HIP syntax
__global__ void vector_add(float *a, float *b, float *c, int n) {
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    if (idx < n) {
        c[idx] = a[idx] + b[idx];
    }
}
```

**Prerequisites:**
- Phase 1 pipeline working
- Phase 2A quick test completed
- Understanding of how Polygeist represents HIP constructs

**Status:** Waiting for Phase 1 completion

---

### Phase 3: Optimization (Ongoing) - After Phase 2

**Areas:**
- Warp-aware scheduling
- Shared memory optimization
- Bank conflict avoidance
- Vortex-specific instruction selection

---

## Files and Scripts Reference

### Documentation
- `POLYGEIST_STATUS.md` - **This file** (current consolidated status)
- `hip_minimal.h` - Minimal HIP header for testing
- `HIP_SUPPORT_INVESTIGATION.md` - Full HIP support analysis
- `cuda-lower-investigation/FINDINGS.md` - CUDA lower investigation results

### Build Scripts
- `build-polygeist.sh` - Main build script (LLVM + Polygeist)
- `auto-build-polygeist.sh` - Automated LLVM→Polygeist build
- `monitor-build.sh` - Build progress monitoring

### Test Scripts
- `run-validation-tests.sh` - C++ → SCF validation tests
- `test-scf-to-gpu.sh` - SCF → GPU compatibility tests
- `investigate-hip-support.sh` - HIP support source code analysis

### Test Results
- `validation-results.txt` - Validation test output
- `scf-gpu-results.txt` - SCF→GPU compatibility results

---

## Phase 2B Progress (November 2025)

### Developer A Status (70% Complete)

**✅ Completed:**
- Thread & Block ID mapping (threadIdx, blockIdx) via TLS globals
- Block & Grid dimension queries (blockDim, gridDim)
- Barrier synchronization (gpu.barrier → vx_barrier)
- FileCheck test suite (185 lines, all passing)
- Build infrastructure optimizations

**🔄 In Progress:**
- Metadata extraction design for kernel arguments

**⏸️ Pending:**
- Kernel launch infrastructure (gpu.launch_func lowering)
- Argument struct generation
- End-to-end integration testing

**Branch:** `yaakov/phase-2B-A` (vortex_hip and Polygeist repos)
**Pass Location:** `Polygeist/lib/polygeist/Passes/ConvertGPUToVortex.cpp` (330/520 lines)

**See:** [PHASE2B_A_STATUS.md](PHASE2B_A_STATUS.md) for detailed implementation notes

### Next Immediate Actions

**Developer A:**
1. Finalize metadata extraction approach (function attributes vs global constants)
2. Implement LaunchFuncOpLowering pattern (~150 lines)
3. Test with simple HIP programs
4. Coordinate with Developer B on argument struct layout

**Developer B:**
1. Begin memory operations implementation (Developer B branch)
2. Implement shared memory allocation patterns
3. Coordinate on kernel argument structure

### Decision Points

**After Phase 2A Quick Test:**
- ✅ If HIP works as-is → No Polygeist modifications needed
- ⚠️ If HIP needs tweaks → Plan modifications (likely minimal)

**After Phase 1 Completion:**
- Review Phase 2A findings
- Plan Phase 2 implementation
- Update custom pass for HIP patterns if needed

---

## Key Insights

1. **Polygeist's role is limited to C++/HIP → SCF conversion**
   - All subsequent work is standard MLIR passes
   - Custom work is only GPUToVortexLLVM pass (~500 lines)

2. **No LLVM version dependency issues**
   - Polygeist ecosystem is self-contained
   - Handoff via LLVM IR is version-independent

3. **HIP support likely works out of the box**
   - Polygeist has HIP references in source
   - HIP is CUDA-compatible
   - Clang frontend supports both

4. **Phased approach de-risks development**
   - Phase 1 validates pipeline without HIP complexity
   - Phase 2A tests HIP in parallel (2 hours)
   - Phase 2 adds HIP incrementally

---

## Troubleshooting

### Common Issues

**Issue:** `stddef.h` not found when using `--cuda-lower`
**Cause:** Missing CUDA/HIP headers
**Solution:** Use `-I` flag to point to `hip_minimal.h` or don't use `--nocudainc`

**Issue:** MLIR verification fails
**Cause:** Invalid MLIR dialect operations
**Solution:** Check cgeist output format, verify dialect registration

**Issue:** Linking errors with llvm-vortex
**Cause:** LLVM IR incompatibility
**Solution:** Ensure LLVM IR is standard (avoid Polygeist-specific extensions)

---

## Appendix: Test Examples

### Example 1: Simple C++ → SCF

**Input:**
```c
void loop_sum(int n, int *arr) {
    for (int i = 0; i < n; i++) {
        arr[i] = i * 2;
    }
}
```

**Command:**
```bash
/home/yaakov/vortex_hip/Polygeist/build/bin/cgeist loop.c -S -o loop.mlir
```

**Output:** Contains `scf.for` operations

### Example 2: HIP Kernel with Minimal Header

**hip_kernel.hip:**
```cpp
#include "hip_minimal.h"

__global__ void saxpy(int n, float a, float *x, float *y) {
    int i = blockIdx.x * blockDim.x + threadIdx.x;
    if (i < n) {
        y[i] = a * x[i] + y[i];
    }
}
```

**Command:**
```bash
cgeist hip_kernel.hip \
  --cuda-lower -S \
  -I /home/yaakov/vortex_hip/Polygeist \
  --function=saxpy \
  -o saxpy.mlir
```

---

## Conclusion

**Polygeist is ready for use in the HIP-to-Vortex pipeline.**

- Build is optimized and complete
- Validation tests all passed
- HIP support likely works with minimal or no modifications
- Architecture is clean with no LLVM version conflicts
- Phased implementation plan reduces risk

**Recommended action:** Begin Phase 1 implementation while conducting Phase 2A quick test in parallel.

---

**Status:** ✅ Ready for implementation
**Last Updated:** November 10, 2025
