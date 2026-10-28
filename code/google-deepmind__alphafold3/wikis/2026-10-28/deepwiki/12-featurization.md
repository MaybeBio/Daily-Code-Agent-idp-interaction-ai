# Featurization

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [src/alphafold3/data/featurisation.py](src/alphafold3/data/featurisation.py)
- [src/alphafold3/model/atom_layout/atom_layout.py](src/alphafold3/model/atom_layout/atom_layout.py)
- [src/alphafold3/model/data3.py](src/alphafold3/model/data3.py)
- [src/alphafold3/model/features.py](src/alphafold3/model/features.py)
- [src/alphafold3/model/merging_features.py](src/alphafold3/model/merging_features.py)
- [src/alphafold3/model/msa_pairing.py](src/alphafold3/model/msa_pairing.py)
- [src/alphafold3/model/pipeline/inter_chain_bonds.py](src/alphafold3/model/pipeline/inter_chain_bonds.py)
- [src/alphafold3/model/pipeline/pipeline.py](src/alphafold3/model/pipeline/pipeline.py)
- [src/alphafold3/model/pipeline/structure_cleaning.py](src/alphafold3/model/pipeline/structure_cleaning.py)

</details>



## Purpose and Scope

This document describes the featurization system in AlphaFold 3, which is responsible for converting raw biological data (proteins, RNA, DNA, and ligands) into numerical representations suitable for the neural network model. Featurization sits between the data pipeline (which performs MSA generation and template searching) and the model inference components.

For details about the input data processing prior to featurization, see [Data Pipeline](4.2). For information about model inference, see [Model Inference](4.4).

Sources:
- [src/alphafold3/data/featurisation.py:20-56]()
- [src/alphafold3/model/pipeline/pipeline.py:20-39]()

## Overview

The featurization system transforms the structured biological data from the data pipeline into a comprehensive set of features encoded as NumPy arrays. These features capture various aspects of the input molecules, including sequence information, evolutionary information from MSAs, structural information from templates, and chemical properties of the molecules.

### Featurization Data Flow

```mermaid
flowchart TD
    subgraph "Featurization System [src/alphafold3/data/featurisation.py]"
        direction LR
        fe["featurise_input()"] --> wp["WholePdbPipeline"]
        wp --> Tokenization["tokenizer()"]
        Tokenization --> Features["compute_features()"]
        
        subgraph "Feature Computation [src/alphafold3/model/features.py]"
            Features --> TokenFeats["TokenFeatures"]
            Features --> MSAFeats["MSA"]
            Features --> TemplateFeats["Templates"]
            Features --> StructureInfo["PredictedStructureInfo"]
            Features --> BondInfo["Bond Information"]
            Features --> FrameInfo["Frames"]
        end
        
        Features --> BatchDict["features.BatchDict"]
    end
    
    Input["folding_input.Input"] --> fe
    ChemComp["chemical_components.Ccd"] --> fe
    BatchDict --> ModelRunner["ModelRunner"]
```

Sources:
- [src/alphafold3/data/featurisation.py:47-121]()
- [src/alphafold3/model/pipeline/pipeline.py:86-160]()
- [src/alphafold3/model/features.py:20-43]()

## Featurization Process

The featurization process consists of several steps that transform the biological input data into a structured representation suitable for deep learning models:

### Featurization Sequence

```mermaid
sequenceDiagram
    participant Input as "folding_input.Input"
    participant Featuriser as "featurise_input()"
    participant Pipeline as "WholePdbPipeline"
    participant Features as "features.py"
    participant Batch as "features.BatchDict"
    
    Input->>Featuriser: validate_fold_input()
    Featuriser->>Pipeline: process_item()
    Pipeline->>Pipeline: clean_structure()
    Pipeline->>Pipeline: tokenizer()
    Pipeline->>Features: compute_features() for each feature type
    Features->>Pipeline: Return feature dataclasses
    Pipeline->>Batch: Assemble batch dictionary
    Batch->>Featuriser: Return BatchDict
```

Sources:
- [src/alphafold3/data/featurisation.py:33-121]()
- [src/alphafold3/model/pipeline/pipeline.py:86-160]()

### 1. Input Validation

The process begins with `validate_fold_input`, ensuring that the input contains the necessary data, such as MSAs and templates for protein chains and MSAs for RNA chains.

Sources:
- [src/alphafold3/data/featurisation.py:33-46]()

### 2. Structure Cleaning

The input structure is cleaned via `structure_cleaning.clean_structure` to remove unwanted elements such as clashing chains, non-standard atoms, waters, and hydrogens. It also handles the filtering of leaving atoms based on covalent bonds via `_get_leaving_atom_mask`.

