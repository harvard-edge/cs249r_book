---
title: "Attention - The Mechanism That Powers Modern AI"
description: "Build scaled dot-product and multi-head attention mechanisms from scratch"
difficulty: "⭐⭐⭐"
time_estimate: "5-6 hours"
prerequisites: ["01_tensor", "02_activations", "03_layers", "11_embeddings"]
next_steps: ["13_transformers"]
learning_objectives:
  - "Understand attention's O(n²) scaling behavior and memory bottlenecks in production systems"
  - "Implement scaled dot-product attention with proper numerical stability and gradient flow"
  - "Build multi-head attention with parallel representation subspaces and head concatenation"
  - "Master masking strategies for causal (GPT), bidirectional (BERT), and padding patterns"
  - "Analyze attention pattern trade-offs: computation cost, memory usage, and interpretability"
---

# 12. Attention - The Mechanism That Powers Modern AI

**ARCHITECTURE TIER** | Difficulty: ⭐⭐⭐ (3/4) | Time: 5-6 hours

## Overview

Implement the attention mechanism that revolutionized AI and sparked the modern transformer era. This module builds scaled dot-product attention and multi-head attention—the exact mechanisms powering GPT, BERT, Claude, and every major language model deployed today. You'll implement attention with explicit loops to viscerally understand the O(n²) complexity that defines both the power and limitations of transformer architectures.

The "Attention is All You Need" paper (2017) introduced these mechanisms and replaced RNNs with pure attention architectures, enabling parallelization and global context from layer one. Understanding attention from first principles—including its computational bottlenecks—is essential for working with production transformers and understanding why FlashAttention, sparse attention, and linear attention are active research frontiers.

## Learning Objectives

By the end of this module, you will be able to:

- **Understand O(n²) Complexity**: Implement attention with explicit loops to witness quadratic scaling in memory and computation, understanding why long-context AI remains challenging
- **Build Scaled Dot-Product Attention**: Implement softmax(QK^T / √d_k)V with proper numerical stability, understanding how 1/√d_k prevents gradient vanishing
- **Create Multi-Head Attention**: Build parallel attention heads that learn different patterns (syntax, semantics, position) and concatenate their outputs for rich representations
- **Master Masking Strategies**: Implement causal masking for autoregressive generation (GPT), understand bidirectional attention for encoding (BERT), and handle padding masks
- **Analyze Production Trade-offs**: Experience attention's memory bottleneck firsthand, understand why FlashAttention matters, and explore the compute-memory trade-off space

## Build → Use → Reflect

This module follows TinyTorch's **Build → Use → Reflect** framework:

1. **Build**: Implement scaled dot-product attention with explicit O(n²) loops (educational), create MultiHeadAttention class with Q/K/V projections and head splitting, and build masking utilities
2. **Use**: Apply attention to realistic sequences with causal masking for language modeling, visualize attention patterns showing what the model "sees," and test with different head configurations
3. **Reflect**: Why does attention scale O(n²)? How do different heads specialize without supervision? What memory bottlenecks emerge at GPT-4 scale (128 heads, 8K+ context)?

## Implementation Guide

### Attention Mechanism Flow

The attention mechanism transforms queries, keys, and values into context-aware representations:

```{mermaid}
graph LR
    A[Query<br/>Q: n×d] --> D[Scores<br/>QK^T/√d]
    B[Key<br/>K: n×d] --> D
    D --> E[Attention<br/>Weights<br/>softmax]
    E --> F[Context<br/>×V]
    C[Value<br/>V: n×d] --> F
    F --> G[Output<br/>n×d]

    style A fill:#e3f2fd
    style B fill:#e3f2fd
    style C fill:#e3f2fd
    style D fill:#fff3e0
    style E fill:#ffe0b2
    style F fill:#f3e5f5
    style G fill:#f0fdf4
```

**Flow**: Queries attend to Keys (QK^T) → Scale by √d → Softmax for weights → Weighted sum of Values → Context output

### Core Components

Your attention implementation consists of three fundamental building blocks:

#### 1. Scaled Dot-Product Attention (`scaled_dot_product_attention`)

The mathematical foundation that powers all transformers:

