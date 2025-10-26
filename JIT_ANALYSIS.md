# JIT Runtime Strategy - Hybrid Self-Optimizing Unikernel

**Date**: 2025-10-26
**Branch**: feat/true-jit-unikernel
**Goal**: Build self-optimizing unikernel with LLVM JIT that converges from 60MB to 2-5MB

## 🎯 Core Philosophy: "Grow to Shrink"

**Inspiration**: 68000 self-sufficient programs + PyPy warmup snapshots + LuaJIT tiered compilation

**Strategy**:
1. **Start BIG** (60MB): Full LLVM statically linked, everything in LLVM IR (interpreted)
2. **Profile everything**: Track all functions (app + LLVM internals + libc)
3. **JIT hot paths**: O0 → O1 → O2 → O3 based on call count + cycle profiling
4. **Eliminate dead code**: Remove unused LLVM passes, unreached functions
5. **Converge**: After N boots → 2-5MB optimized appliance binary
6. **Persist**: Snapshot to FAT16, next boot loads optimized version

**Why JIT for TinyLlama?**
- Matrix multiply: JIT specializes for actual matrix sizes (e.g., always 512×512)
- Vectorization: JIT uses actual CPU features (AVX2/AVX512) detected at boot
- Devirtualization: JIT inlines callbacks after observing actual types
- **Expected gain**: 2-5× on inference hot paths vs generic AOT O3

---

## 📊 Current Implementation Analysis

### File: `kernel/jit_llvm18.cpp` (282 lines)

**Purpose**: LLVM 18 OrcJIT wrapper with profiling and adaptive optimization

**Interface**: `kernel/jit_interface.h` (C API for kernel integration)

---

## 🔗 LLVM Dependencies

### Core LLVM Headers Required:
```cpp
#include <llvm/ExecutionEngine/Orc/LLJIT.h>          // Main JIT engine
#include <llvm/IR/LLVMContext.h>                     // IR context
#include <llvm/IR/Module.h>                          // Module representation
#include <llvm/IRReader/IRReader.h>                  // Parse IR from file
#include <llvm/Support/SourceMgr.h>                  // Error diagnostics
#include <llvm/Support/TargetSelect.h>               // Native target init
#include <llvm/Support/MemoryBuffer.h>               // Memory IR loading
```

### Key LLVM Classes Used:
- **LLJIT**: Main JIT execution engine (Orc v2)
- **LLVMContext**: IR parsing and module context
- **ThreadSafeModule**: Multi-threaded module wrapper
- **MemoryBuffer**: In-memory bitcode loading
- **SMDiagnostic**: Error reporting

### LLVM Initialization Required:
```cpp
InitializeNativeTarget();           // x86 codegen
InitializeNativeTargetAsmPrinter(); // Assembly output
InitializeNativeTargetAsmParser();  // Assembly parsing
```

---

## 📦 C++ Standard Library Dependencies

### Containers & Smart Pointers:
```cpp
std::unique_ptr<LLJIT>                              // JIT engine ownership
std::unique_ptr<LLVMContext>                        // Context ownership
std::unordered_map<std::string, FunctionProfile>   // Function tracking
std::string                                         // Error messages, names
std::vector                                         // (in struct definitions)
```

### Memory Management:
- `std::make_unique<T>()` - Smart pointer factory
- `std::move()` - Move semantics
- `new` / `delete` - Heap allocation

### Standard Headers:
```cpp
#include <memory>        // unique_ptr, make_unique
#include <string>        // std::string
#include <unordered_map> // std::unordered_map
#include <vector>        // std::vector
#include <cstring>       // strcmp, etc.
```

---

## 🎯 API Functions (11 total)

### Lifecycle:
1. `jit_create()` - Create JIT context
2. `jit_destroy()` - Cleanup

### Module Loading:
3. `jit_load_bitcode(path)` - Load from file
4. `jit_load_bitcode_memory(data, size)` - Load from memory
5. `jit_unload_module()` - Unload module

### Function Management:
6. `jit_find_function(name)` - Lookup function pointer
7. `jit_recompile_function(name, opt_level)` - Reoptimize
8. `jit_get_function_info(name, info)` - Get profiling data
9. `jit_list_functions(infos, max)` - List all functions

