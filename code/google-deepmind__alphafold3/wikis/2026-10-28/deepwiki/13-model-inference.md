# Model Inference

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [run_alphafold.py](run_alphafold.py)
- [run_alphafold_test.py](run_alphafold_test.py)
- [src/alphafold3/model/model.py](src/alphafold3/model/model.py)
- [src/alphafold3/model/model_config.py](src/alphafold3/model/model_config.py)
- [src/alphafold3/model/network/evoformer.py](src/alphafold3/model/network/evoformer.py)

</details>





## Purpose and Scope

This document details the model inference component of AlphaFold 3, which is responsible for executing the neural network architecture to predict 3D structures based on the featurized input data. Model inference occurs after the input processing, data pipeline, and featurization stages, and produces structure predictions that are then post-processed into the final output.

For technical details regarding the neural network layers, modules, and component libraries, see [Network Architecture](#4.4.1). For details on model weights, parameter loading, and JAX utility libraries, see [Model Parameters and JAX Utilities](#4.4.2).

Sources: [run_alphafold.py:11-20](), [src/alphafold3/model/model.py:11-12]()

## Inference Pipeline Overview

AlphaFold 3's inference process involves several key components that work together to transform featurized biological data into a predicted 3D structure with confidence metrics.

Title: Model Inference Pipeline
```mermaid
flowchart TB
    subgraph "Model Inference Pipeline"
        BatchDict["features.BatchDict"] --> ModelRunner
        
        subgraph "ModelRunner [run_alphafold.py]"
            InitRunner["Initialize with config/device"]
            LoadParams["Load model parameters [params.py]"]
            PrepareModel["Prepare jitted model [model.py]"]
            RunInference["Run inference"]
            ExtractResults["Extract results & embeddings"]
            
            InitRunner --> LoadParams
            LoadParams --> PrepareModel
            PrepareModel --> RunInference
            RunInference --> ExtractResults
        end
        
        Seeds["RNG Seeds"] --> RunInference
        ModelRunner --> ResultsForSeed
        
        ResultsForSeed --> |"Multiple samples\nper seed"| InferenceResult["model.InferenceResult"]
    end
    
    InferenceResult --> PostProcessing["Post-processing"]
```

The inference pipeline takes featurized inputs and processes them through the AlphaFold 3 model to generate structure predictions. A single input can generate multiple output structures through multiple random seeds and multiple diffusion samples per seed.

Sources: [run_alphafold.py:399-463](), [src/alphafold3/model/model.py:45-68]()

## Core Components

### ModelRunner

The `ModelRunner` class is the central component that manages model inference. It handles parameter loading via `params.py`, JIT compilation via JAX, and execution on the specified device.

Title: ModelRunner Code Associations
```mermaid
classDiagram
    class ModelRunner {
        -model_config: model.Model.Config
        -device: jax.Device
        -model_dir: pathlib.Path
        +model_params() hk.Params
        -_model() Callable
        +run_inference(featurised_example, rng_key) model.ModelResult
        +extract_inference_results_and_maybe_embeddings() tuple
    }
    class Model {
        +get_inference_result()
    }
    class ParamsLoader["params.py"] {
        +get_model_haiku_params(model_dir)
        +select_model_files(model_dir)
    }
    ModelRunner --> Model : executes
    ModelRunner ..> ParamsLoader : uses
```

The `ModelRunner` caches model parameters using `get_model_haiku_params` from `src/alphafold3/model/params.py` and maintains the compiled forward pass function. The parameter loading system supports reading from sharded, compressed (`.zst`), or standard binary files.

Sources: [run_alphafold.py:304-378](), [src/alphafold3/model/params.py:176-212]()

### Model Configuration

The model configuration, defined in `src/alphafold3/model/model_config.py`, controls the model's behavior during inference, including the number of diffusion steps and recycling iterations.

Key configuration parameters include:
- `num_recycles`: Number of iterations through the trunk.
- `num_samples`: Number of diffusion samples generated per seed [src/alphafold3/model/network/diffusion_head.py:98]().
- `steps`: Number of denoising steps in the diffusion head [src/alphafold3/model/network/diffusion_head.py:117]().

Sources: [run_alphafold.py:286-301](), [src/alphafold3/model/network/diffusion_head.py:104-122](), [src/alphafold3/test_data/model_config.json:203-228]()

## Diffusion Sampling Process

The diffusion process is managed by the `DiffusionHead` in `src/alphafold3/model/network/diffusion_head.py`. It implements a denoising process that starts from noise and iteratively refines atom positions.

Title: Diffusion Sampling and Transformer Interaction
```mermaid
flowchart TD
    subgraph "DiffusionHead.__call__ [diffusion_head.py]"
        Start["Noisy Positions [N(0, SIGMA_DATA)]"] --> Schedule["noise_schedule(t)"]
        Schedule --> Cond["_conditioning()"]
        Cond --> CrossAtt["atom_cross_att_encoder"]
        CrossAtt --> Transformer["diffusion_transformer.Transformer"]
        Transformer --> Pred["Predict Denoised Positions"]
        Pred --> Step["Update positions (Langevin-like)"]
        Step --> Loop{"More steps?"}
        Loop -- Yes --> Schedule
        Loop -- No --> Final["Final Atom Positions"]
    end
    
    subgraph "Transformer Components [diffusion_transformer.py]"
        Transformer --> SelfAtt["self_attention"]
        Transformer --> TransBlock["transition_block"]
        SelfAtt --> AdaLN["adaptive_layernorm"]
        TransBlock --> AdaZero["adaptive_zero_init"]
    end
```

The diffusion process uses a noise schedule defined by `noise_schedule(t)` with parameters `smin=0.0004` and `smax=160.0`, and a reference scale `SIGMA_DATA = 16.0`.

Sources: [src/alphafold3/model/network/diffusion_head.py:30-31](), [src/alphafold3/model/network/diffusion_head.py:79-83](), [src/alphafold3/model/network/diffusion_head.py:202-230](), [src/alphafold3/model/network/diffusion_transformer.py:23-111]()

## JAX Compilation and Execution

AlphaFold 3 leverages JAX for high-performance execution. The model is wrapped in a `haiku.transform` and then `jax.jit` compiled.

### Sharded Execution
To manage memory on large structures, AlphaFold 3 uses `sharded_map` and `sharded_apply` from `src/alphafold3/model/components/mapping.py`. For example, `GridSelfAttention` uses `get_shard_size` to determine how to partition residues during attention calculation.

Sources: [src/alphafold3/model/components/mapping.py:55-84](), [src/alphafold3/model/network/modules.py:27-38](), [src/alphafold3/model/network/modules.py:223-225]()

### Precision and Context
The model utilizes `bfloat16` precision for most operations to improve performance and reduce memory usage, controlled by `utils.bfloat16_context()`. This is particularly critical in the `DiffusionHead` and `create_target_feat_embedding`.

Sources: [src/alphafold3/model/model.py:152-156](), [src/alphafold3/model/network/diffusion_head.py:212-213]()

## Results and Post-processing

After the diffusion process completes, the raw tensor outputs are converted into a `structure.Structure` object via `get_predicted_structure`.

Title: Structure Construction Data Flow
```mermaid
flowchart LR
    subgraph "Model Output Extraction [model.py]"
        RawCoords["diffusion_samples['atom_positions']"] --> Layout["atom_layout.compute_gather_idxs"]
        Layout --> Convert["atom_layout.convert"]
        Convert --> PredCoords["pred_flat_atom_coords"]
        PredCoords --> Structure["Structure.copy_and_update_atoms"]
        Structure --> InferenceResult["InferenceResult"]
    end
```

The conversion process involves:
1. Rearranging coordinates from the model-specific layout to a flat output layout using `atom_layout.compute_gather_idxs`.
2. Mapping predicted confidence scores (pLDDT) to atom B-factors using `atom_layout.convert`.
3. Constructing the final structure representation by updating the `empty_output_struc` provided in the `Batch`.

Sources: [src/alphafold3/model/model.py:70-140](), [src/alphafold3/model/feat_batch.py:32-33]()

## Confidence Metrics Generation

During inference, several confidence heads produce scores alongside the structure:
- **pLDDT**: Per-atom local distance difference test score, extracted from the model result and converted to flat layout.
- **pTM/ipTM**: Predicted Template Modeling scores, computed from PAE (Predicted Aligned Error) in `_compute_ptm`.
- **Distogram**: Predicted distance distributions from `DistogramHead`, which calculates contact probabilities using a threshold of 8.0Å.

Sources: [src/alphafold3/model/model.py:95-103](), [src/alphafold3/model/model.py:174-193](), [src/alphafold3/model/network/distogram_head.py:24-25](), [src/alphafold3/model/network/distogram_head.py:46-83]()

## Related Child Pages
- [Network Architecture](#4.4.1)
- [Model Parameters and JAX Utilities](#4.4.2)

---