```python
def scaled_dot_product_attention(Q, K, V, mask=None):
    """
    Attention(Q, K, V) = softmax(QK^T / √d_k) V

    This exact formula powers GPT, BERT, Claude, and all transformers.
    Implemented with explicit loops to show O(n²) complexity.

    Args:
        Q: Query matrix (batch, seq_len, d_model)
        K: Key matrix (batch, seq_len, d_model)
        V: Value matrix (batch, seq_len, d_model)
        mask: Optional causal mask (batch, seq_len, seq_len)

    Returns:
        output: Attended values (batch, seq_len, d_model)
        attention_weights: Attention matrix (batch, seq_len, seq_len)
    """
    # Step 1: Compute attention scores (O(n²) operation)
    # For each query i and key j: score[i,j] = Q[i] · K[j]

    # Step 2: Scale by 1/√d_k for numerical stability
    # Prevents softmax saturation as dimensionality increases

    # Step 3: Apply optional causal mask
    # Masked positions set to -1e9 (becomes ~0 after softmax)

    # Step 4: Softmax normalization (each row sums to 1)
    # Converts scores to probability distribution

    # Step 5: Weighted sum of values (another O(n²) operation)
    # output[i] = Σ(attention_weights[i,j] × V[j]) for all j
```

**Key Implementation Details:**
- **Explicit Loops**: Educational implementation shows exactly where O(n²) complexity comes from (every query attends to every key)
- **Scaling Factor**: 1/√d_k prevents dot products from growing large as dimensionality increases, maintaining gradient flow
- **Masking Before Softmax**: Setting masked positions to -1e9 makes them effectively zero after softmax
- **Return Attention Weights**: Essential for visualization and interpretability analysis

**What You'll Learn:**
- Why attention weights must sum to 1 (probability distribution property)
- How the scaling factor prevents gradient vanishing
- The exact computational cost: 2n²d operations (QK^T + weights×V)
- Why memory scales as O(batch × n²) for attention matrices

#### 2. Multi-Head Attention (`MultiHeadAttention`)

Parallel attention "heads" that learn different relationship patterns:

```python
class MultiHeadAttention:
    """
    Multi-head attention from 'Attention is All You Need'.

    Projects input to Q, K, V, splits into multiple heads,
    applies attention in parallel, concatenates, and projects output.

    Example: d_model=512, num_heads=8
    → Each head processes 64 dimensions (512 ÷ 8)
    → 8 heads learn different attention patterns in parallel
    """
    def __init__(self, embed_dim, num_heads):
        # Validate: embed_dim must be divisible by num_heads
        # Create Q, K, V projection layers (Linear(embed_dim, embed_dim))
        # Create output projection layer

    def forward(self, x, mask=None):
        # 1. Project input to Q, K, V
        # 2. Split into heads: (batch, seq, embed_dim) → (batch, heads, seq, head_dim)
        # 3. Apply attention to each head in parallel
        # 4. Concatenate heads back together
        # 5. Apply output projection to mix information across heads
```

**Architecture Flow:**
```
Input (batch, seq, 512)
    ↓ [Q/K/V Linear Projections]
Q, K, V (batch, seq, 512)
    ↓ [Reshape & Split into 8 heads]
(batch, 8 heads, seq, 64 per head)
    ↓ [Parallel Attention on Each Head]
Head₁ learns syntax patterns (subject-verb agreement)
Head₂ learns semantics (word similarity)
Head₃ learns position (relative distance)
Head₄ learns long-range (coreference)
...
    ↓ [Concatenate Heads]
(batch, seq, 512)
    ↓ [Output Projection]
Output (batch, seq, 512)
```

**Key Implementation Details:**
- **Head Splitting**: Reshape from (batch, seq, embed_dim) to (batch, heads, seq, head_dim) via transpose operations
- **Parallel Processing**: All heads compute simultaneously—GPU parallelism critical for efficiency
- **Four Linear Layers**: Three for Q/K/V projections, one for output (standard transformer architecture)
- **Head Concatenation**: Reverse the split operation to merge heads back to original dimensions

**What You'll Learn:**
- Why multiple heads capture richer representations than single-head
- How heads naturally specialize without explicit supervision
- The computational trade-off: same O(n²d) complexity but higher constant factor
- Why head_dim = embed_dim / num_heads is the standard configuration

#### 3. Masking Utilities

Control information flow patterns for different tasks:

```python
def create_causal_mask(seq_len):
    """
    Lower triangular mask for autoregressive (GPT-style) attention.
    Position i can only attend to positions ≤ i (no future peeking).

    Example (seq_len=4):
        [[1, 0, 0, 0],     # Position 0 sees only position 0
         [1, 1, 0, 0],     # Position 1 sees 0, 1
         [1, 1, 1, 0],     # Position 2 sees 0, 1, 2
         [1, 1, 1, 1]]     # Position 3 sees all positions
    """
    return Tensor(np.tril(np.ones((seq_len, seq_len))))

def create_padding_mask(lengths, max_length):
    """
    Prevents attention to padding tokens in variable-length sequences.
    Essential for efficient batching of different-length sequences.
    """
    # Create mask where 1=real token, 0=padding
    # Shape: (batch_size, 1, 1, max_length) for broadcasting
```

**Masking Strategies:**
- **Causal (GPT)**: Lower triangular—blocks n(n-1)/2 connections for autoregressive generation
- **Bidirectional (BERT)**: No mask—full n² connections for encoding with full context
- **Padding**: Batch-specific—prevents attention to padding tokens in variable-length batches
- **Combined**: Can multiply masks element-wise (e.g., causal + padding)

**What You'll Learn:**
- How masking strategy fundamentally defines model capabilities (generation vs encoding)
- Why causal masking is essential for language modeling training stability
- The performance benefit of efficient batching with padding masks
- How mask shape broadcasting works with attention scores

### Attention Complexity Analysis

Understanding the computational and memory bottlenecks:

#### Time Complexity: O(n² × d)

```
For sequence length n and embedding dimension d:

QK^T computation:
- n queries × n keys = n² similarity scores
- Each score: dot product over d dimensions
- Total: O(n² × d) operations

Softmax normalization:
- Apply to n² scores
- Total: O(n²) operations

Attention × Values:
- n² weights × n values = n³ operations
- But dimension d: effectively O(n² × d)
- Total: O(n² × d) operations

Dominant: O(n² × d) for both QK^T and weights×V
```

**Scaling Impact:**
- Doubling sequence length quadruples compute
- n=1024 → 1M scores per head
- n=4096 (GPT-3) → 16M scores per head (16× more)
- n=32K (GPT-4) → 1B scores per head (1000× more than 1024)

#### Memory Complexity: O(batch × heads × n²)

```
Attention weights matrix shape: (batch, heads, seq_len, seq_len)

Example: GPT-3 scale inference
- batch=32, heads=96, seq=2048
- Attention weights: 32 × 96 × 2048 × 2048 = 12.8 billion values
- At FP32 (4 bytes): 51.2 GB just for attention weights
- With 96 layers: 4.9 TB total (clearly infeasible!)

This is why:
- FlashAttention fuses operations to avoid storing attention matrix
- Mixed precision training uses FP16 (2× memory reduction)
- Gradient checkpointing recomputes instead of storing
- Production models use extensive optimization tricks
```

**The Memory Bottleneck:**
- For long contexts (32K+ tokens), attention memory dominates total usage
- Storing attention weights becomes infeasible—must compute on-the-fly
- FlashAttention breakthrough: O(n) memory instead of O(n²) via kernel fusion
- Understanding this bottleneck guides all modern attention optimization research

### Comparing to PyTorch

Your implementation vs `torch.nn.MultiheadAttention`:

| Aspect | Your TinyTorch Implementation | PyTorch Production |
|--------|-------------------------------|-------------------|
| **Algorithm** | Exact same: softmax(QK^T/√d_k)V | Same mathematical formula |
| **Loops** | Explicit (educational) | Fused GPU kernels |
| **Masking** | Manual application | Built-in mask parameter |
| **Memory** | O(n²) attention matrix stored | FlashAttention-optimized |
| **Batching** | Standard implementation | Highly optimized kernels |
| **Numerical Stability** | 1/√d_k scaling | Same + additional safeguards |

**What You Gained:**
- Deep understanding of O(n²) complexity by seeing explicit loops
- Insight into why FlashAttention and kernel fusion matter
- Knowledge of masking strategies and their architectural implications
- Foundation for understanding advanced attention variants (sparse, linear)

## Getting Started

### Prerequisites

Ensure you understand these foundations:

```bash
# Activate TinyTorch environment
source scripts/activate-tinytorch

# Verify prerequisite modules
tito test tensor      # Matrix operations (matmul, transpose)
tito test activations  # Softmax for attention normalization
tito test layers      # Linear layers for Q/K/V projections
tito test embeddings  # Token/position embeddings attention operates on
```