### Profiling:
10. `jit_record_call(name, cycles)` - Record execution
11. `jit_auto_optimize(name)` - Auto-reoptimize after 100 calls

### Utilities:
12. `jit_get_stats()` - Global stats
13. `jit_get_last_error()` - Error message

---

## 💾 Data Structures

### JITContext (per-instance state):
```cpp
struct JITContext {
    std::unique_ptr<LLJIT> jit;                              // ~50KB+
    std::unique_ptr<LLVMContext> context;                    // ~10KB+
    std::string last_error;                                  // Variable
    JITStats stats;                                          // 40 bytes
    std::unordered_map<std::string, FunctionProfile> profiles; // ~N*200 bytes
};
```

### FunctionProfile (per-function):
```cpp
struct FunctionProfile {
    std::string name;               // ~32 bytes
    void* code_ptr;                 // 4 bytes
    uint64_t call_count;            // 8 bytes
    uint64_t total_cycles;          // 8 bytes
    uint32_t code_size;             // 4 bytes
    JITOptLevel current_opt_level;  // 4 bytes
};
// Total: ~60 bytes + string overhead
```

---

## 🧬 LLVM-libc Integration

**Key Insight**: Use LLVM's libc instead of custom kernel_lib/stdlib.c

**Why LLVM-libc?**
- Written in **pure C** (no inline assembly) → fully JIT-optimizable
- All libc functions compiled to LLVM IR → can be specialized
- Vectorization, inlining, constant propagation work on libc calls too!

**Example**: `memcpy` specialization
```c
// Generic AOT memcpy: handles any size, alignment
void* memcpy(void* dst, void* src, size_t n);

// JIT observes: ALWAYS called with n=512, 64-byte aligned
// → Generates specialized version:
void* memcpy_512_aligned64(void* dst, void* src) {
    // Unrolled AVX2 copy (8×64 bytes)
    // No size check, no alignment check
    // 10× faster than generic version
}
```

**Strategy**:
1. Link with `llvm-libc` static library (instead of custom stdlib.c)
2. Compile llvm-libc to LLVM IR (not native)
3. JIT optimizes app + libc together → cross-module inlining!

**Files to replace**:
```
kernel_lib/memory/string.c   → llvm-libc (memcpy, memset, strlen)
kernel_lib/memory/malloc.c   → llvm-libc allocator
kernel_lib/stdlib.c          → llvm-libc (most functions)
```

**What stays custom**:
- I/O (VGA, serial, keyboard) - hardware-specific
- CPU features (rdtsc, cpuid) - privileged instructions
- JIT runtime itself

---

## 🔄 Hybrid Strategy: AOT + JIT Convergence

### Phase 1: Full LLVM (Boot 1-10) - 60MB
```
┌─────────────────────────────────────────────┐
│  Everything in LLVM IR (bitcode)            │
│  ├── TinyLlama inference code (.bc)         │
│  ├── llvm-libc functions (.bc)              │
│  └── Runtime helpers (.bc)                  │
│                                             │
│  Execution: LLVM Interpreter (slow)         │
│  Profiling: Track ALL function calls        │
│  Coverage: Mark which code paths executed   │
└─────────────────────────────────────────────┘
```

### Phase 2: Tiered JIT (Boot 10-100) - 30MB
```
Profiling thresholds:
  10 calls:    JIT compile to O0 (fast compilation)
  100 calls:   Recompile to O1 (balanced)
  1000 calls:  Recompile to O2 (aggressive)
  10000 calls: Recompile to O3 + specialization

Hot path example (matrix_multiply):
  Boot 1:   Interpreted       (~1000 ms)
  Boot 10:  O0 JIT            (~500 ms)
  Boot 50:  O2 JIT specialized (~100 ms)  ← 10× speedup!
  Boot 100: O3 + AVX2         (~50 ms)   ← 20× vs interpreted
```

