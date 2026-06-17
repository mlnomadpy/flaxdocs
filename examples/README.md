# Flax NNX Complete Training Guides - Modular Edition ✅

**20 categorized examples plus a standalone ImageNet app, organized and runnable!**

Comprehensive, runnable Python examples for training deep learning models with Flax NNX. Each guide is organized into categories, and the core examples use shared, tested components for consistency and reusability.

## ✅ Structure Overview

The examples are organized into a modular structure:
- **20 examples** organized into 6 categories (plus a standalone `imagenet/main.py` app)
- **Shared component library** with tested models and utilities
- **27 passing tests** (23 unit + 4 integration)
- **Clean, organized directory structure** with no duplicates

## 🎯 What's New in This Refactored Version

### ✨ Modular Design
- **Shared Components**: Reusable model architectures, training utilities, and data loaders in `shared/`
- **Organized Structure**: Examples categorized into logical folders (basics, training, export, etc.)
- **Unit Tested**: All shared components have comprehensive unit tests (23+ tests)
- **Best Practices**: Follows modern Flax NNX patterns and conventions

### 🧩 Shared Components Library

The `shared/` package provides battle-tested, reusable components. Today the core
examples `basics/model_definition.py` and `training/vision_mnist.py` import from it;
other examples are self-contained but follow the same patterns:

#### Models (`shared/models.py`)
- `MLP` - Multi-layer perceptron with configurable layers
- `CNN` - Convolutional neural network for vision tasks
- `MultiHeadAttention` - Self-attention mechanism
- `TransformerBlock` - Complete transformer block
- `ResNetBlock` - Residual block with skip connections

#### Training Utilities (`shared/training_utils.py`)
- `create_train_step()` - JIT-compiled training step
- `create_eval_step()` - JIT-compiled evaluation step
- `create_optimizer()` - Optimizer factory (Adam, SGD, AdamW)
- `compute_mse_loss()` - Mean squared error
- `compute_cross_entropy_loss()` - Cross-entropy for classification
- `compute_accuracy()` - Classification accuracy
- `create_warmup_cosine_schedule()` - Learning rate scheduling
- `clip_gradients()` - Gradient clipping utilities

## 📁 Complete Directory Structure

```
examples/
├── shared/                          # ✅ Shared, tested components
│   ├── __init__.py
│   ├── models.py                    # 5 reusable architectures
│   └── training_utils.py            # Complete training infrastructure
│
├── tests/                           # ✅ 27 tests (100% passing)
│   ├── unit/                        # 23 unit tests
│   │   ├── test_models.py          # Model architecture tests
│   │   └── test_training_utils.py  # Training utility tests
│   └── integration/                 # 4 integration tests
│       └── test_model_definition.py
│
├── basics/                          # ✅ 4 examples
│   ├── model_definition.py          # Uses shared components
│   ├── save_load_model.py
│   ├── data_loading_tfds.py
│   └── data_loading_grain.py
│
├── training/                        # ✅ 2 examples
│   ├── vision_mnist.py              # Uses shared components
│   └── language_model.py
│
├── export/                          # ✅ 1 example
│   └── model_formats.py
│
├── integrations/                    # ✅ 3 examples
│   ├── huggingface.py
│   ├── resnet_streaming.py
│   └── wandb.py
│
├── advanced/                        # ✅ 6 examples
│   ├── bert_fineweb.py
│   ├── gpt_training.py
│   ├── simclr_contrastive.py
│   ├── maml_metalearning.py
│   ├── knowledge_distillation.py
│   └── dqn_reinforcement_learning.py
│
├── distributed/                     # ✅ 4 examples
│   ├── data_parallel_pmap.py
│   ├── sharding_spmd.py
│   ├── pipeline_parallel.py
│   └── fsdp_sharding.py
│
├── imagenet/                        # ✅ Standalone app
│   └── main.py
│
├── index.py                         # 📋 Complete example index
└── requirements.txt                 # Updated with pytest
```

**Total: 20 categorized examples + 1 standalone ImageNet app**

## 🚀 Quick Start

### View All Examples

```bash
# See complete index of all examples
python examples/index.py
```

### Installation

```bash
# Core dependencies
pip install jax jaxlib flax optax orbax-checkpoint

# For data loading
pip install tensorflow-datasets datasets

# For testing
pip install pytest

# Or install everything
pip install -r requirements.txt
```

### Run Examples

```bash
# Basics - Model definition using shared components
python examples/basics/model_definition.py

# Training - Full MNIST CNN training
python examples/training/vision_mnist.py

# Advanced - GPT training
python examples/advanced/gpt_training.py

# See all examples with descriptions
python examples/index.py
```

