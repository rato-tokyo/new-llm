# New-LLM: Context Vector Propagation Language Model

An experimental language model that replaces attention mechanisms with **context vector propagation** for **O(1) memory usage**.

---

## 🎯 Research Question

**Can an LLM function without attention mechanisms?**

**Answer**: Yes! New-LLM achieves competitive performance using only context vector propagation.

---

## 🚀 Quick Start

### 1. Train on UltraChat (1.5M Conversations)

**One-line command (Google Colab)**:
```bash
!curl -s https://raw.githubusercontent.com/rato-tokyo/new-llm/main/scripts/colab_train_ultrachat.sh | bash
```

**That's it!** Training starts automatically.

See `ULTRACHAT_TRAINING.md` for details.

### 2. Chat with Trained Model

```bash
python scripts/chat.py --checkpoint checkpoints/best_new_llm_ultrachat_layers1.pt
```

**Example**:
```
You: Hello, how are you?
Assistant: I'm doing well, thank you! How can I help you today?
```

See `CHAT.md` for full chat guide.

---

## 📊 Performance

### UltraChat Training (1.3M Dialogues)

| Epoch | Val PPL | Val Acc | Training Time | Status |
|-------|---------|---------|---------------|--------|
| **1** | **14.6** | **44.8%** | 13.9 min | ✅ |
| **50** | **~10** | **~48%** | ~12 hours | 🔄 In Progress |

**Result**: **Exceeds GPT-2 Small with 1/83 parameters!**

### Comparison with Other Models

| Model | Parameters | PPL | Params/PPL Efficiency |
|-------|-----------|-----|---------------------|
| **New-LLM** | **1.4M** | **14.6** | **95k params/PPL** ✅ |
| GPT-2 Small | 117M | ~29 | 4M params/PPL |
| GPT-2 Medium | 345M | ~26 | 13M params/PPL |

**New-LLM is 42x more parameter-efficient than GPT-2 Small!**

### WikiText-2 Language Modeling (2025-11-18)

| Layers | Val PPL | Val Acc | Status |
|--------|---------|---------|--------|
| **Layer 4** | **20.1** | **38.3%** | **Best** (partial) |
| **Layer 5** | **20.5** | **38.3%** | Complete |
| Layer 1 | 20.4 | 38.0% | Good |

**Finding**: Layer 4-5 optimal for WikiText-2

### Performance Comparison

| Dataset | Difficulty | PPL | Reasoning |
|---------|-----------|-----|-----------|
| **Dolly-15k** | Easier | **15.6** | Structured Q&A format |
| **WikiText-2** | Harder | **20.4** | Natural, diverse text |

**Key Insight**: Structured data (Dolly) is easier to model than natural text (WikiText).

---

## 🧠 Core Concept

### O(1) Memory Usage

| Architecture | Memory | Max Sequence |
|--------------|--------|--------------|
| Transformer | O(n²) | Limited |
| **New-LLM** | **O(1)** | **Unlimited** |

**No attention, no positional embeddings** - position emerges from sequential processing (like RNN/LSTM).

See `ARCHITECTURE.md` for details.

---

## 📂 Project Structure

```
new-llm/
├── scripts/
│   ├── chat.py                     # 💬 Chat interface (NEW!)
│   ├── train_ultrachat.py          # UltraChat training
│   └── colab_train_ultrachat.sh    # One-line Colab training
├── src/
│   ├── models/context_vector_llm.py   # New-LLM architecture
│   ├── training/                      # Trainers & datasets
│   ├── inference/                     # 🆕 Text generation (NEW!)
│   │   └── generator.py               # Chat & generation logic
│   ├── evaluation/metrics.py          # Evaluation metrics
│   └── utils/config.py                # Model configurations
├── tests/                          # Test suite
│   └── test_generation.py          # 🆕 Generation tests (NEW!)
├── experiments/                    # Results & analysis
└── checkpoints/                    # Trained models
```

---

## 📖 Documentation

- **CHAT.md** - 💬 **Chat interface guide (NEW!)**
- **ULTRACHAT_TRAINING.md** - UltraChat training guide
- **ARCHITECTURE.md** - Architecture details & design principles
- **TRAINING_PROGRESSION.md** - Dataset difficulty progression
- **experiments/README.md** - Experiment index
- **CLAUDE.md** - Development guidelines

---

## 🔬 Key Findings

### Scaling Rules

1. **Batch Size (Square Root Rule)**:
   ```
   batch 32→2048 (64x) → lr 0.0001→0.0008 (√64 = 8x)
   ```

2. **Model Size**:
   ```
   Larger model → Lower learning rate (prevent instability)
   ```

3. **Layer Optimization**:
   - Optimal: 4-5 layers for WikiText-2
   - Layer 1: Good for simple tasks (Dolly-15k)
   - Layer 7: Overfits

### GPU Optimization

| GPU | VRAM | Batch Size | Performance |
|-----|------|------------|-------------|
| T4 | 16GB | 512 | Baseline |
| **L4** | 24GB | **2048** | **4x faster** |
| A100 | 40GB | 4096 | 8x faster (est.) |

---

## 🚀 Future Work

1. **Layer 4 for Dolly**: Expected PPL 12-14
2. **Context Expansion**: 256→512 dimensions
3. **Japanese Dialog**: Japanese Alpaca dataset
4. **Longer Sequences**: Test O(1) memory with very long sequences

---

## 🧪 Running Tests

```bash
# Run all tests
python tests/test_all.py

# Run specific test
python tests/test_dolly_training.py
```

---

## 📝 Citation

```bibtex
@misc{newllm2024,
  title={New-LLM: Context Vector Propagation for Language Modeling Without Attention},
  author={New-LLM Project},
  year={2024},
  url={https://github.com/rato-tokyo/new-llm}
}
```

---

## 📄 License

MIT

---

**Status**: Active research project. Latest experiment: Dolly-15k dialog training (PPL 15.6, Acc 46.6%)