### Phase 3: Dead Code Elimination (Boot 100-500) - 10MB
```
Coverage analysis finds:
  - 40% of LLVM optimizer passes NEVER used
  - 30% of llvm-libc functions NEVER called
  - 50% of app helper functions NEVER reached

Action: Relink binary WITHOUT dead code
  → Binary shrinks from 60MB → 10MB
```

### Phase 4: Snapshot Export (Boot 500+) - 2-5MB
```
JIT-optimized code → Export as native AOT binary

/boot/snapshots/
  bareflow_boot001.img   (60MB - initial, full LLVM + IR)
  bareflow_boot100.img   (10MB - dead code removed, O3 hot paths)
  bareflow_final.img     (2-5MB - pure native, LLVM removed)

Final binary = JIT-optimized native code only
Can be used as regular unikernel (no JIT runtime needed)
```

### Phase 5: Hardware Adaptation (Optional)
```
If booted on NEW hardware:
  - Detect new CPU features (cpuid)
  - Re-enable JIT for hot paths
  - Recompile with new ISA extensions
  - Converge again → new optimized snapshot

Example: Boot on Ryzen (AVX2) → Intel Xeon (AVX512)
  → Automatic recompilation with -mavx512
```

---

## ⚠️ Bare-Metal Challenges

### 1. C++ Standard Library
**Problem**: No `std::string`, `std::unordered_map`, `std::unique_ptr`
**Solution**:
- Replace `std::string` → `char[64]` (fixed-size)
- Replace `std::unordered_map` → Custom hash table or linear array
- Replace `std::unique_ptr` → Raw pointers with manual cleanup
- Implement `operator new/delete` → Custom allocator

### 2. LLVM Dependencies
**Problem**: LLVM requires C++ runtime, exceptions, RTTI
**Solution**:
- Build LLVM with `-DLLVM_ENABLE_RTTI=OFF -DLLVM_ENABLE_EH=OFF`
- Static link LLVM libs (~10-50MB compressed)
- Provide custom allocator for LLVM (`operator new/delete`)

### 3. Memory Footprint
**Problem**: LLVM JIT needs significant heap space
**Estimated Requirements**:
- LLVM JIT engine: ~50-100KB baseline
- IR parsing: ~10-50KB per module
- Code generation: ~5-20KB per function
- Working memory: ~1-2MB recommended

**Total Estimate**: **2-5MB heap minimum**

### 4. File I/O
**Problem**: `jit_load_bitcode(path)` needs filesystem
**Solution**:
- Use `jit_load_bitcode_memory()` exclusively
- Embed bitcode in binary or load from FAT16
- Remove file-based API for bare-metal

### 5. Threading
**Problem**: `ThreadSafeModule` assumes threading support
**Solution**:
- Single-threaded mode only
- Remove `ThreadSafeModule` wrapper (use raw `Module*`)
- No multi-threaded compilation

---

## 🔧 Proposed Bare-Metal Design

### Minimal API (8 functions):
```c
// Lifecycle
jit_context_t* jit_init(void* heap, size_t heap_size);
void jit_shutdown(jit_context_t* ctx);

// Module loading (memory only)
int jit_load_ir(jit_context_t* ctx, const uint8_t* ir_data, size_t size);

// Function lookup
void* jit_get_function(jit_context_t* ctx, const char* name);

// Recompilation
int jit_recompile(jit_context_t* ctx, const char* name, int opt_level);

// Profiling
void jit_profile_call(jit_context_t* ctx, const char* name, uint64_t cycles);
int jit_should_reoptimize(jit_context_t* ctx, const char* name);

// Stats
void jit_get_stats(jit_context_t* ctx, jit_stats_t* stats);
```

### Simplified Data Structures:
```c
#define JIT_MAX_FUNCTIONS 32
#define JIT_NAME_MAX 32

typedef struct {
    char name[JIT_NAME_MAX];
    void* code_ptr;
    uint64_t call_count;
    uint64_t total_cycles;
    uint8_t opt_level;
} jit_function_t;

typedef struct {
    void* llvm_jit;          // Opaque LLVM handle
    void* llvm_context;      // Opaque LLVM context
    char last_error[128];
    jit_function_t functions[JIT_MAX_FUNCTIONS];
    int function_count;
    uint64_t total_compiles;
} jit_context_t;
```

