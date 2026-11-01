# Multimer MSA Pairing

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [alphafold/data/msa_pairing.py](alphafold/data/msa_pairing.py)
- [alphafold/data/pipeline.py](alphafold/data/pipeline.py)
- [alphafold/data/pipeline_multimer.py](alphafold/data/pipeline_multimer.py)
- [alphafold/data/tools/hhsearch.py](alphafold/data/tools/hhsearch.py)
- [alphafold/data/tools/hmmbuild.py](alphafold/data/tools/hmmbuild.py)
- [alphafold/data/tools/hmmsearch.py](alphafold/data/tools/hmmsearch.py)

</details>



## Purpose and Scope

This document describes the MSA (Multiple Sequence Alignment) pairing logic for multimer protein complex predictions in AlphaFold. When predicting the structure of protein complexes with multiple chains, identifying which sequences in each chain's MSA correspond to the same organism is critical, as these co-evolved sequences provide signal for inter-chain interactions.

This page focuses on the pairing algorithm and feature merging logic implemented in [alphafold/data/msa_pairing.py](). This logic is a key component of the multimer data pipeline described in [alphafold/data/pipeline_multimer.py]().

**Sources:** [alphafold/data/msa_pairing.py:1-15](), [alphafold/data/pipeline_multimer.py:1-15]()

---

## Overview: The Pairing Problem

In multimer prediction, each chain has its own MSA generated independently (see [3.1 MSA Generation](3.1)). The pairing system must:

1.  **Identify common species** across chain MSAs using species identifiers.
2.  **Match sequences** from the same species across chains based on sequence similarity to the target.
3.  **Merge features**—paired sequences are concatenated horizontally, while unpaired sequences are block-diagonalized.

```mermaid
graph TB
    Chain1MSA["Chain 1 MSA<br/>(msa_all_seq)"]
    Chain2MSA["Chain 2 MSA<br/>(msa_all_seq)"]
    
    SpeciesID["Species Identification<br/>msa_species_identifiers_all_seq"]
    
    Pairing["Sequence Pairing<br/>pair_sequences()"]
    
    PairedRows["Paired Rows<br/>(concatenated)"]
    UnpairedRows["Unpaired Rows<br/>(block-diagonalized)"]
    
    Merge["Feature Merging<br/>merge_chain_features()"]
    
    Output["Merged FeatureDict<br/>(model input)"]
    
    Chain1MSA --> SpeciesID
    Chain2MSA --> SpeciesID
    
    SpeciesID --> Pairing
    
    Pairing --> PairedRows
    Pairing --> UnpairedRows
    
    PairedRows --> Merge
    UnpairedRows --> Merge
    
    Merge --> Output
```

**Diagram: High-Level MSA Pairing and Merging Flow**

**Sources:** [alphafold/data/msa_pairing.py:153-186](), [alphafold/data/msa_pairing.py:256-319](), [alphafold/data/msa_pairing.py:513-543]()

---

## MSA Statistics and Species Grouping

### MSAStatistics Dataclass

The `MSAStatistics` class [alphafold/data/msa_pairing.py:70-151]() provides a structured representation of MSA properties for a single chain:

| Attribute | Type | Description |
| :--- | :--- | :--- |
| `species_identifiers` | `np.ndarray` | Species identifier for each MSA row (e.g., from UniProt metadata). |
| `row` | `np.ndarray` | Original row indices in the MSA. |
| `similarity` | `np.ndarray` | Sequence similarity to the target sequence (range: 0-1). |
| `gap` | `np.ndarray` | Gap percentage for each sequence (range: 0-1). |

### Key Methods

*   **`from_chain_features()`** [alphafold/data/msa_pairing.py:87-122](): Creates an `MSAStatistics` object. It computes similarity by checking `target_seq[None] == chain_msa` [alphafold/data/msa_pairing.py:112-116]() and gap percentages using `chain_msa == MSA_GAP_IDX` [alphafold/data/msa_pairing.py:117-121]().
*   **`to_species_dict()`** [alphafold/data/msa_pairing.py:132-150](): Groups MSA rows by species identifier, returning a mapping from species bytes to `MSAStatistics` objects.
*   **`get_top_msa_rows()`** [alphafold/data/msa_pairing.py:127-130](): Returns row indices sorted by descending sequence similarity.

```mermaid
graph LR
    ChainFeats["Chain Features<br/>(pipeline.FeatureDict)"]
    
    Constructor["MSAStatistics.from_chain_features()"]
    
    Stats["MSAStatistics Object<br/>(row, similarity, gap)"]
    
    SpeciesMap["to_species_dict()"]
    
    Lookup["Mapping:<br/>species_id -> MSAStatistics"]
    
    ChainFeats --> Constructor
    Constructor --> Stats
    Stats --> SpeciesMap
    SpeciesMap --> Lookup
```

**Diagram: MSAStatistics Construction and Species Grouping**

**Sources:** [alphafold/data/msa_pairing.py:70-151]()

---

## Sequence Pairing Algorithm

### The Pairing Process

The core logic resides in `pair_sequences()` [alphafold/data/msa_pairing.py:256-319](). It identifies which rows across multiple MSAs should be linked.