### Run Tests

```bash
# Run all tests
pytest

# Run only unit tests
pytest tests/unit/ -v

# Run only integration tests
pytest tests/integration/ -v

# Run with coverage
pytest --cov=shared --cov-report=html
```

## 📚 Example Categories

### Basics (`basics/`) - 4 Examples ✅
Learn fundamental concepts with shared, tested components:
- **model_definition.py** - Define models (MLP, CNN) using shared components ✅ 
- **save_load_model.py** - Checkpoint management with Orbax ✅
- **data_loading_tfds.py** - TensorFlow Datasets integration ✅
- **data_loading_grain.py** - Pure Python data loading ✅

### Training (`training/`) - 2 Examples ✅
End-to-end training examples using shared utilities:
- **vision_mnist.py** - Train CNN on MNIST using shared components ✅
- **language_model.py** - Transformer language model training ✅

### Export (`export/`) - 1 Example ✅
Export models to various formats:
- **model_formats.py** - SafeTensors and ONNX export ✅

### Integrations (`integrations/`) - 3 Examples ✅
Integrate with the ML ecosystem:
- **huggingface.py** - HuggingFace Hub integration ✅
- **resnet_streaming.py** - ResNet with streaming datasets ✅
- **wandb.py** - Weights & Biases experiment tracking ✅

### Advanced (`advanced/`) - 6 Examples ✅
Cutting-edge techniques:
- **bert_fineweb.py** - BERT training on FineWeb ✅
- **gpt_training.py** - GPT from scratch ✅
- **simclr_contrastive.py** - Contrastive learning (SimCLR) ✅
- **maml_metalearning.py** - Meta-learning (MAML) ✅
- **knowledge_distillation.py** - Knowledge distillation ✅
- **dqn_reinforcement_learning.py** - Deep Q-Network reinforcement learning ✅

### Distributed (`distributed/`) - 4 Examples ✅
Scale training across devices:
- **data_parallel_pmap.py** - Data parallelism with pmap ✅
- **sharding_spmd.py** - SPMD sharding ✅
- **pipeline_parallel.py** - Pipeline parallelism ✅
- **fsdp_sharding.py** - FSDP sharding ✅

### ImageNet (`imagenet/`) - Standalone App ✅
Full-scale training application (not part of the categorized example set):
- **main.py** - Standalone ResNet ImageNet training app ✅

## 💡 Benefits of Modular Design

### For Learners
- ✅ **Consistent Patterns**: Core examples share the same tested components, and all follow the same conventions
- ✅ **Focus on Concepts**: Less boilerplate, more learning
- ✅ **Tested Code**: Confidence that examples work correctly
- ✅ **Easy Navigation**: Organized by topic and difficulty

### For Contributors
- ✅ **Reusable Components**: Don't repeat yourself
- ✅ **Test-Driven**: Add tests first, then implementation
- ✅ **Clear Structure**: Know where new examples belong
- ✅ **Quality Assurance**: CI runs all tests automatically

### For Researchers
- ✅ **Rapid Prototyping**: Use proven components for experiments
- ✅ **Reproducible**: Tested utilities ensure consistency
- ✅ **Extensible**: Easy to add custom components
- ✅ **Production-Ready**: Battle-tested patterns

## 🧪 Test-Driven Development

All shared components are developed using TDD:

1. **Write Tests First**: Define expected behavior
2. **Implement**: Create minimal code to pass tests
3. **Refactor**: Improve while keeping tests green
4. **Integrate**: Use in examples with confidence

### Test Coverage

| Component | Tests | Status |
|-----------|-------|--------|
| `shared.models.MLP` | 3 | ✅ Passing |
| `shared.models.CNN` | 3 | ✅ Passing |
| `shared.models.MultiHeadAttention` | 2 | ✅ Passing |
| `shared.models.TransformerBlock` | 2 | ✅ Passing |
| `shared.models.ResNetBlock` | 4 | ✅ Passing |
| `shared.training_utils` (train/eval) | 4 | ✅ Passing |
| `shared.training_utils` (loss/metrics) | 4 | ✅ Passing |
| `shared.training_utils` (schedules) | 1 | ✅ Passing |
| **Total Unit Tests** | **23** | **✅ All Passing** |
| **Integration Tests** | **4** | **✅ All Passing** |

## 🎓 Learning Path

### Beginner (Start Here!)
1. **basics/model_definition.py** - Learn to create models with shared components ✅
2. **basics/save_load_model.py** - Checkpoint management ✅
3. **training/vision_mnist.py** - First complete training loop ✅