Sources:
- [src/alphafold3/model/pipeline/pipeline.py:35-36]()
- [src/alphafold3/model/pipeline/structure_cleaning.py:32-72]()
- [src/alphafold3/model/pipeline/structure_cleaning.py:75-111]()

### 3. Tokenization

The `tokenizer` function maps a flat atom layout to tokens for the Evoformer neural network. It creates one token per polymer residue (protein or nucleic acid) and one token per ligand atom. Optionally, non-standard residues can be "flattened" (represented as one token per atom) if `flatten_non_standard_residues` is enabled.

```mermaid
flowchart LR
    subgraph "Tokenization Process [src/alphafold3/model/features.py]"
        direction TB
        flat["AtomLayout (flat_output_layout)"] --> tokenizer["tokenizer()"]
        ccd["chemical_components.Ccd"] --> tokenizer
        tokenizer --> all_tokens["all_tokens (AtomLayout)"]
        tokenizer --> all_token_atoms["all_token_atoms_layout (AtomLayout)"]
        tokenizer --> std_idxs["standard_token_idxs"]
    end
```

Sources:
- [src/alphafold3/model/features.py:173-203]()
- [src/alphafold3/model/pipeline/pipeline.py:155-155]()

### 4. Feature Computation

After tokenization, the system computes various types of features:

- **TokenFeatures**: Basic information about each token, including residue index, atom type, chain identifiers, and molecule type flags.
- **MSA**: Evolutionary information. This involves `msa_pairing.create_paired_features` to align sequences across chains by species and `data3.get_profile_features` for MSA profiles.
- **Templates**: Structural information from template structures, converted to AlphaFold 3 format using `data3.fix_template_features`.
- **AtomCrossAtt**: Features for atom-level cross-attention in the model.
- **RefStructure**: Reference structure features, including atom coordinates.
- **PolymerLigandBondInfo** and **LigandLigandBondInfo**: Information about covalent bonds derived from the input structure.
- **PseudoBetaInfo**: Features for the backbone atoms for distance calculations.
- **Frames**: Local coordinate frames for structural predictions.

Sources:
- [src/alphafold3/model/pipeline/pipeline.py:86-160]()
- [src/alphafold3/model/features.py:20-50]()
- [src/alphafold3/model/data3.py:35-47]()
- [src/alphafold3/model/data3.py:50-98]()
- [src/alphafold3/model/msa_pairing.py:87-165]()

### 5. Batch Assembly and Padding

All computed features are assembled into a batch dictionary. The pipeline uses `calculate_bucket_size` to determine the appropriate padding size based on the `buckets` configuration to minimize JAX re-compilation.

Sources:
- [src/alphafold3/model/pipeline/pipeline.py:43-71]()
- [src/alphafold3/model/features.py:69-102]()

## Key Data Structures

### PaddingShapes

Defines padding dimensions for different feature types to ensure consistent batch sizes during JAX compilation:

```python
@dataclasses.dataclass(frozen=True)
class PaddingShapes:
  num_tokens: int
  msa_size: int
  num_chains: int
  num_templates: int
  num_atoms: int
```

Sources:
- [src/alphafold3/model/features.py:60-67]()

### Chains

Contains information about chain identifiers and symmetry, computed via `_compute_asym_entity_and_sym_id`:

```python
@dataclasses.dataclass(frozen=True)
class Chains:
  chain_id: np.ndarray
  asym_id: np.ndarray
  entity_id: np.ndarray
  sym_id: np.ndarray
```

Sources:
- [src/alphafold3/model/features.py:113-125]()
- [src/alphafold3/model/features.py:128-171]()

### Feature Classes

The following dataclasses and dictionary structures represent different types of features:

| Feature Class / Category | Purpose | Key Attributes / Contents |
|--------------------------|---------|---------------------------|
| `MSA` | Multiple sequence alignment | `msa`, `msa_mask`, `deletion_matrix`, `profile` |
| `Templates` | Template structures | `template_aatype`, `template_atom_mask`, `template_atom_positions` |
| `TokenFeatures` | Token information | `res_id`, `token_index`, `asym_id`, `is_protein`, `is_ligand` |
| `PredictedStructureInfo` | Structure info | `atom_mask`, `residue_center_index` |
| `PolymerLigandBondInfo` | Polymer-ligand bonds | `bond_indices`, `bond_type` |
| `LigandLigandBondInfo` | Ligand-ligand bonds | `bond_indices`, `bond_type` |
| `PseudoBetaInfo` | Backbone atoms | `pseudo_beta`, `pseudo_beta_mask` |
| `AtomCrossAtt` | Atom attention | `atom_to_token_queries`, `atom_to_token_keys` |
| `Frames` | Coordinate frames | `rigidgroups_gt_frames`, `rigidgroups_gt_exists` |

