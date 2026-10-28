# Memory Management

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [docker/Dockerfile](docker/Dockerfile)
- [docker/easel_fast_fasta_parsing.patch](docker/easel_fast_fasta_parsing.patch)
- [docker/jackhmmer_parallel_fasta.patch](docker/jackhmmer_parallel_fasta.patch)
- [docs/known_issues.md](docs/known_issues.md)
- [docs/performance.md](docs/performance.md)

</details>



## Purpose and Scope

This document explains memory management strategies for running AlphaFold 3 model inference on GPUs. It covers memory preallocation, unified memory configurations, XLA memory settings, and hardware-specific optimization strategies for different GPU sizes. For general performance optimization including compilation and data pipeline parallelization, see [8. Performance Optimization](). For hardware requirements and compute capabilities, see [8.1. Hardware Configuration]().

Sources: [docker/Dockerfile:95-98](), [docs/performance.md:1-10]()

## Memory Allocation Strategies

AlphaFold 3 supports two primary memory allocation strategies for GPU execution: preallocation and unified memory. The choice between these strategies depends on the input size (measured in tokens) and available GPU memory.

### Preallocation Strategy

The preallocation strategy reserves a fixed fraction of GPU memory at startup, preventing fragmentation and ensuring consistent performance. This is the default configuration for standard workloads.

**Configuration:**

```sh
XLA_PYTHON_CLIENT_PREALLOCATE=true
XLA_CLIENT_MEM_FRACTION=0.95
```

The `XLA_CLIENT_MEM_FRACTION` value of `0.95` means AlphaFold 3 will preallocate 95% of available GPU memory. This configuration enables folding inputs up to 5,120 tokens on an A100 (80 GB) or H100 (80 GB) [docker/Dockerfile:97-98]().

**Characteristics:**
- **Performance:** Optimal performance with no memory access overhead.
- **Capacity:** Limited to preallocated memory size.
- **Use Case:** Standard inputs (≤ 5,120 tokens) on 80 GB GPUs.
- **OOM Behavior:** Will fail with out-of-memory error if input exceeds capacity.

Sources: [docker/Dockerfile:97-98]()

### Unified Memory Strategy

The unified memory strategy allows GPU memory to spill to host (CPU) RAM when GPU memory is exhausted. This enables processing larger inputs or running on GPUs with less memory at the cost of reduced performance.

**Configuration:**

```sh
XLA_PYTHON_CLIENT_PREALLOCATE=false
TF_FORCE_UNIFIED_MEMORY=true
XLA_CLIENT_MEM_FRACTION=3.2
```

The `XLA_CLIENT_MEM_FRACTION` value of `3.2` allows the system to use up to 3.2× the physical GPU memory by spilling to host RAM.

**Characteristics:**
- **Performance:** Slower than preallocation due to host memory access.
- **Capacity:** Can handle inputs larger than GPU memory.
- **Use Case:** Large inputs (> 5,120 tokens) or smaller GPUs (< 80 GB).
- **OOM Behavior:** Requires sufficient host RAM; will use swap if needed.

Sources: [docker/Dockerfile:95-98]()

### Memory Strategy Selection

```mermaid
graph TD
    Input["InputTokenCount"] --> CheckSize{"TokenCount <= 5,120?"}
    CheckSize -->|Yes| CheckGPU{"GPUMemory >= 80 GB?"}
    CheckSize -->|No| UseUnified["UseUnifiedMemory<br/>XLA_PYTHON_CLIENT_PREALLOCATE=false<br/>TF_FORCE_UNIFIED_MEMORY=true<br/>XLA_CLIENT_MEM_FRACTION=3.2"]
    
    CheckGPU -->|Yes| UsePrealloc["UsePreallocation<br/>XLA_PYTHON_CLIENT_PREALLOCATE=true<br/>XLA_CLIENT_MEM_FRACTION=0.95"]
    CheckGPU -->|No| CheckSmallGPU{"GPUMemory >= 40 GB?"}
    
    CheckSmallGPU -->|Yes| UseUnifiedSmall["UseUnifiedMemory<br/>Adjust pair_transition_shard_spec"]
    CheckSmallGPU -->|No| UseUnifiedVerySmall["UseUnifiedMemory<br/>LimitedTokenCapacity"]
    
    UsePrealloc --> Result["OptimalPerformance"]
    UseUnified --> Result2["ReducedPerformanceHigherCapacity"]
    UseUnifiedSmall --> Result3["ReducedPerformanceUpTo4352Tokens"]
    UseUnifiedVerySmall --> Result4["ReducedPerformanceUpTo1280TokensV100"]
```

