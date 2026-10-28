# Embedding Generation

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [src/bioemu/get_embeds.py](src/bioemu/get_embeds.py)
- [tests/test_embeds.py](tests/test_embeds.py)

</details>



## Purpose and Overview

This document describes how BioEmu generates and manages protein sequence embeddings, which are critical representations that capture evolutionary information needed for accurate protein structure prediction. The embedding generation process leverages ColabFold to create both single (per-residue) and pair (residue-residue interaction) representations from input amino acid sequences.

For information about how these embeddings are used in structure sampling, see [Protein Structure Sampling](#3.1).

## Embedding Generation Process

The embedding generation workflow consists of several steps, from receiving an input sequence to outputting numerical representations that can be used by the diffusion model.

```mermaid
flowchart LR
    seq["Amino Acid Sequence"] --> hash["SHA256 Hash Generation"]
    hash --> cache_check{"Cached\nEmbeddings\nExist?"}
    cache_check -->|"Yes"| load["Load Cached Embeddings"]
    cache_check -->|"No"| fasta["Convert to FASTA"]
    fasta --> cf["Run ColabFold"]
    cf --> save["Save Embeddings to Cache"]
    save --> emb["Return Embedding Paths"]
    load --> emb
```

Sources: [src/bioemu/get_embeds.py:127-203](). [src/bioemu/get_embeds.py:28-30]().

## Key Components and Technical Implementation

### Embedding Types

BioEmu generates and uses two types of embeddings:

1. **Single Representations**: Per-residue embeddings that capture information about each amino acid in the sequence
2. **Pair Representations**: Residue-residue interaction embeddings that capture information about how different positions in the sequence relate to each other

```mermaid
graph TD
    subgraph "Embedding Files"
        single["Single Representation\n{hash}_single.npy"]
        pair["Pair Representation\n{hash}_pair.npy"]
    end
    
    subgraph "Dimensionality"
        single --- dims1["Shape: (L, D)\nL = sequence length\nD = embedding dimension"]
        pair --- dims2["Shape: (L, L, D')\nL = sequence length\nD' = pair embedding dimension"]
    end
```

Sources: [src/bioemu/get_embeds.py:155-156](). [tests/test_embeds.py:27-28]().

### Caching Mechanism

BioEmu implements an efficient caching system to avoid redundant computation of embeddings:

```mermaid
flowchart TD
    input["Input: Protein Sequence"] --> hash["Generate SHA256 Hash"]
    hash --> paths["Generate Cache Paths"]
    paths --> check{"Check Cache\nExistence"}
    check -->|"Cache Exists"| return["Return Cached Paths"]
    check -->|"Cache Missing"| compute["Run ColabFold"]
    compute --> save["Save Embeddings to Cache"]
    save --> return
```

Sources: [src/bioemu/get_embeds.py:147-160](). [src/bioemu/get_embeds.py:83-85]().

The cache directory defaults to `~/.bioemu_embeds_cache` but can be customized when calling the embedding functions.

### ColabFold Integration

BioEmu integrates with ColabFold by:

1. Managing the ColabFold installation
2. Preparing input files in the required format
3. Executing ColabFold with appropriate parameters
4. Extracting and storing the resulting embeddings

```mermaid
graph TB
    subgraph "ColabFold Integration"
        install["ensure_colabfold_install()"]
        run["run_colabfold()"]
        extract["Extract Embeddings"]
    end
    
    subgraph "Key Parameters"
        model["--model-type alphafold2"]
        order["--model-order 3"]
        recycle["--num-recycle 0"]
        save["--save-single-representations\n--save-pair-representations"]
    end
    
    install --> run
    run --> extract
    model --- run
    order --- run
    recycle --- run
    save --- run
```

Sources: [src/bioemu/get_embeds.py:58-80](). [src/bioemu/get_embeds.py:88-124]().

## API Usage

### Primary Function: `get_colabfold_embeds`

The main API for generating embeddings is the `get_colabfold_embeds` function:

```
get_colabfold_embeds(
    seq: str,
    cache_embeds_dir: StrPath | None,
    msa_file: StrPath | None = None,
    msa_host_url: str | None = None
) -> tuple[StrPath, StrPath]
```

This function takes a protein sequence and returns paths to the single and pair embeddings.

| Parameter | Type | Description |
|-----------|------|-------------|
| `seq` | `str` | Protein sequence in one-letter amino acid code |
| `cache_embeds_dir` | `StrPath \| None` | Directory to store cached embeddings (defaults to `~/.bioemu_embeds_cache`) |
| `msa_file` | `StrPath \| None` | Optional path to a precomputed MSA file in A3M format |
| `msa_host_url` | `str \| None` | Optional URL for a custom MSA server |

**Return value**: A tuple of paths `(single_rep_file, pair_rep_file)` to the embedding files.

Sources: [src/bioemu/get_embeds.py:127-143](). [tests/test_embeds.py:32-54]().

### Input/Output File Structure

The embedding generation system uses several file types:

```mermaid
graph LR
    subgraph "Input Files"
        fasta[".fasta\nAmino Acid Sequence"]
        a3m[".a3m\nMultiple Sequence Alignment"]
    end
    
    subgraph "Output Files"
        single["{hash}_single.npy\nSingle Representation"]
        pair["{hash}_pair.npy\nPair Representation"]
        hash_fasta["{hash}.fasta\nReference Sequence"]
    end
    
    fasta --> process["get_colabfold_embeds()"]
    a3m -->|"Optional"| process
    process --> single
    process --> pair
    process --> hash_fasta
```

Sources: [src/bioemu/get_embeds.py:155-156](). [src/bioemu/get_embeds.py:201]().

## Implementation Details

### Sequence Hashing

BioEmu uses SHA-256 hashing to generate unique identifiers for protein sequences, which are used for embedding file naming and lookup:

```python
def shahexencode(s: str) -> str:
    """Simple sha256 string encoding"""
    return hashlib.sha256(s.encode()).hexdigest()
```

This ensures a deterministic mapping between sequences and their cached embeddings.

Sources: [src/bioemu/get_embeds.py:28-30]().

### ColabFold Configuration

The system runs ColabFold with specific parameters:

- Uses model 3 of AlphaFold2 for embedding generation
- Disables recycling for faster computation
- Explicitly saves both single and pair representations
- Allows customization of MSA server URLs

Sources: [src/bioemu/get_embeds.py:107-123]().

### Automated Installation

The system ensures ColabFold is properly installed before attempting to generate embeddings:

```mermaid
flowchart TD
    start["ensure_colabfold_install()"] --> check{"ColabFold\nInstalled?"}
    check -->|"Yes"| verify{"Properly\nPatched?"}
    check -->|"No"| install["Run Installation Script"]
    verify -->|"No"| fail["Assert Failure"]
    verify -->|"Yes"| return["Return ColabFold bin directory"]
    install --> return
```

Sources: [src/bioemu/get_embeds.py:58-80]().

### MSA Sources

BioEmu supports multiple sources for Multiple Sequence Alignments (MSAs):

1. **Default**: Uses ColabFold's remote MSA server
2. **Custom MSA server**: Allows specifying an alternative MSA server URL
3. **Precomputed MSA**: Accepts a3m files containing precomputed MSAs

Note: When using precomputed MSAs, the system warns that this might result in different distributions than those produced by the default ColabFold MSA server.

Sources: [src/bioemu/get_embeds.py:176-181]().

## Integration with BioEmu Pipeline

The embedding generation component integrates with the broader BioEmu system as follows:

```mermaid
flowchart LR
    subgraph "BioEmu Pipeline"
        input["Amino Acid Sequence"] --> embeds["Embedding Generation\nget_colabfold_embeds()"]
        embeds --> diffusion["Diffusion Model\nStructure Sampling"]
        diffusion --> output["Protein Structure Ensemble"]
    end
    
    subgraph "Data Flow"
        seq["Sequence (str)"] --> sha["SHA256 Hash"]
        sha --> cache["Cache Lookup"]
        cache --> |"Miss"| colabfold["ColabFold Processing"]
        colabfold --> numpy["Numpy Arrays\n{hash}_single.npy\n{hash}_pair.npy"]
        cache -->|"Hit"| numpy
        numpy --> tensors["PyTorch Tensors"]
    end
```

Sources: [src/bioemu/get_embeds.py:127-203]().

## Performance and Practical Considerations

- Embeddings are computed only once per unique sequence and cached for future use
- The first-time embedding generation can take several minutes depending on sequence length
- Cached embeddings load almost instantly
- MSA generation by ColabFold requires internet access unless a local MSA server or precomputed MSA is provided
- The embedding cache can grow large for many sequences, so consider monitoring disk usage

---