1.  **Initialize with target sequences**: The first row of each MSA (the target) is always paired [alphafold/data/msa_pairing.py:282-284]().
2.  **Find common species**: It identifies all species present in at least two chains [alphafold/data/msa_pairing.py:270-280]().
3.  **Filter and Match**:
    *   It skips species present in only one chain [alphafold/data/msa_pairing.py:298-300]().
    *   It skips species with more than 600 sequences in a single chain to avoid combinatorial explosion [alphafold/data/msa_pairing.py:302-310]().
    *   It calls `_match_rows_by_sequence_similarity()` to perform greedy matching [alphafold/data/msa_pairing.py:312]().

### Greedy Similarity Matching

The `_match_rows_by_sequence_similarity()` function [alphafold/data/msa_pairing.py:220-253]() performs the following:
*   Sorts sequences of the same species in each chain by similarity to the target [alphafold/data/msa_pairing.py:248]().
*   Pairs the top $N$ sequences across chains, where $N$ is the count in the chain with the fewest sequences for that species [alphafold/data/msa_pairing.py:240-252]().
*   If a chain is missing a species entirely, it uses a padding index `-1` [alphafold/data/msa_pairing.py:250]().

### Reordering

`reorder_paired_rows()` [alphafold/data/msa_pairing.py:322-346]() sorts the final paired set. It prioritizes pairings that include the most chains (descending order of `num_chains_paired`) [alphafold/data/msa_pairing.py:340]().

**Sources:** [alphafold/data/msa_pairing.py:220-346]()

---

## Feature Merging Strategies

AlphaFold Multimer uses two distinct merging strategies for MSA features.

### 1. Paired Concatenation
Paired sequences (those identified by `pair_sequences`) are concatenated horizontally along the residue dimension. This creates a "dense" MSA row representing the entire complex.

### 2. Block Diagonalization (Unpaired)
Unpaired sequences (sequences found in one chain's MSA that couldn't be paired) are block-diagonalized using `block_diag()` [alphafold/data/msa_pairing.py:349-355](). This means a sequence for Chain A is padded with gaps for all positions belonging to Chain B.

| Feature Type | Paired Rows | Unpaired Rows |
| :--- | :--- | :--- |
| **MSA** (`msa`) | Concatenated | Block-diagonalized |
| **Deletion Matrix** | Concatenated | Block-diagonalized |
| **Sequence** (`aatype`) | Concatenated | Concatenated |
| **Templates** | Concatenated | Concatenated |

**Sources:** [alphafold/data/msa_pairing.py:349-355](), [alphafold/data/msa_pairing.py:434-466]()

---

## The Complete Merging Pipeline

The function `merge_chain_features()` [alphafold/data/msa_pairing.py:513-543]() is the high-level orchestrator that assembles the final model features.

```mermaid
graph TB
    Input["List of chain FeatureDicts"]
    
    Templates["_pad_templates()<br/>Standardize template counts"]
    
    Homomers["_merge_homomers_dense_msa()<br/>Merge identical entities"]
    
    Unpaired["_merge_features_from_multiple_chains()<br/>Diagonalize unpaired MSAs"]
    
    PairCheck{{"pair_msa_sequences?"}}
    
    PairedMerge["_concatenate_paired_and_unpaired_features()<br/>Combine paired rows with diagonalized ones"]
    
    Correction["_correct_post_merged_feats()<br/>Finalize shapes and masks"]
    
    Input --> Templates
    Templates --> Homomers
    Homomers --> Unpaired
    Unpaired --> PairCheck
    PairCheck -- Yes --> PairedMerge
    PairCheck -- No --> Correction
    PairedMerge --> Correction
```

**Diagram: merge_chain_features() Execution Flow**

### Key Pipeline Components

*   **`_merge_homomers_dense_msa()`** [alphafold/data/msa_pairing.py:469-495](): Handles chains with the same `entity_id` (homomers). These are merged with concatenation to provide a dense representation.
*   **`_correct_post_merged_feats()`** [alphafold/data/msa_pairing.py:358-408](): Updates `num_alignments` and `seq_length`. It also generates the `cluster_bias_mask` [alphafold/data/msa_pairing.py:391-393]() and initializes the `bert_mask` [alphafold/data/msa_pairing.py:395-396]().
*   **`deduplicate_unpaired_sequences()`** [alphafold/data/msa_pairing.py:546-567](): Removes any unpaired sequences that are identical to sequences already present in the paired MSA section to reduce redundancy.

**Sources:** [alphafold/data/msa_pairing.py:358-567]()

---

## Feature Padding and Constants

The system uses specific padding values defined in `MSA_PAD_VALUES` [alphafold/data/msa_pairing.py:31-40]():
*   `msa`: `MSA_GAP_IDX` (20) [alphafold/data/msa_pairing.py:36]().
*   `msa_mask`: 1 [alphafold/data/msa_pairing.py:37]().
*   `deletion_matrix`: 0 [alphafold/data/msa_pairing.py:38]().

The `pad_features()` function [alphafold/data/msa_pairing.py:188-217]() is used to add a single "padding" row to the end of a feature array, which is then indexed by the pairing algorithm when a chain lacks a specific species match.

**Sources:** [alphafold/data/msa_pairing.py:27-40](), [alphafold/data/msa_pairing.py:188-217]()

---