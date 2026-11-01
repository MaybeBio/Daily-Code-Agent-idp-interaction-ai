# Model Execution

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [alphafold/model/features.py](alphafold/model/features.py)
- [alphafold/model/model.py](alphafold/model/model.py)
- [alphafold/model/modules.py](alphafold/model/modules.py)
- [alphafold/model/modules_multimer.py](alphafold/model/modules_multimer.py)
- [alphafold/model/tf/proteins_dataset.py](alphafold/model/tf/proteins_dataset.py)

</details>



## Purpose and Scope

This document describes how AlphaFold models are executed at runtime. It covers the `RunModel` class, which serves as the primary interface for model inference, including parameter initialization, feature processing, Haiku functional transformations, JAX JIT compilation, and the prediction workflow that produces structural predictions and confidence metrics.

For information about the model architecture that gets executed, see [Evoformer Stack](#4.2) and [Structure Module](#4.3). For configuration options that control execution, see [Configuration System](#4.1). For post-prediction structure refinement, see [Structure Relaxation](#6.2).

## RunModel Class Overview

The `RunModel` class ([alphafold/model/model.py:72-184]()) is a container that wraps the AlphaFold neural network model for inference. It handles the transformation of the model into a functional form using Haiku, JIT compilation with JAX, parameter management, and the execution pipeline.

### Class Structure

```mermaid
graph TB
    subgraph "RunModel_Initialization"
        Constructor["RunModel.__init__[alphafold/model/model.py:75-102]<br/>(config, params)"]
        Constructor --> SetConfig["self.config = config"]
        Constructor --> SetParams["self.params = params"]
        Constructor --> CheckMode["Check multimer_mode<br/>from config.model.global_config"]
        
        CheckMode -->|multimer=True| MultimerFn["Define _forward_fn<br/>modules_multimer.AlphaFold[alphafold/model/modules_multimer.py]"]
        CheckMode -->|multimer=False| MonomerFn["Define _forward_fn<br/>modules.AlphaFold[alphafold/model/modules.py]"]
        
        MultimerFn --> Transform1["hk.transform(_forward_fn)"]
        MonomerFn --> Transform2["hk.transform(_forward_fn)"]
        
        Transform1 --> JIT1["jax.jit(transform.apply)"]
        Transform1 --> JIT2["jax.jit(transform.init)"]
        Transform2 --> JIT3["jax.jit(transform.apply)"]
        Transform2 --> JIT4["jax.jit(transform.init)"]
        
        JIT1 --> Apply["self.apply[alphafold/model/model.py:101]"]
        JIT2 --> Init["self.init[alphafold/model/model.py:102]"]
        JIT3 --> Apply
        JIT4 --> Init
    end
    
    subgraph "RunModel_Methods"
        Apply --> Predict["predict(feat, random_seed)[alphafold/model/model.py:153]"]
        Init --> InitParams["init_params(feat, random_seed)[alphafold/model/model.py:104]"]
        
        Process["process_features(raw_features, random_seed)[alphafold/model/model.py:122]"]
        EvalShape["eval_shape(feat)[alphafold/model/model.py:143]"]
    end
```

**Sources:** [alphafold/model/model.py:72-103](), [alphafold/model/modules.py:134-143](), [alphafold/model/modules_multimer.py:15-21]()

### Key Attributes

| Attribute | Type | Description |
|-----------|------|-------------|
| `config` | `ml_collections.ConfigDict` | Model configuration dictionary |
| `params` | `Mapping[str, Mapping[str, jax.Array]]` | Model parameters (weights) |
| `multimer_mode` | `bool` | Whether to use multimer architecture |
| `apply` | JIT-compiled function | Forward pass function for inference |
| `init` | JIT-compiled function | Parameter initialization function |

**Sources:** [alphafold/model/model.py:75-102]()

## Haiku Transforms and JAX JIT Compilation

AlphaFold uses Haiku's functional programming paradigm combined with JAX's JIT compilation for efficient execution.

### Haiku Transform Process

```mermaid
graph LR
    subgraph "Step_1_Define_Forward_Function"
        ForwardDef["def _forward_fn(batch):<br/>model = modules.AlphaFold(config)<br/>return model(batch, ...)"]
    end
    
    subgraph "Step_2_Haiku_Transform"
        Transform["hk.transform(_forward_fn)"]
        Transform --> TransObj["Transformed Object<br/>.apply(params, rng, batch)<br/>.init(rng, batch)"]
    end
    
    subgraph "Step_3_JAX_JIT_Compilation"
        JITApply["jax.jit(transform.apply)[alphafold/model/model.py:101]"]
        JITInit["jax.jit(transform.init)[alphafold/model/model.py:102]"]
        
        JITApply --> CompiledApply["Compiled Apply Function<br/>XLA-optimized"]
        JITInit --> CompiledInit["Compiled Init Function<br/>XLA-optimized"]
    end
    
    ForwardDef --> Transform
    TransObj --> JITApply
    TransObj --> JITInit
```

**Sources:** [alphafold/model/model.py:86-102]()

### Forward Function Definitions

The forward function differs between monomer and multimer modes:

**Monomer Mode** ([alphafold/model/model.py:92-99]()):
```python
def _forward_fn(batch):
    model = modules.AlphaFold(self.config.model)
    return model(
        batch,
        is_training=False,
        compute_loss=False,
        ensemble_representations=True,
    )
```

**Multimer Mode** ([alphafold/model/model.py:86-88]()):
```python
def _forward_fn(batch):
    model = modules_multimer.AlphaFold(self.config.model)
    return model(batch, is_training=False)
```

**Sources:** [alphafold/model/model.py:84-99]()

### JIT Compilation Benefits

JAX's JIT compilation ([alphafold/model/model.py:101-102]()) provides:
- XLA-optimized execution on GPU/TPU
- Automatic parallelization
- Efficient memory usage
- Compiled once, executed many times

## Prediction Workflow

The complete prediction workflow involves several stages, coordinated by methods of the `RunModel` class.

```mermaid
graph TB
    Start["Input: raw_features<br/>(NumPy dict from data pipeline)"]
    
    Start --> Process["process_features()[alphafold/model/model.py:122]<br/>Prepare features for model"]
    
    Process -->|multimer| MultFeat["Return raw_features<br/>(no processing needed)"]
    Process -->|monomer| MonoFeat["np_example_to_features()[alphafold/model/features.py:45]<br/>TensorFlow pipeline<br/>Cropping, MSA sampling, etc."]
    
    MultFeat --> CheckParams{"Parameters<br/>initialized?"}
    MonoFeat --> CheckParams
    
    CheckParams -->|No| InitParams["init_params()[alphafold/model/model.py:104]<br/>Initialize randomly or<br/>load from checkpoint"]
    CheckParams -->|Yes| Predict
    
    InitParams --> Predict["predict(feat, random_seed)[alphafold/model/model.py:153]<br/>Run model inference"]
    
    Predict --> Apply["self.apply(params, rng, feat)<br/>JIT-compiled forward pass"]
    
    Apply --> Block["Block until ready<br/>tree.map(block_until_ready)[alphafold/model/model.py:179]"]
    
    Block --> Confidence["get_confidence_metrics()[alphafold/model/model.py:31]<br/>Compute pLDDT, pTM, ipTM, PAE"]
    
    Confidence --> Result["Return: prediction_result<br/>+ confidence_metrics"]
```

**Sources:** [alphafold/model/model.py:104-184](), [alphafold/model/features.py:45-76]()

### Parameter Initialization

The `init_params` method ([alphafold/model/model.py:104-120]()) handles model parameter initialization:

```mermaid
graph LR
    Entry["init_params(feat, random_seed=0)"]
    
    Entry --> Check{"self.params<br/>exists?"}
    
    Check -->|Yes| Skip["Skip initialization<br/>Use provided params"]
    Check -->|No| Random["Generate random seed<br/>jax.random.PRNGKey(random_seed)"]
    
    Random --> CallInit["self.init(rng, feat)<br/>Initialize parameters"]
    CallInit --> Convert["hk.data_structures.to_mutable_dict()[alphafold/model/model.py:119]<br/>Convert to mutable dict"]
    Convert --> Store["self.params = initialized params"]
    Store --> Warn["Log warning:<br/>'Initialized parameters randomly'"]
```

**Sources:** [alphafold/model/model.py:104-120]()

### Feature Processing

Feature processing differs significantly between monomer and multimer modes:

| Mode | Processing | Implementation |
|------|------------|----------------|
| **Multimer** | No processing | Returns `raw_features` as-is ([alphafold/model/model.py:137]()) |
| **Monomer** | TensorFlow pipeline | Calls `features.np_example_to_features()` ([alphafold/model/model.py:139-141]()) |

**Sources:** [alphafold/model/model.py:122-141]()

#### Monomer Feature Processing Pipeline

For monomer mode, features are processed through a TensorFlow pipeline ([alphafold/model/features.py:45-76]()):

```mermaid
graph TB
    RawFeat["raw_features<br/>(NumPy dict)"]
    
    RawFeat --> NumRes["Extract num_res<br/>from seq_length"]
    NumRes --> MakeConfig["make_data_config()[alphafold/model/features.py:28]<br/>Set crop_size = num_res"]
    
    MakeConfig --> DelMatrix["Convert deletion_matrix_int<br/>to float32 deletion_matrix"]
    
    DelMatrix --> TFGraph["Create tf.Graph()[alphafold/model/features.py:60]"]
    TFGraph --> Convert["np_to_tensor_dict()[alphafold/model/tf/proteins_dataset.py:109]<br/>Convert NumPy to TF tensors"]
    
    Convert --> Reshape["parse_reshape_logic()[alphafold/model/tf/proteins_dataset.py:29]<br/>Reshape features to correct dims"]
    
    Reshape --> Process["input_pipeline.process_tensors_from_config()<br/>Crop, sample MSA, add random seed"]
    
    Process --> Session["tf.Session.run()[alphafold/model/features.py:74]<br/>Execute TensorFlow graph"]
    
    Session --> Filter["Filter out object dtype<br/>features"]
    
    Filter --> Output["Processed features<br/>(NumPy dict)"]
```

**Sources:** [alphafold/model/features.py:45-76](), [alphafold/model/tf/proteins_dataset.py:109-131]()

### Model Prediction

The `predict` method ([alphafold/model/model.py:153-184]()) executes the model:

| Step | Operation | Code Reference |
|------|-----------|----------------|
| 1 | Initialize parameters if needed | `self.init_params(feat)` [alphafold/model/model.py:169]() |
| 2 | Log input shapes | `logging.info(...)` [alphafold/model/model.py:170-173]() |
| 3 | Run JIT-compiled model | `result = self.apply(...)` [alphafold/model/model.py:174]() |
| 4 | Block until outputs ready | `tree.map(lambda x: x.block_until_ready(), result)` [alphafold/model/model.py:179]() |
| 5 | Compute confidence metrics | `get_confidence_metrics(result, multimer_mode)` [alphafold/model/model.py:181]() |
| 6 | Update result dict | `result.update(confidence_metrics)` [alphafold/model/model.py:180-182]() |
| 7 | Log output shapes | `logging.info(...)` [alphafold/model/model.py:183]() |
| 8 | Return results | `return result` [alphafold/model/model.py:184]() |

**Sources:** [alphafold/model/model.py:153-184]()

## Confidence Metric Computation

The `get_confidence_metrics` function ([alphafold/model/model.py:31-69]()) post-processes model outputs to compute confidence scores.

```mermaid
graph TB
    Input["prediction_result<br/>(model outputs)"]
    
    Input --> pLDDT["confidence.compute_plddt()[alphafold/common/confidence.py]<br/>Per-residue confidence"]
    
    Input --> CheckPAE{"Has predicted_aligned_error?"}
    
    CheckPAE -->|Yes| PAE["compute_predicted_aligned_error()[alphafold/common/confidence.py]<br/>Pairwise confidence matrix"]
    
    PAE --> pTM["predicted_tm_score()[alphafold/common/confidence.py]<br/>Global confidence metric"]
    
    pTM --> CheckMultimer{"multimer_mode?"}
    
    CheckMultimer -->|Yes| ipTM["predicted_tm_score(interface=True)[alphafold/common/confidence.py]<br/>Interface confidence"]
    CheckMultimer -->|No| MonoRank["ranking_confidence =<br/>mean(plddt)[alphafold/model/model.py:65]"]
    
    ipTM --> MultiRank["ranking_confidence =<br/>0.8 * iptm + 0.2 * ptm[alphafold/model/model.py:59]"]
    
    pLDDT --> Output
    PAE --> Output
    pTM --> Output
    ipTM --> Output
    MonoRank --> Output
    MultiRank --> Output
    CheckPAE -->|No| Output
    
    Output["confidence_metrics dict:<br/>plddt, ptm, iptm (multimer),<br/>pae, ranking_confidence"]
```

**Sources:** [alphafold/model/model.py:31-69]()

### Confidence Metrics Summary

| Metric | Computation | Monomer | Multimer | Purpose |
|--------|-------------|---------|----------|---------|
| **pLDDT** | `confidence.compute_plddt()` | ✓ | ✓ | Per-residue confidence (0-100) |
| **PAE** | `confidence.compute_predicted_aligned_error()` | ✓* | ✓* | Pairwise alignment error matrix |
| **pTM** | `confidence.predicted_tm_score()` (asym_id=None) | ✓* | ✓* | Global TM-score prediction |
| **ipTM** | `confidence.predicted_tm_score()` (interface=True) | ✗ | ✓* | Interface TM-score (multi-chain) |
| **ranking_confidence** | mean(pLDDT) or 0.8×ipTM + 0.2×pTM | ✓ | ✓ | Used to rank multiple predictions |

*Only available if model has `predicted_aligned_error` head (e.g., `*_ptm` models)

**Sources:** [alphafold/model/model.py:31-69]()

## Monomer vs Multimer Execution Differences

The execution path diverges based on the `multimer_mode` configuration flag ([alphafold/model/model.py:82]()).

### Comparison Table

| Aspect | Monomer | Multimer |
|--------|---------|----------|
| **Architecture Module** | `modules.AlphaFold` [alphafold/model/model.py:93]() | `modules_multimer.AlphaFold` [alphafold/model/model.py:87]() |
| **Forward Function Args** | `is_training=False`, `ensemble_representations=True` [alphafold/model/model.py:96-98]() | `is_training=False` [alphafold/model/model.py:88]() |
| **Feature Processing** | TensorFlow pipeline [alphafold/model/model.py:139]() | No processing [alphafold/model/model.py:137]() |
| **Random Seed Usage** | Controls MSA sampling in processing | Controls MSA sampling in model [alphafold/model/model.py:156]() |
| **ipTM Computation** | Not computed | Computed for interface confidence [alphafold/model/model.py:53-58]() |
| **Ranking Metric** | `mean(plddt)` [alphafold/model/model.py:65-67]() | `0.8 * iptm + 0.2 * ptm` [alphafold/model/model.py:59-61]() |

**Sources:** [alphafold/model/model.py:84-99](), [alphafold/model/model.py:122-141](), [alphafold/model/model.py:51-67]()

## Evaluation Shape Utility

The `eval_shape` method ([alphafold/model/model.py:143-151]()) is a utility for determining output shapes without running the full computation using `jax.eval_shape`.

```mermaid
graph LR
    Input["eval_shape(feat)"]
    Input --> Init["init_params(feat)<br/>Ensure params exist"]
    Init --> Log1["Log input shapes"]
    Log1 --> Eval["jax.eval_shape(self.apply, ...)[alphafold/model/model.py:149]<br/>Trace computation without execution"]
    Eval --> Log2["Log output shapes"]
    Log2 --> Return["Return ShapeDtypeStruct"]
```

**Sources:** [alphafold/model/model.py:143-151]()

## Usage Pattern

Typical usage of the `RunModel` class follows this pattern:

1. **Instantiate** with configuration and optional pre-trained parameters ([alphafold/model/model.py:75-81]()).
2. **Process features** from raw data pipeline output ([alphafold/model/model.py:122-141]()).
3. **Predict** to run inference and get results ([alphafold/model/model.py:153-184]()).
4. Use confidence metrics for ranking and filtering ([alphafold/model/model.py:31-69]()).

The class is designed to be reused for multiple predictions with the same model configuration, amortizing the JIT compilation cost across many inference calls.

**Sources:** [alphafold/model/model.py:72-184]()

---