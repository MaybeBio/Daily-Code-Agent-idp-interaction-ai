# Hardware Configuration

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [docs/known_issues.md](docs/known_issues.md)
- [docs/performance.md](docs/performance.md)
- [run_alphafold.py](run_alphafold.py)
- [run_alphafold_test.py](run_alphafold_test.py)

</details>



This page details the GPU, CPU, and memory hardware requirements for running AlphaFold 3. It covers officially supported GPU configurations, compute capability requirements, CPU allocation recommendations, and performance characteristics across different hardware setups.

For memory management strategies specific to different GPU sizes, see [Memory Management](#8.2). For optimization of compilation and execution, see [Compilation and Execution](#8.3).

Sources: [docs/performance.md:1-10](), [docs/known_issues.md:1-8]()

## GPU Requirements

### Officially Supported Configurations

AlphaFold 3 has been extensively tested and verified for numerical accuracy and throughput efficiency on the following GPU configurations:

| GPU Model | Memory | Max Token Support | Status |
|-----------|--------|------------------|--------|
| NVIDIA A100 | 80 GB | 5,120 tokens | Officially supported |
| NVIDIA H100 | 80 GB | 5,120 tokens | Officially supported |

These configurations represent the primary deployment targets for the codebase. The repository is optimized to maximize throughput when running on a single GPU of these types, achieving superior efficiency compared to multi-GPU setups.

**Performance Comparison: A100 80GB vs H100 80GB**

Title: Inference Performance by Input Size
```mermaid
graph TB
    subgraph Input["Input Size Categories"]
        Small["Small<br/>1024 tokens"]
        Medium["Medium<br/>2048-3072 tokens"]
        Large["Large<br/>4096-5120 tokens"]
    end
    
    subgraph A100["NVIDIA A100 80GB<br/>Compile-free inference time"]
        A100_1024["62 seconds"]
        A100_2048["275 seconds"]
        A100_3072["703 seconds"]
        A100_4096["1434 seconds"]
        A100_5120["2547 seconds"]
    end
    
    subgraph H100["NVIDIA H100 80GB<br/>Compile-free inference time"]
        H100_1024["34 seconds<br/>1.8x faster"]
        H100_2048["144 seconds<br/>1.9x faster"]
        H100_3072["367 seconds<br/>1.9x faster"]
        H100_4096["774 seconds<br/>1.9x faster"]
        H100_5120["1416 seconds<br/>1.8x faster"]
    end
    
    Small -.-> A100_1024
    Small -.-> H100_1024
    Medium -.-> A100_2048
    Medium -.-> H100_2048
    Medium -.-> A100_3072
    Medium -.-> H100_3072
    Large -.-> A100_4096
    Large -.-> H100_4096
    Large -.-> A100_5120
    Large -.-> H100_5120
```

Sources: [docs/performance.md:166-203]()

### Compute Capability Requirements

**Minimum Compute Capability:** CUDA Compute Capability **8.0 or greater**.

This requirement excludes older GPU architectures:
- **Supported:** Ampere (A100, A30), Ada (RTX 4090), Hopper (H100), and newer architectures.
- **Not Recommended:** Volta (V100, compute capability 7.0), Pascal (P100, compute capability 6.0).

Numerical accuracy has been specifically verified on NVIDIA A100 and H100 GPUs. When selecting a JAX backend in `run_alphafold.py`, the device is queried via `jax.local_devices()[0]` [run_alphafold_test.py:161-161](), supporting `JaxBackend` options (`CPU`, `GPU`, `MPS`) [run_alphafold.py:72-77]().

Sources: [run_alphafold.py:72-77](), [run_alphafold_test.py:159-163](), [docs/performance.md:236-257]()

### Hardware-to-Pipeline Stage Mapping

Title: Resource Allocation Mapped to Code Entities
```mermaid
graph LR
    subgraph Hardware["Hardware Resources"]
        GPU["GPU<br/>NVIDIA A100/H100 80GB<br/>jax.local_devices"]
        CPU["CPU<br/>12+ cores<br/>jackhmmer_n_cpu"]
        RAM["RAM<br/>64+ GB"]
        Disk["Disk Storage<br/>1 TB SSD"]
    end
    
    subgraph Pipeline["Pipeline Code Entities"]
        DataPipeline["Data Pipeline<br/>run_alphafold.py --run_inference=false<br/>CPU + RAM intensive"]
        Featurization["Featurization<br/>alphafold3.data.featurisation<br/>CPU bound"]
        Inference["Model Inference<br/>ModelRunner<br/>run_alphafold_test.py<br/>GPU intensive"]
    end
    
    CPU --> DataPipeline
    RAM --> DataPipeline
    Disk --> DataPipeline
    
    CPU --> Featurization
    RAM --> Featurization
    
    GPU --> Inference
```

Sources: [run_alphafold.py:101-112](), [run_alphafold_test.py:159-163](), [docs/performance.md:19-25]()

## CPU and Memory Requirements

### CPU Allocation

**Minimum:** 12 CPU cores (recommended for single-chain predictions).

**Optimal Configuration:** The CPU requirements scale with parallelization strategy:

- **Base usage:** Each `Jackhmmer` or `Nhmmer` process uses dedicated CPU cores configured via command line flags [run_alphafold.py:114-138]().
- **Database parallelization:** When using sharded databases, total cores = `n_cpu × max_parallel_shards × num_databases_searched_in_parallel`. AlphaFold 3 runs genetic search against multiple databases in parallel [docs/performance.md:79-81]().

**Example calculation for sharded databases:**
```
Total cores = (2 CPUs per process) × (16 parallel shards) × (4 protein databases)
           = 128 cores for protein chains
```

Sources: [run_alphafold.py:114-138](), [docs/performance.md:70-162]()

### RAM Requirements

**Minimum:** 64 GB.

**Recommended:** 170 GB.

RAM usage patterns:
- **Data pipeline stage:** Can require substantial RAM for sequences with deep MSAs during `Jackhmmer` or `Nhmmer` execution beyond the recommended 64 GB [docs/performance.md:82-83]().
- **Model inference:** GPU memory is the primary constraint; host RAM usage is minimal during this stage.
- **Peak usage:** Occurs during genetic database searches, particularly for highly homologous sequences.

Sources: [docs/performance.md:82-83]()

### Disk Storage

**Total requirement:** Up to 1 TB for genetic databases.

**Storage type:** SSD strongly recommended for optimal performance. The disk speed directly influences genetic search speed during the data pipeline stage [docs/performance.md:74-78](). Sharding scripts assist in managing SSD-backed database storage [docs/performance.md:104-110]().

Sources: [docs/performance.md:76-78]()

## Hardware Configuration Selection

Title: Hardware Selection Logic with Code Configurations
```mermaid
flowchart TD
    Start["Input Requirements"]
    
    TokenSize{"Maximum<br/>Token Size?"}
    GPUAvail{"Available<br/>GPU?"}
    
    A100_80["Configuration: A100 80GB<br/>XLA_PYTHON_CLIENT_PREALLOCATE=true<br/>XLA_CLIENT_MEM_FRACTION=0.95<br/>Max: 5120 tokens"]
    
    H100_80["Configuration: H100 80GB<br/>XLA_PYTHON_CLIENT_PREALLOCATE=true<br/>XLA_CLIENT_MEM_FRACTION=0.95<br/>Max: 5120 tokens<br/>~1.8x faster than A100"]
    
    A100_40["Configuration: A100 40GB<br/>XLA_PYTHON_CLIENT_PREALLOCATE=false<br/>TF_FORCE_UNIFIED_MEMORY=true<br/>XLA_CLIENT_MEM_FRACTION=3.2<br/>Max: 4352 tokens"]
    
    V100["Configuration: V100<br/>XLA_FLAGS with custom-kernel-fusion-rewriter disabled<br/>TF_FORCE_UNIFIED_MEMORY=true<br/>Max: 1280 tokens"]
    
    P100["Configuration: P100<br/>No special configuration<br/>Max: 1024 tokens"]
    
    Unsupported["Unsupported<br/>Consider cloud GPU rental<br/>or reduce input size"]
    
    Start --> TokenSize
    
    TokenSize -->|"≤5120 tokens"| GPUAvail
    TokenSize -->|">5120 tokens"| Unsupported
    
    GPUAvail -->|"A100 80GB"| A100_80
    GPUAvail -->|"H100 80GB"| H100_80
    GPUAvail -->|"A100 40GB"| A100_40
    GPUAvail -->|"V100"| V100
    GPUAvail -->|"P100"| P100
    GPUAvail -->|"Other"| Unsupported
```

Sources: [docs/performance.md:186-257]()

## Alternative Hardware Configurations

### NVIDIA A100 40GB

**Maximum token support:** 4,352 tokens [docs/performance.md:213]().

**Required configuration changes:**

1. **Enable unified memory**:
   ```bash
   XLA_PYTHON_CLIENT_PREALLOCATE=false
   TF_FORCE_UNIFIED_MEMORY=true
   XLA_CLIENT_MEM_FRACTION=3.2
   ```

2. **Adjust memory sharding** in model configuration parameters to control allocation for the pair transition module [docs/performance.md:225-234]().

Sources: [docs/performance.md:207-234]()

### NVIDIA V100 (Compute Capability 7.x)

**Maximum token support:** 1,280 tokens (with unified memory) [docs/performance.md:243]().

**Known issues:** CUDA Capability 7.x devices (e.g., V100) produce bad output with clashing residues (ranking scores of -99 or lower) unless specific XLA flags are set [docs/known_issues.md:3-8]().

**Required workaround:**
```bash
XLA_FLAGS="--xla_disable_hlo_passes=custom-kernel-fusion-rewriter"
```

Sources: [docs/performance.md:236-243](), [docs/known_issues.md:3-8]()

### NVIDIA P100 (Compute Capability 6.0)

**Maximum token support:** 1,024 tokens [docs/performance.md:248]().

**Configuration:** No special configuration changes needed beyond standard setup [docs/performance.md:245-248]().

Sources: [docs/performance.md:245-248]()

## Summary of Environment Variables

The following environment variables are critical for hardware performance and stability:

| Variable | Recommended Value | Purpose |
|----------|---------------|---------|
| `XLA_PYTHON_CLIENT_PREALLOCATE` | `true` (for 80GB) | Enables JAX memory preallocation. [docs/performance.md:186-189]() |
| `XLA_CLIENT_MEM_FRACTION` | `0.95` (for 80GB) | Allocates 95% of GPU memory. [docs/performance.md:186-189]() |
| `TF_FORCE_UNIFIED_MEMORY` | `true` (for <80GB) | Enables CUDA Unified Memory for larger inputs. [docs/performance.md:213-217]() |
| `XLA_FLAGS` | (See Workarounds) | Disables specific HLO passes for older GPUs. [docs/known_issues.md:7-8]() |

Sources: [docs/performance.md:186-217](), [docs/known_issues.md:3-8]()

---