**Core Concepts You'll Need:**
- **Matrix Multiplication**: Understanding QK^T computation and broadcasting
- **Softmax Numerical Stability**: Subtracting max before exp prevents overflow
- **Layer Composition**: How Q/K/V projections combine with attention
- **Shape Manipulation**: Reshape and transpose operations for head splitting

### Development Workflow

1. **Open the development file**: `modules/12_attention/attention_dev.ipynb` (notebook) or `attention_dev.py` (script)
2. **Implement scaled_dot_product_attention**: Build core attention formula with explicit loops showing O(n²) complexity
3. **Create MultiHeadAttention class**: Add Q/K/V projections, head splitting, parallel attention, and output projection
4. **Build masking utilities**: Create causal mask for GPT-style attention and padding mask for batching
5. **Test and analyze**: Run comprehensive tests, visualize attention patterns, and profile computational scaling
6. **Export and verify**: `tito module complete 12 && tito test attention`

## Testing

### Comprehensive Test Suite

Run the full test suite to verify attention functionality:

```bash
# TinyTorch CLI (recommended)
tito test attention

# Direct pytest execution
python -m pytest tests/ -k attention -v

# Inline testing during development
python modules/12_attention/attention_dev.py
```

### Test Coverage Areas

- ✅ **Attention Scores Computation**: Verifies QK^T produces correct shapes and values
- ✅ **Numerical Stability**: Confirms 1/√d_k scaling prevents softmax saturation
- ✅ **Probability Normalization**: Validates attention weights sum to 1.0 per query
- ✅ **Causal Masking**: Tests that future positions get zero attention weight
- ✅ **Multi-Head Configuration**: Checks head splitting, parallel processing, and concatenation
- ✅ **Shape Preservation**: Ensures input shape equals output shape
- ✅ **Gradient Flow**: Verifies differentiability through attention computation graph
- ✅ **Computational Complexity**: Profiles O(n²) scaling with increasing sequence length

### Inline Testing & Complexity Analysis

The module includes comprehensive validation and performance analysis:

```python
🔬 Unit Test: Scaled Dot-Product Attention...
✅ Attention scores computed correctly (QK^T shape verified)
✅ Scaling factor 1/√d_k applied
✅ Softmax normalization verified (each row sums to 1.0)
✅ Output shape matches expected (batch, seq, d_model)
✅ Causal masking blocks future positions correctly
📈 Progress: Scaled Dot-Product Attention ✓

🔬 Unit Test: Multi-Head Attention...
✅ 8 heads process 512 dimensions in parallel
✅ Head splitting and concatenation correct
✅ Q/K/V projection layers initialized properly
✅ Output projection applied
✅ Shape: (batch, seq, 512) → (batch, seq, 512) ✓
📈 Progress: Multi-Head Attention ✓

📊 Analyzing Attention Complexity...
Seq Len | Attention Matrix | Memory (KB) | Scaling
--------------------------------------------------------
     16 |            256  |       1.00  |     1.0x
     32 |          1,024  |       4.00  |     4.0x
     64 |          4,096  |      16.00  |     4.0x
    128 |         16,384  |      64.00  |     4.0x
    256 |         65,536  |     256.00  |     4.0x

💡 Memory scales as O(n²) with sequence length
🚀 For seq_len=2048 (GPT-3), attention matrix needs 16 MB per layer
```

### Manual Testing Examples

```python
from attention_dev import scaled_dot_product_attention, MultiHeadAttention
from tinytorch.core.tensor import Tensor
import numpy as np

# Test 1: Basic scaled dot-product attention
batch, seq_len, d_model = 2, 10, 64
Q = Tensor(np.random.randn(batch, seq_len, d_model))
K = Tensor(np.random.randn(batch, seq_len, d_model))
V = Tensor(np.random.randn(batch, seq_len, d_model))

output, weights = scaled_dot_product_attention(Q, K, V)
print(f"Output shape: {output.shape}")  # (2, 10, 64)
print(f"Weights shape: {weights.shape}")  # (2, 10, 10)
print(f"Weights sum: {weights.data.sum(axis=2)}")  # All ~1.0

# Test 2: Multi-head attention
mha = MultiHeadAttention(embed_dim=128, num_heads=8)
x = Tensor(np.random.randn(2, 10, 128))
attended = mha.forward(x)
print(f"Multi-head output: {attended.shape}")  # (2, 10, 128)

# Test 3: Causal masking for language modeling
causal_mask = Tensor(np.tril(np.ones((batch, seq_len, seq_len))))
causal_output, causal_weights = scaled_dot_product_attention(Q, K, V, causal_mask)
# Verify upper triangle is zero (no future attention)
print("Future attention blocked:", np.allclose(causal_weights.data[0, 3, 4:], 0))

# Test 4: Visualize attention patterns
print("\nAttention pattern (position → position):")
print(weights.data[0, :5, :5].round(3))  # First 5x5 submatrix
```