---

## 📏 Memory Budget

### Userspace Measurements (LLVM 18.1.8):

**Dynamic Linking** (test_jit_minimal):
```
Binary size:       31KB
Shared library:    118MB (libLLVM-18.so.1)
Total:             ~118MB (not viable for bare-metal)
```

**Static Library Sizes** (individual archives):
```
Core JIT components:
  libLLVMOrcJIT.a:        5.1MB
  libLLVMOrcTargetProcess.a: 368KB
  libLLVMOrcDebugging.a:  240KB
  libLLVMOrcShared.a:     96KB

X86 Target (32-bit):
  libLLVMX86CodeGen.a:    11MB
  libLLVMX86Desc.a:       5.2MB
  libLLVMX86AsmParser.a:  964KB
  libLLVMX86Disassembler.a: 2.5MB

Core Infrastructure:
  libLLVMCodeGen.a:       18MB
  libLLVMCore.a:          8.5MB
  libLLVMAnalysis.a:      11MB
  libLLVMSupport.a:       (included in above)
-------------------------------------------
Estimated total:         ~60MB unstripped
```

### Conservative Estimate (Bare-Metal):

**With aggressive optimization** (-Os, strip, LTO, only X86 i686):
```
LLVM static libs:  ~2-5MB (stripped, MinSizeRel, X86 only)
JIT runtime:       ~200KB (baseline + wrappers)
Heap (working):    ~2MB (recommended)
Code cache:        ~500KB (generated code)
-------------------------------------------
Total:             ~5-8MB
```

**Optimistic target** (with custom LLVM build):
```
LLVM static libs:  ~500KB-1MB (MinSizeRel, X86 i686 only, no unused features)
JIT runtime:       ~100KB (minimal wrapper)
Heap (working):    ~1-2MB
Code cache:        ~500KB
-------------------------------------------
Total:             ~2-4MB
```

### Target for Unikernel:
- Binary size: <2MB (LLVM + app, first iteration)
- Optimized target: <500KB (with custom LLVM build)
- Runtime heap: 2MB dedicated
- Total footprint: ~4-6MB (initial), ~2.5MB (optimized)

---

## ✅ Revised Roadmap: Hybrid Self-Optimizing Unikernel

### Phase 3.2 - Full Static Link (Week 3) ✅ NEXT
**Goal**: 60MB bootable binary with full LLVM + LLVM-libc

1. **Static link ALL LLVM archives**:
   ```bash
   # Link everything (we don't care about size yet!)
   clang++-18 -m32 -static -nostdlib \
     -Wl,--whole-archive \
     /usr/lib/llvm-18/lib/libLLVM*.a \
     -Wl,--no-whole-archive \
     -o bareflow_full.elf
   ```

2. **Integrate LLVM-libc** (replace kernel_lib/stdlib):
   - Build llvm-libc to LLVM IR (.bc files)
   - Link with app IR (cross-module optimization)
   - Keep custom I/O (VGA, serial)

3. **Test in userspace first**:
   - Verify 60MB binary runs
   - Test LLVM Interpreter mode
   - Validate basic JIT compilation

### Phase 3.3 - LLVM Interpreter + Profiler (Week 4)
**Goal**: Execute TinyLlama from LLVM IR, profile everything

1. **Compile app to LLVM IR** (not native):
   ```bash
   clang-18 -emit-llvm -c tinyllama.c -o tinyllama.bc
   clang-18 -emit-llvm -c llvm-libc/*.c -o libc.bc
   llvm-link-18 tinyllama.bc libc.bc -o app_full.bc
   ```

2. **Implement interpreter mode**:
   - Use `llvm::Interpreter` or `lli` functionality
   - Execute IR directly (slow, but works)
   - Instrument all function calls

3. **Profile tracking**:
   - Hook every function entry/exit
   - Record: call_count, total_cycles, arguments
   - Store profiles to FAT16 at shutdown

### Phase 3.4 - Tiered JIT (Week 5)
**Goal**: Adaptive compilation based on profiling

1. **JIT compilation thresholds**:
   - 10 calls → JIT O0
   - 100 calls → JIT O1
   - 1000 calls → JIT O2 + specialization
   - 10000 calls → JIT O3 + vectorization

