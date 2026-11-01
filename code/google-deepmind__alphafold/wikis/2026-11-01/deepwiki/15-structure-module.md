# Structure Module

<details>
<summary>Relevant source files</summary>

The following files were used as context for generating this wiki page:

- [alphafold/common/residue_constants_test.py](alphafold/common/residue_constants_test.py)
- [alphafold/model/all_atom.py](alphafold/model/all_atom.py)
- [alphafold/model/all_atom_multimer.py](alphafold/model/all_atom_multimer.py)
- [alphafold/model/all_atom_test.py](alphafold/model/all_atom_test.py)
- [alphafold/model/folding.py](alphafold/model/folding.py)
- [alphafold/model/folding_multimer.py](alphafold/model/folding_multimer.py)
- [alphafold/model/mapping.py](alphafold/model/mapping.py)
- [alphafold/model/prng.py](alphafold/model/prng.py)
- [alphafold/model/quat_affine.py](alphafold/model/quat_affine.py)

</details>



The Structure Module is a critical component of AlphaFold that transforms the abstract representations from the Evoformer into 3D atomic coordinates. It implements an iterative, attention-based folding process that produces physically plausible protein structures. This document explains the architecture, key components, and operating principles of the Structure Module.

## 1. Role in AlphaFold Pipeline

The Structure Module is the final major computational step in the AlphaFold architecture that performs the actual 3D structure prediction. It receives pair and single representations from the Evoformer and outputs atomic coordinates.

```mermaid
flowchart LR
    subgraph "Evoformer Processing"
        MSA["MSA Representation"] --> Single["Single Representation"]
        MSA --> Pair["Pair Representation"]
    end

    Single --> StructMod["Structure Module"]
    Pair --> StructMod
    
    subgraph "Structure Module"
        StructMod --> FoldIter["Iterative Folding"]
        FoldIter --> Frames["Rigid Body Frames"]
        Frames --> Coords["3D Coordinates"]
    end
    
    Coords --> Output["Final Structure\nPDB/mmCIF"]
```

Sources: 
- [alphafold/model/folding_multimer.py:556-625]()

## 2. Core Architecture and Components

The Structure Module follows an iterative refinement approach where it gradually improves the 3D structure through multiple folding iterations.

```mermaid
flowchart TD
    Input["Input Representations"] --> SM["StructureModule"]
    
    subgraph "Structure Module"
        SM --> GMR["generate_monomer_rigids"]
        
        subgraph "Iterative Folding"
            GMR --> |"For each layer"| FI["FoldIteration"]
            FI --> |"1. Apply attention"| IPA["InvariantPointAttention"]
            FI --> |"2. Update representations"| TR["Transition Layers"]
            FI --> |"3. Update coordinates"| RU["Rigid Update"]
            FI --> |"4. Predict sidechains"| SC["MultiRigidSidechain"]
        end
    end
    
    SC --> |"Convert to atom positions"| AA14["Atom14 Positions"]
    AA14 --> |"Convert representation"| AA37["Atom37 Positions"]
    AA37 --> Output["Final Protein Structure"]
```

Sources:
- [alphafold/model/folding_multimer.py:556-625]()
- [alphafold/model/folding_multimer.py:374-476]()
- [alphafold/model/folding_multimer.py:478-553]()

## 3. Key Components

### 3.1 Rigid Body Representations

The Structure Module uses rigid body transformations (`Rigid3Array`) to represent the position and orientation of residues and atoms in 3D space. These consist of:

1. **Rotation**: Represented using `Rot3Array` (often parameterized as quaternions)
2. **Translation**: Represented using `Vec3Array` for 3D positions

```mermaid
classDiagram
    class Rigid3Array {
        rotation: Rot3Array
        translation: Vec3Array
        apply_to_point()
        inverse()
        compose()
    }
    
    class QuatRigid {
        __call__(activations) -> Rigid3Array
    }
    
    Rigid3Array -- QuatRigid : creates
```

Sources:
- [alphafold/model/folding_multimer.py:65-137]()
- [alphafold/model/folding_multimer.py:512]()
- [alphafold/model/quat_affine.py:200-222]()

### 3.2 Invariant Point Attention

The `InvariantPointAttention` module is a specialized attention mechanism that works in 3D space. Unlike standard attention which operates solely on feature vectors, InvariantPointAttention:

1. Projects queries and keys as points in 3D space via `PointProjection` [alphafold/model/folding_multimer.py:144-192]().
2. Computes attention based on Euclidean distances between these points.
3. Combines 3D point-based attention with traditional scalar attention.
4. Enables the model to reason about spatial relationships in a geometrically meaningful way.

```mermaid
flowchart TD
    I1D["Inputs 1D\n(N, C)"] --> QPointProj["q_point_projection"]
    I1D --> KPointProj["k_point_projection"]
    I1D --> QScalarProj["q_scalar_projection"]
    I1D --> KScalarProj["k_scalar_projection"]
    I1D --> VScalarProj["v_scalar_projection"]
    I1D --> VPointProj["v_point_projection"]
    
    I2D["Inputs 2D\n(N, M, C')"] --> Attn2D["attention_2d"]
    
    QPointProj --> |"(N, num_head, num_point_qk)"| PointDist["Point Distance\nComputation"]
    KPointProj --> |"(N, num_head, num_point_qk)"| PointDist
    
    QScalarProj --> |"(N, num_head, num_scalar_qk)"| ScalarAttn["Scalar Attention\nComputation"]
    KScalarProj --> |"(N, num_head, num_scalar_qk)"| ScalarAttn
    
    PointDist --> |"-0.5 * dist²"| AttnLogits["Attention Logits"]
    ScalarAttn --> AttnLogits
    Attn2D --> AttnLogits
    
    AttnLogits --> |"softmax"| AttnWeights["Attention Weights"]
    
    AttnWeights --> |"Apply to value vectors"| ResultScalar["Result Scalar"]
    VScalarProj --> ResultScalar
    
    AttnWeights --> |"Apply to value points"| ResultPoint["Result Point"]
    VPointProj --> ResultPoint
    
    ResultScalar --> |"Concatenate"| OutputFeatures["Output Features"]
    ResultPoint --> |"Transform to local frame"| OutputFeatures
    
    OutputFeatures --> OutputProj["Output Projection"]
```

Sources:
- [alphafold/model/folding_multimer.py:188-371]()
- [alphafold/model/folding.py:37-198]()

### 3.3 FoldIteration

The `FoldIteration` class performs a single step of the iterative folding process and is composed of:

1. **Attention Layer**: Uses `InvariantPointAttention` to update residue features [alphafold/model/folding_multimer.py:408-414]().
2. **Transition Layers**: Several feed-forward layers to transform the features [alphafold/model/folding_multimer.py:446-455]().
3. **Rigid Update**: Updates the rigid frames using the refined features via `QuatRigid` [alphafold/model/folding_multimer.py:461-468]().
4. **Sidechain Prediction**: Predicts sidechain positions using `MultiRigidSidechain` [alphafold/model/folding_multimer.py:470-476]().

Sources:
- [alphafold/model/folding_multimer.py:374-476]()

### 3.4 MultiRigidSidechain

The `MultiRigidSidechain` class predicts the positions of sidechain atoms using:

1. Residue representations to predict torsion angles (chi angles) [alphafold/model/folding_multimer.py:1124-1129]().
2. Conversion of torsion angles to 3D frames via `torsion_angles_to_frames` [alphafold/model/all_atom_multimer.py:374-438]().
3. Placement of atoms according to standard residue templates via `frames_and_literature_positions_to_atom14_pos` [alphafold/model/all_atom_multimer.py:441-472]().

```mermaid
flowchart LR
    Rigid["Rigid Frames"] --> MRSC["MultiRigidSidechain"]
    Repr["Representations"] --> MRSC
    AAtype["Amino Acid Types"] --> MRSC
    
    subgraph "MultiRigidSidechain"
        MRSC --> |"Residual blocks"| Act["Activations"]
        Act --> |"Predict angles"| Angles["Torsion Angles"]
        Angles --> |"torsion_angles_to_frames"| Frames["All Frames"]
        Frames --> |"frames_and_literature_positions_to_atom14_pos"| AtomPos["Atom Positions"]
    end
    
    Frames --> Output["Output Dict"]
    AtomPos --> Output
    Angles --> Output
```

Sources:
- [alphafold/model/folding_multimer.py:1079-1162]()
- [alphafold/model/all_atom_multimer.py:374-438]()
- [alphafold/model/all_atom_multimer.py:441-472]()

## 4. Folding Process

The Structure Module implements protein folding as an iterative process through the `generate_monomer_rigids` function:

1. **Initialization**: Start with a flat structure (identity rigid transforms) [alphafold/model/folding_multimer.py:497-512]().
2. **Iterative Refinement**: Apply multiple layers of `FoldIteration` [alphafold/model/folding_multimer.py:514-531]().
3. **Final Structure**: Produce the final atom positions and frames [alphafold/model/folding_multimer.py:533-553]().

```mermaid
sequenceDiagram
    participant SM as StructureModule
    participant GMR as generate_monomer_rigids
    participant FI as FoldIteration
    participant IPA as InvariantPointAttention
    participant MRSC as MultiRigidSidechain
    
    SM->>GMR: Call with representations
    GMR->>GMR: Initialize rigid frames
    
    loop For each layer
        GMR->>FI: Apply fold iteration
        FI->>IPA: Apply attention
        IPA-->>FI: Updated activations
        FI->>FI: Apply transition layers
        FI->>FI: Update rigid frames
        FI->>MRSC: Predict sidechains
        MRSC-->>FI: Sidechain positions
        FI-->>GMR: Updated activations and outputs
    end
    
    GMR-->>SM: Final structure (rigid frames & atom positions)
    SM->>SM: Convert to atom37 representation
    SM-->>User: Final atom positions and masks
```

Sources:
- [alphafold/model/folding_multimer.py:478-553]()
- [alphafold/model/folding_multimer.py:570-625]()

## 5. Coordinate Systems and Representations

The Structure Module uses different representations for atom positions and transformations:

### 5.1 Atom Representation Formats

1. **atom14**: Compact representation with 14 atoms per residue [alphafold/model/all_atom.py:23-28]().
2. **atom37**: Complete representation with 37 atoms per residue [alphafold/model/all_atom.py:18-22]().

The module converts between these formats as needed using `atom14_to_atom37` [alphafold/model/all_atom.py:75-92]() and `atom37_to_atom14` [alphafold/model/all_atom.py:95-112]().

```mermaid
flowchart LR
    subgraph "atom14 Representation"
        direction TB
        A14["14 atoms per residue"]
        A14Pos["Local atom positions"]
    end
    
    subgraph "atom37 Representation"
        direction TB
        A37["37 atoms per residue"]
        A37Pos["Standard PDB format"]
    end
    
    A14 <--> |"atom14_to_atom37\natom37_to_atom14"| A37
```

Sources:
- [alphafold/model/folding_multimer.py:604-615]()
- [alphafold/model/all_atom.py:15-34]()
- [alphafold/model/all_atom_multimer.py:225-254]()

### 5.2 Rigid Transformations and Frames

The module uses a hierarchical system of rigid body frames:

1. **Backbone Frame**: Defines the position/orientation of each residue (N, CA, C atoms) [alphafold/model/folding_multimer.py:52-62]().
2. **Sidechain Frames**: 8 frames per residue (1 backbone + 7 for sidechains/torsions) [alphafold/model/all_atom.py:115-147]().
3. **Global Coordinates**: Final atom positions in global coordinate system.

```mermaid
flowchart TD
    subgraph "Hierarchy of Frames"
        direction TB
        BackboneFrame["Backbone Frame\n(N, CA, C atoms)"]
        ChiFrames["Chi Frames\n(χ1, χ2, χ3, χ4)"]
        AtomPos["Atom Positions"]
        
        BackboneFrame --> ChiFrames
        ChiFrames --> AtomPos
    end
```

Sources:
- [alphafold/model/all_atom_multimer.py:275-371]()
- [alphafold/model/all_atom_multimer.py:374-438]()

## 6. Loss Functions and Violation Detection

During training, the Structure Module evaluates the quality of predicted structures using several loss functions:

1. **Frame-Aligned Point Error (FAPE)**: Measures structural accuracy by aligning frames and computing positional errors [alphafold/model/all_atom.py:533-596]().
2. **Sidechain Loss**: FAPE applied to sidechain atoms [alphafold/model/folding_multimer.py:831-868]().
3. **Chi Angle Loss**: Penalizes incorrect torsion angles [alphafold/model/folding_multimer.py:874-877]().
4. **Structural Violation Loss**: Detects and penalizes physically impossible structures [alphafold/model/folding_multimer.py:889-978]().

The module also includes comprehensive violation detection via `find_structural_violations` [alphafold/model/all_atom_multimer.py:679-727]():