### Intermediate
4. **training/language_model.py** - Work with text and transformers ✅
5. **integrations/wandb.py** - Track experiments ✅
6. **export/model_formats.py** - Deploy models ✅

### Advanced
7. **advanced/bert_fineweb.py** - Large-scale pre-training ✅
8. **advanced/gpt_training.py** - Autoregressive models ✅
9. **distributed/data_parallel_pmap.py** - Multi-GPU training ✅

## 🔥 Key Features

### Shared Components
```python
# Import tested, reusable components
from shared.models import CNN, MLP, TransformerBlock
from shared.training_utils import (
    create_train_step,
    create_eval_step,
    create_optimizer
)

# Use in your code
model = CNN(num_classes=10, rngs=rngs)
optimizer = create_optimizer(model, lr=0.001)
train_step = create_train_step('cross_entropy')
```

### Type-Safe & Documented
```python
def create_optimizer(
    model: nnx.Module,
    learning_rate: float,
    optimizer_name: str = 'adam',
    **kwargs
) -> nnx.Optimizer:
    """Create an optimizer for the model.
    
    Args:
        model: The model to optimize
        learning_rate: Learning rate or schedule
        optimizer_name: 'adam', 'sgd', or 'adamw'
        **kwargs: Additional optimizer arguments
        
    Returns:
        Optimizer instance
    """
```

### JIT-Compiled for Performance
```python
@nnx.jit
def train_step(model, optimizer, batch):
    # Automatically JIT-compiled for 10-100x speedup
    def loss_fn(model):
        logits = model(batch['x'], train=True)
        return compute_cross_entropy_loss(logits, batch['y'])
    
    loss, grads = nnx.value_and_grad(loss_fn)(model)
    optimizer.update(model, grads)
    return loss
```

## 🛠 Development Workflow

### Adding New Shared Components

1. **Write Tests** (`tests/unit/`)
```python
def test_new_component():
    """Test new component works correctly."""
    component = NewComponent(params)
    output = component(input)
    assert output.shape == expected_shape
```

2. **Implement** (`shared/`)
```python
class NewComponent(nnx.Module):
    """New reusable component."""
    def __init__(self, ...):
        ...
    def __call__(self, x):
        ...
```

3. **Test & Iterate**
```bash
pytest tests/unit/test_new_component.py -v
```

4. **Use in Examples**
```python
from shared.components import NewComponent
```

### Contributing Examples

1. Choose appropriate category folder
2. Import from `shared/` where possible
3. Add integration tests in `tests/integration/`
4. Update this README with example description
5. Ensure all tests pass: `pytest`

## 📊 Benchmarks

Training speeds (approximate, on V100 GPU):

| Model | Params | Dataset | Speed | Example |
|-------|--------|---------|-------|---------|
| CNN | 422K | MNIST | ~1000 samples/sec | training/vision_mnist.py |
| ResNet-18 | 11M | CIFAR-10 | ~500 samples/sec | _(Coming)_ |
| BERT-Small | 30M | FineWeb | ~100 samples/sec | _(Coming)_ |
| GPT-Small | 50M | FineWeb | ~80 samples/sec | _(Coming)_ |

## 🐛 Troubleshooting

### Import Errors
```python
# Always add parent to path in examples
import sys
from pathlib import Path
sys.path.insert(0, str(Path(__file__).parent.parent))

from shared.models import CNN
```

### Test Failures
```bash
# Run with verbose output
pytest -v --tb=short

# Run specific test
pytest tests/unit/test_models.py::TestCNN::test_cnn_forward_shape -v
```

### Out of Memory
- Reduce batch size
- Use mixed precision (coming soon)
- Enable gradient checkpointing (coming soon)

## 📖 Additional Resources

- [Flax Documentation](https://flax.readthedocs.io/)
- [JAX Documentation](https://jax.readthedocs.io/)
- [Flax Examples](https://github.com/google/flax/tree/main/examples)

## 🤝 Contributing

We welcome contributions! Please:
1. Follow TDD approach (tests first)
2. Use shared components where possible
3. Add integration tests for new examples
4. Update documentation
5. Ensure `pytest` passes

## 📝 License

MIT License - see LICENSE file for details

## ✨ Acknowledgments

These guides focus on **Flax NNX**, the new API that combines the best of Flax Linen and Flax NNX. All examples use the latest patterns and best practices as of 2025.

The modular refactoring was done using Test-Driven Development to ensure code quality and maintainability.

---

**Happy Training! 🚀**

For questions or issues, please check:
- Individual example files for detailed documentation
- `tests/` directory for usage examples
- Shared component docstrings for API details