## Systems Thinking Questions

### Real-World Applications

- **Large Language Models (GPT-4, Claude)**: 96+ layers with 128 heads each means 12,288+ parallel attention operations per forward pass; attention accounts for 70% of total compute
- **Machine Translation (Google Translate)**: Cross-attention between source and target languages enables word alignment; attention weights provide interpretable translation decisions
- **Vision Transformers (ViT)**: Self-attention over image patches replaced convolutions at Google/Meta/OpenAI; global receptive field from layer 1 vs deep CNN stacks
- **Scientific AI (AlphaFold2)**: Attention over protein sequences captures amino acid interactions; solved 50-year protein folding problem using transformer architecture

### Mathematical Foundations

- **Query-Key-Value Paradigm**: Attention implements differentiable "search"—queries look for relevant keys and retrieve corresponding values
- **Scaling Factor (1/√d_k)**: For unit variance Q and K, QK^T has variance d_k; dividing by √d_k restores unit variance, keeping softmax responsive (critical for gradient flow)
- **Softmax Normalization**: Converts arbitrary scores to valid probability distribution; enables differentiable, learned routing mechanism
- **Masking Implementation**: Setting masked positions to -∞ before softmax makes them effectively zero attention weight after normalization

### Computational Characteristics

- **Quadratic Memory Scaling**: Attention matrix is O(n²); for GPT-3 scale (96 layers, 2048 context), attention weights alone require ~1.5 GB—understanding this guides optimization priorities
- **Time-Memory Trade-off**: Can avoid storing attention matrix and recompute in backward pass (gradient checkpointing) at cost of 2× compute
- **Parallelization Benefits**: Unlike RNNs, all n² attention scores compute simultaneously; fully utilizes GPU parallelism for massive speedup
- **FlashAttention Breakthrough**: Reformulates computation order to reduce memory from O(n²) to O(n) via kernel fusion—enables 2-4× speedup and longer contexts (8K+ tokens)

### How Your Implementation Maps to PyTorch

**What you just built:**
```python
# Your TinyTorch attention implementation
from tinytorch.core.attention import MultiheadAttention

# Create multi-head attention
mha = MultiheadAttention(embed_dim=512, num_heads=8)

# Forward pass
query = Tensor(...)  # (batch, seq_len, embed_dim)
key = Tensor(...)
value = Tensor(...)

# Compute attention: YOUR implementation
output, attn_weights = mha(query, key, value, mask=causal_mask)
# output shape: (batch, seq_len, embed_dim)
# attn_weights shape: (batch, num_heads, seq_len, seq_len)
```

**How PyTorch does it:**
```python
# PyTorch equivalent
import torch.nn as nn

# Create multi-head attention
mha = nn.MultiheadAttention(embed_dim=512, num_heads=8, batch_first=True)

# Forward pass
query = torch.tensor(...)  # (batch, seq_len, embed_dim)
key = torch.tensor(...)
value = torch.tensor(...)

# Compute attention: PyTorch implementation
output, attn_weights = mha(query, key, value, attn_mask=causal_mask)
# Same shapes, identical semantics
```

**Key Insight**: Your attention implementation computes the **exact same mathematical formula** that powers GPT, BERT, and every transformer model:

```
Attention(Q, K, V) = softmax(QK^T / √d_k) V
```

When you implement this with explicit loops, you viscerally understand the O(n²) memory scaling that limits context length in production transformers.