```mermaid
flowchart TD
    Pred["Predicted Structure"] --> VD["Violation Detection"]
    
    subgraph "Structural Violation Detection"
        VD --> BR["Between-Residue Violations"]
        VD --> WR["Within-Residue Violations"]
        
        BR --> Bond["Bond Length Violations"]
        BR --> Angle["Bond Angle Violations"]
        BR --> Clash["Clashes Between Residues"]
        
        WR --> Internal["Internal Clashes"]
        WR --> Constraints["Distance Constraint Violations"]
    end
    
    Bond --> VM["Violation Metrics"]
    Angle --> VM
    Clash --> VM
    Internal --> VM
    Constraints --> VM
```

Sources:
- [alphafold/model/folding_multimer.py:781-1008]()
- [alphafold/model/all_atom_multimer.py:475-727]()
- [alphafold/model/all_atom_test.py:96-190]()

## 7. Outputs and Integration

The Structure Module produces several key outputs:

1. **Atom Positions**: 3D coordinates for all atoms in atom14 and atom37 formats.
2. **Atom Masks**: Binary indicators of which atoms are present.
3. **Rigid Frames**: Positional and orientational information for residues.

```mermaid
flowchart LR
    SM["StructureModule"] --> |"compute_loss=False"| BasicOut["Basic Outputs"]
    SM --> |"compute_loss=True"| FullOut["Complete Outputs"]
    
    subgraph "Basic Outputs"
        BasicOut --> FinalAtomPos["final_atom_positions\n(N, 37, 3)"]
        BasicOut --> FinalAtomMask["final_atom_mask\n(N, 37)"]
        BasicOut --> ActOut["act\nActivations for confidence"]
    end
    
    subgraph "Complete Outputs (additional)"
        FullOut --> Traj["traj\nAll iteration frames"]
        FullOut --> SC["sidechains\nDetailed sidechain info"]
        FullOut --> Atom14Pos["final_atom14_positions\n(N, 14, 3)"]
        FullOut --> Atom14Mask["final_atom14_mask\n(N, 14)"]
    end
```

Sources:
- [alphafold/model/folding_multimer.py:591-624]()

## 8. Technical Implementation Details

### 8.1 Invariant Point Attention Details

The InvariantPointAttention mechanism is a key innovation that enables geometric reasoning. It:

1. Projects points in local reference frames.
2. Converts them to a global frame for distance calculations.
3. Combines scalar, point-based, and pair attention.

| Component | Dimension | Purpose |
|-----------|-----------|---------|
| q_point | (N, num_head, num_point_qk) | Query points |
| k_point | (N, num_head, num_point_qk) | Key points |
| q_scalar | (N, num_head, num_scalar_qk) | Query scalars |
| k_scalar | (N, num_head, num_scalar_qk) | Key scalars |
| v_scalar | (N, num_head, num_scalar_v) | Value scalars |
| v_point | (N, num_head, num_point_v) | Value points |
| attention_2d | (N, N, num_head) | Pair bias attention |

Sources:
- [alphafold/model/folding_multimer.py:188-371]()
- [alphafold/model/folding.py:115-166]()

### 8.2 Ambiguous Atom Handling

The Structure Module handles ambiguous atom naming in sidechains (e.g., symmetric atoms in PHE, TYR, ASP, GLU) by:

1. Considering alternative namesakes for ambiguous residues via `_make_renaming_matrices` [alphafold/model/all_atom_multimer.py:57-83]().
2. Computing optimal renaming to maximize structure accuracy.
3. Applying the optimal naming during evaluation in `supervised_chi_loss` [alphafold/model/all_atom_multimer.py:730-782]().

Sources:
- [alphafold/model/folding_multimer.py:752-778]()
- [alphafold/model/all_atom_multimer.py:57-83]()
- [alphafold/model/all_atom_multimer.py:730-782]()

## 9. Integration with Rest of AlphaFold

The Structure Module integrates with the rest of AlphaFold by:

1. Receiving representations from the Evoformer module.
2. Processing these representations to produce 3D structures.
3. Supporting the calculation of confidence metrics (pLDDT, PAE).
4. Providing structures for relaxation via the Amber force field.

The final outputs of the Structure Module include atom positions that can be directly converted to PDB/mmCIF format for visualization and analysis.

Sources:
- [alphafold/model/folding_multimer.py:556-625]()

---