Sources: [docker/Dockerfile:95-98]()

## XLA Memory Configuration

### Core Environment Variables

AlphaFold 3 uses several XLA-specific environment variables to control memory allocation and GPU behavior:

| Environment Variable | Purpose | Default Value | Usage |
|---------------------|---------|---------------|--------|
| `XLA_PYTHON_CLIENT_PREALLOCATE` | Enable/disable memory preallocation | `true` | Set to `false` for unified memory [docker/Dockerfile:97]() |
| `XLA_CLIENT_MEM_FRACTION` | Fraction of GPU memory to use | `0.95` | Higher values allow more memory usage [docker/Dockerfile:98]() |
| `TF_FORCE_UNIFIED_MEMORY` | Enable unified memory | Not set | Set to `true` for unified memory |
| `XLA_FLAGS` | Compiler optimization flags | See below | Additional flags for specific GPUs [docker/Dockerfile:95]() |

Sources: [docker/Dockerfile:95-98]()

### Required XLA Flags

#### Standard Configuration

The following XLA flag is required to work around a known XLA compilation time issue:

```sh
XLA_FLAGS="--xla_gpu_enable_triton_gemm=false"
```

This flag is set by default in the provided `Dockerfile` [docker/Dockerfile:95]() and must be present for all GPU configurations.

#### CUDA Capability 7.x GPUs

GPUs with CUDA Capability 7.x (e.g., NVIDIA V100) require an additional XLA flag to avoid numerical issues:

```sh
XLA_FLAGS="--xla_disable_hlo_passes=custom-kernel-fusion-rewriter"
```

This flag disables the custom kernel fusion rewriter, which produces incorrect results on these GPUs [docs/known_issues.md:5-8](). When using this flag, you must also set `--flash_attention_implementation=xla` in `run_alphafold.py`.

Sources: [docker/Dockerfile:95-98](), [docs/known_issues.md:3-8]()

### XLA Configuration and Hardware Validation

The following diagram illustrates how the system validates hardware compatibility and applies memory-related flags during initialization.

```mermaid
graph TB
    subgraph "ValidationSpace"
        Main["run_alphafold.py"] --> CheckInference["--run_inference=true"]
        CheckInference --> GetDevices["jax.local_devices()"]
        GetDevices --> CheckCapability["Check compute_capability"]
        CheckCapability --> ValidateCompat{"Capability < 6.0?"}
        ValidateCompat -->|Yes| Error1["ValueError: Minimum capability 6.0"]
        ValidateCompat -->|No| CheckV100{"7.0 <= Capability < 8.0?"}
        
        CheckV100 -->|Yes| ValidateXLAFlags["Validate XLA_FLAGS"]
        ValidateXLAFlags --> CheckFlagSet{"XLA_FLAGS contains custom-kernel-fusion-rewriter?"}
        CheckFlagSet -->|No| Error2["ValueError: XLA_FLAGS required for V100"]
        CheckFlagSet -->|Yes| CheckFlashAttn{"flash_attention_implementation == 'xla'?"}
        CheckFlashAttn -->|No| Error3["ValueError: Must use xla attention"]
        CheckFlashAttn -->|Yes| Proceed["Proceed with ModelRunner"]
        CheckV100 -->|No| Proceed
    end
    
    subgraph "EnvironmentSpace"
        EnvXLAPre["XLA_PYTHON_CLIENT_PREALLOCATE"]
        EnvXLAFrac["XLA_CLIENT_MEM_FRACTION"]
        EnvXLAFlags["XLA_FLAGS"]
        EnvTFUnified["TF_FORCE_UNIFIED_MEMORY"]
    end
    
    ValidateXLAFlags -.reads.-> EnvXLAFlags
    Proceed -.initializes.-> ModelRunner["ModelRunner"]
```

Sources: [docker/Dockerfile:95-98](), [docs/known_issues.md:3-8]()

## Hardware-Specific Configurations

### NVIDIA A100 (80 GB) - Default Configuration

The default configuration is optimized for A100 (80 GB) GPUs.