**What's the SAME?**
- **Core formula**: Scaled dot-product attention (Vaswani et al., 2017)
- **Multi-head architecture**: Parallel attention in representation subspaces
- **Masking patterns**: Causal masking (GPT), padding masking (BERT)
- **API design**: `(query, key, value)` inputs, attention weights output
- **Conceptual bottleneck**: O(n²) memory for attention matrix

**What's different in production PyTorch?**
- **Backend**: C++/CUDA kernels ~10-100× faster than Python loops
- **Memory optimization**: Fused kernels avoid materializing full attention matrix
- **FlashAttention**: PyTorch 2.0+ uses optimized attention (O(n) memory vs your O(n²))
- **Multi-query attention**: Production systems use grouped-query attention (GQA) to reduce KV cache size

**Why this matters**: When you see `RuntimeError: CUDA out of memory` training transformers with long sequences, you understand it's the O(n²) attention matrix from YOUR implementation—doubling sequence length quadruples memory. When papers mention "linear attention" or "flash attention", you know they're solving the scaling bottleneck you experienced.

**Production usage example**:
```python
# PyTorch Transformer implementation (after TinyTorch)
import torch
import torch.nn as nn

class TransformerBlock(nn.Module):
    def __init__(self, d_model=512, num_heads=8):
        super().__init__()
        # Uses same multi-head attention you built
        self.mha = nn.MultiheadAttention(d_model, num_heads, batch_first=True)
        self.ffn = nn.Sequential(
            nn.Linear(d_model, 4 * d_model),
            nn.ReLU(),
            nn.Linear(4 * d_model, d_model)
        )

    def forward(self, x, mask=None):
        # Same pattern you implemented
        attn_out, _ = self.mha(x, x, x, attn_mask=mask)  # YOUR attention logic
        x = x + attn_out  # Residual connection
        x = x + self.ffn(x)
        return x
```

After implementing attention yourself, you understand that GPT's causal attention is your `mask=causal_mask`, BERT's bidirectional attention is your `mask=padding_mask`, and every transformer's O(n²) scaling comes from the attention matrix you explicitly computed in your implementation.

## Ready to Build?

You're about to implement the mechanism that sparked the AI revolution and powers every modern language model. Understanding attention from first principles—including its computational bottlenecks—will give you deep insight into why transformers dominate AI and what limitations remain.

**Your Mission**: Implement scaled dot-product attention with explicit loops to viscerally understand O(n²) complexity. Build multi-head attention that processes parallel representation subspaces. Master causal and padding masking for different architectural patterns. Test on real sequences, visualize attention patterns, and profile computational scaling.

**Why This Matters**: The attention mechanism you're building didn't just improve NLP—it unified deep learning across all domains. GPT, BERT, Vision Transformers, AlphaFold, DALL-E, and Claude all use the exact formula you're implementing. Understanding attention's power (global context, parallelizable) and limitations (quadratic scaling) is essential for working with production AI systems.

**After Completion**: Module 13 (Transformers) will combine your attention with feedforward layers and normalization to build complete transformer blocks. Module 14 (Profiling) will measure your attention's O(n²) scaling and identify optimization opportunities. Module 18 (Acceleration) will implement FlashAttention-style optimizations for your mechanism.

Choose your preferred way to engage with this module:

````{grid} 1 2 3 3

```{grid-item-card} 🚀 Launch Binder
:link: https://mybinder.org/v2/gh/mlsysbook/TinyTorch/main?filepath=modules/12_attention/attention_dev.ipynb
:class-header: bg-light

Run this module interactively in your browser. No installation required!
```

```{grid-item-card} ⚡ Open in Colab
:link: https://colab.research.google.com/github/mlsysbook/TinyTorch/blob/main/modules/12_attention/attention_dev.ipynb
:class-header: bg-light

Use Google Colab for GPU access and cloud compute power.
```

```{grid-item-card} 📖 View Source
:link: https://github.com/mlsysbook/TinyTorch/blob/main/modules/12_attention/attention_dev.ipynb
:class-header: bg-light

Browse the notebook source code and understand the implementation.
```

````

```{admonition} 💾 Save Your Progress
:class: tip
**Binder sessions are temporary!** Download your completed notebook when done, or switch to local development for persistent work.
```

---

<div class="prev-next-area">
<a class="left-prev" href="../chapters/11_embeddings.html" title="previous page">← Module 11: Embeddings</a>
<a class="right-next" href="../chapters/13_transformers.html" title="next page">Module 13: Transformers →</a>
</div>