Sources:
- [src/alphafold3/model/features.py:20-50]()
- [src/alphafold3/model/data3.py:35-121]()

## Tokenization Details

The `tokenizer` function maps a flat atom layout to tokens for the Evoformer neural network:

```mermaid
flowchart TD
    subgraph "Tokenization Logic [src/alphafold3/model/features.py]"
        direction TB
        input["AtomLayout (flat_output_layout)"] --> process["Process Residues"]
        process --> decision{"Residue Type?"}
        
        decision -->|"Standard Protein"| protein["One token per residue (CA atom)"]
        decision -->|"Standard Nucleic"| nucleic["One token per residue (C1' atom)"]
        decision -->|"Non-standard"| nonstandard["One token per atom (if flatten_non_standard_residues=True)"]
        decision -->|"Ligand"| ligand["One token per atom"]
        
        protein --> output["Tokens with Atom Layout"]
        nucleic --> output
        nonstandard --> output
        ligand --> output
    end
```

For standard residues (protein and nucleic acids), one token represents the entire residue, with a representative atom (CA for proteins, C1' for nucleic acids) chosen as the token's position. For ligands and optionally for non-standard residues, each atom is represented by its own token.

Sources:
- [src/alphafold3/model/features.py:173-203]()
- [src/alphafold3/model/pipeline/pipeline.py:140-160]()

## Feature Computation Details

### MSA Features

MSA features include:
- Aligned sequences from the MSA.
- Sequence masks and deletion matrices.
- Profile information via `msa_profile.compute_msa_profile` called within `data3.get_profile_features`.
- Deletion mean (average number of deletions at each position).

The system handles both paired and unpaired MSAs. Functions like `msa_pairing.create_paired_features` and `merging_features.merge_paired_and_unpaired_msa` manage alignment and concatenation across species.

Sources:
- [src/alphafold3/model/msa_pairing.py:40-165]()
- [src/alphafold3/model/data3.py:35-47]()
- [src/alphafold3/model/merging_features.py:73-101]()

### Template Features

Template features include residue types, 3D positions, and masks. The `data3.fix_template_features` function maps representations to the AlphaFold 3 dense atom format. If no templates are found, `data3.empty_template_features` generates masked-out features to maintain tensor shape consistency.

Sources:
- [src/alphafold3/model/data3.py:50-121]()

### Token Features

Token features encode the identity and hierarchy of each token:
- `res_id` and `token_index`.
- Chain identifiers (`asym_id`, `entity_id`, `sym_id`).
- Molecule type flags.

Sources:
- [src/alphafold3/model/features.py:113-171]()

## Configuration Options

The `WholePdbPipeline.Config` class provides numerous configuration options for the featurization process:

```python
class Config(base_config.BaseConfig):
  max_atoms_per_token: int = 24
  pad_num_chains: int = 1000
  buckets: list[int] | None = None
  msa_crop_size: int = 16384
  max_templates: int = 4
  flatten_non_standard_residues: bool = True
  deterministic_frames: bool = True
  resolve_msa_overlaps: bool = True
```

Sources:
- [src/alphafold3/model/pipeline/pipeline.py:89-160]()

## AtomLayout System

The `AtomLayout` system provides a consistent representation of atom arrangements:

```mermaid
flowchart LR
    subgraph "AtomLayout System [src/alphafold3/model/atom_layout/atom_layout.py]"
        direction TB
        AL["AtomLayout (Dataclass)"] --> Flat["Flat Layout (1D)"]
        AL --> Dense["Dense Layout (2D)"]
        
        Flat <-->|"convert()"| Dense
        
        AL --> Structure["structure.Structure"]
    end
```

The `AtomLayout` contains:
- `atom_name`: Atom names (e.g., 'CA', 'NE2').
- `res_id`: Residue indices.
- `chain_id`: Chain identifiers.
- `atom_element`: Element types.
- `res_name`: Residue names.
- `chain_type`: Chain types.

Sources:
- [src/alphafold3/model/atom_layout/atom_layout.py:44-111]()

## Conclusion

The featurization system is a critical component of AlphaFold 3 that transforms biological data into a structured representation suitable for neural network processing. It handles various types of biomolecules, accounts for their chemical properties, and incorporates evolutionary and structural information to create a comprehensive feature set that enables accurate structure prediction.

Sources:
- [src/alphafold3/data/featurisation.py:47-121]()
- [src/alphafold3/model/pipeline/pipeline.py:86-160]()

---