**Memory Settings:**
```sh
XLA_PYTHON_CLIENT_PREALLOCATE=true
XLA_CLIENT_MEM_FRACTION=0.95
```

**Capacity:**
- Maximum tokens: 5,120 (with default preallocation) [docker/Dockerfile:96-98]().
- Can handle larger inputs with unified memory.

Sources: [docker/Dockerfile:95-98]()

### NVIDIA A100 (40 GB)

Running on A100 (40 GB) requires unified memory and model configuration adjustments.

**Memory Settings:**
```sh
XLA_PYTHON_CLIENT_PREALLOCATE=false
TF_FORCE_UNIFIED_MEMORY=true
XLA_CLIENT_MEM_FRACTION=3.2
```

**Model Configuration:**
Adjust `pair_transition_shard_spec` in the model configuration to reduce memory usage.

**Capacity:**
- Maximum tokens: 4,352 (with unified memory and sharding).

Sources: [docker/Dockerfile:95-98]()

### NVIDIA H100 (80 GB)

H100 (80 GB) uses the same configuration as A100 (80 GB) with improved performance.

**Performance Comparison:**

| Tokens | A100 80 GB (seconds) | H100 80 GB (seconds) | Speedup |
|--------|---------------------|---------------------|---------|
| 1024   | 62                  | 34                  | 1.8×    |
| 2048   | 275                 | 144                 | 1.9×    |
| 5120   | 2547                | 1416                | 1.8×    |

Sources: [docker/Dockerfile:95-98]()

### NVIDIA V100

V100 GPUs (CUDA Capability 7.x) require special XLA flags and have limited capacity [docs/known_issues.md:5-8]().

**XLA Flags:**
```sh
XLA_FLAGS="--xla_disable_hlo_passes=custom-kernel-fusion-rewriter"
```

**Flash Attention:**
- Must use `--flash_attention_implementation=xla`.

**Capacity:**
- Maximum tokens: 1,280 (with unified memory).

Sources: [docker/Dockerfile:95-98](), [docs/known_issues.md:3-8]()

## Compilation Buckets and Memory

### Bucket Mechanism

AlphaFold 3 uses compilation buckets to avoid recompiling the model for every input size. When featurizing an input, the system determines the smallest bucket that accommodates the input and pads it accordingly.

**Bucket Selection Process:**

```mermaid
graph LR
    Input["InputTokenCount"] --> FindBucket["Find smallest bucket >= count"]
    FindBucket --> CheckExists{"Bucket exists?"}
    CheckExists -->|Yes| Pad["Pad input to bucket size"]
    CheckExists -->|No| CreateNew["Create new bucket<br/>(recompilation)"]
    
    Pad --> CheckCompiled{"Model compiled?"}
    CheckCompiled -->|Yes| UseCache["Use cached compilation"]
    CheckCompiled -->|No| Compile["Compile model"]
    
    CreateNew --> Compile
    UseCache --> Inference["Run inference"]
    Compile --> CacheStore["Store in JAX cache<br/>--jax_compilation_cache_dir"]
    CacheStore --> Inference
```

Sources: [docker/Dockerfile:95-98]()

## Troubleshooting Memory Issues

### Out-of-Memory (OOM) Errors

| Scenario | Solution |
|----------|----------|
| Input ≤ 5,120 tokens on A100 80 GB | Ensure `XLA_PYTHON_CLIENT_PREALLOCATE=true` [docker/Dockerfile:97](). |
| Input > 5,120 tokens | Enable unified memory: `XLA_PYTHON_CLIENT_PREALLOCATE=false` [docker/Dockerfile:97](). |
| Using A100 40 GB | Enable unified memory + adjust `pair_transition_shard_spec`. |
| Using V100 | Set `XLA_FLAGS` to disable `custom-kernel-fusion-rewriter` [docs/known_issues.md:8](). |

### Performance Degradation

**Common causes:**
1. **Unified memory enabled unnecessarily:** Check if input fits in GPU memory with preallocation.
2. **Excessive padding:** Review bucket configuration to reduce padding overhead.
3. **Incorrect XLA flags:** Ensure Triton GEMM is disabled (`--xla_gpu_enable_triton_gemm=false`) [docker/Dockerfile:95]().

Sources: [docker/Dockerfile:95-98](), [docs/known_issues.md:3-8]()

---