2. **Code swapping**:
   - Replace interpreter call with native JIT code
   - Atomic pointer update (no locks needed in unikernel)

3. **Specialization**:
   - Detect constant arguments (e.g., matrix size always 512)
   - Generate specialized versions
   - Inline across app + libc boundaries

### Phase 3.5 - Dead Code Elimination (Week 6)
**Goal**: Remove unused code, shrink binary

1. **Coverage analysis**:
   - Mark all reachable functions
   - Identify unreached LLVM passes
   - Find unused libc functions

2. **Selective relinking**:
   - Generate new linker script
   - Exclude dead symbols
   - Measure size reduction (60MB → ~10MB)

3. **Snapshot persistence**:
   - Write optimized binary to FAT16
   - Load on next boot instead of full version

### Phase 3.6 - Native Export (Week 7)
**Goal**: Export JIT-optimized code as pure AOT binary

1. **Freeze optimizations**:
   - All hot paths compiled to native
   - No more interpreter needed
   - LLVM runtime can be removed

2. **Final binary**:
   - Pure native code (2-5MB)
   - Can boot without JIT runtime
   - Optimal for THIS hardware + workload

3. **Hardware adaptation**:
   - If booted on new CPU → re-enable JIT
   - Recompile with new ISA features
   - Converge again

---

## 🎯 Success Criteria (Revised for Hybrid Strategy)

### Phase 3.2 (Static Link):
- ✅ 60MB bootable binary with full LLVM
- ✅ LLVM-libc integrated (replace custom stdlib)
- ✅ Boot in QEMU bare-metal
- ✅ LLVM Interpreter executes simple function

### Phase 3.3 (Interpreter + Profiler):
- ✅ TinyLlama runs from LLVM IR (interpreted)
- ✅ All function calls tracked with cycle counts
- ✅ Profiles persisted to FAT16
- ✅ Coverage map identifies dead code

### Phase 3.4 (Tiered JIT):
- ✅ Hot path JIT compilation (O0 → O3)
- ✅ Measure >2× speedup on matrix_multiply after 100 boots
- ✅ Specialization works (constant propagation for matrix sizes)
- ✅ Cross-module inlining (app + libc)

### Phase 3.5 (Dead Code Elimination):
- ✅ Binary shrinks from 60MB → <10MB
- ✅ Identify >40% dead LLVM code
- ✅ Snapshot persistence works
- ✅ Boot from optimized snapshot

### Phase 3.6 (Native Export):
- ✅ Final binary <5MB (pure native, no LLVM runtime)
- ✅ Performance equivalent to hand-optimized AOT
- ✅ Can re-enable JIT on new hardware
- ✅ Total speedup >5× vs initial interpreted version

---

## 🧪 Userspace Test Results

### Test: test_jit_minimal.cpp
**Date**: 2025-10-26
**LLVM Version**: 18.1.8

**Test Code**:
- Creates simple `int add(int, int)` function via IRBuilder
- Compiles with LLJIT
- Executes: `add(42, 58) = 100`

**Results**:
```
✓ Compilation: SUCCESS (clang++-18 -O2)
✓ Execution: SUCCESS (add(42, 58) = 100)
✓ Binary size: 31KB (dynamic linking)
✓ Shared lib: 118MB (libLLVM-18.so.1)
✗ Static linking: FAILED (no monolithic libLLVM-18.a)
```

**Conclusions**:
1. ✅ LLVM 18 JIT works perfectly in userspace
2. ✅ OrcJIT API is stable and functional
3. ⚠️ Dynamic linking not viable for bare-metal (~118MB overhead)
4. ⚠️ Static linking requires custom LLVM build or manual archive linking
5. 📊 Estimated bare-metal footprint: **2-5MB** (conservative) or **500KB-1MB** (optimized)

**Next Phase**: Design custom allocator and C++ runtime stubs for bare-metal LLVM integration.

---

**Created**: 2025-10-26
**Updated**: 2025-10-26 (with userspace measurements)
**For**: Phase 3 JIT Runtime Implementation
