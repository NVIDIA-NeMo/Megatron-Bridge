# Megatron Bridge Documentation

Welcome to the Megatron Bridge documentation! This guide helps you navigate our comprehensive documentation to find exactly what you need for training, converting, and working with large language models and vision language models.

## 🚀 Quick Start Paths

### I want to

**🏃‍♂️ Get started with model conversion**
→ Start with [Bridge Guide](bridge-guide.md) for Hugging Face ↔ Megatron conversion

**⚡ Understand parallelisms and performance**
→ Jump to [Parallelisms Guide](parallelisms.md) and [Performance Guide](performance-guide.md)

**🚀 Start training a model**
→ See [Training Documentation](training/README.md) for comprehensive training guides

**📚 Find model documentation**
→ Browse [Supported Models](models/llm/index.md) for LLMs or [Vision Language Models](models/vlm/index.md) for VLMs

**🔧 Migrate from NeMo 2 or Megatron-LM**
→ Check [NeMo 2 Migration Guide](nemo2-migration-guide.md) or [Megatron-LM Migration Guide](megatron-lm-to-megatron-bridge.md)

**📊 Use training recipes**
→ Read [Recipe Usage](recipe-usage.md) for pre-configured training recipes

**🔌 Add support for a new model**
→ Refer to [Adding New Models](adding-new-models.md)

**📋 Check version information**
→ See [Releases Documentation](releases/README.md) for versions, changelog, and known issues

---

## 👥 Documentation by Role

### For ML Engineers & Researchers

- **Start here:** [Bridge Guide](bridge-guide.md) → [Training Documentation](training/README.md)
- **Deep dive:** [Performance Guide](performance-guide.md) → [Training Optimization Guides](training/README.md#optimization-and-performance)
- **Model support:** [Supported Models](models/llm/index.md) → [Adding New Models](adding-new-models.md)

### For Training Engineers

- **Start here:** [Training Documentation](training/README.md) → [Configuration Container Overview](training/config-container-overview.md)
- **Performance:** [Performance Guide](performance-guide.md) → [Performance Summary](performance-summary.md)
- **Parallelisms:** [Parallelisms Guide](parallelisms.md) → [Training Optimization](training/README.md#optimization-and-performance)

### For Model Developers

- **Start here:** [Bridge Guide](bridge-guide.md) → [Bridge Tech Details](bridge-tech-details.md)
- **Model support:** [Adding New Models](adding-new-models.md) → [Model Documentation](models/llm/index.md)
- **Integration:** [Bridge RL Integration](bridge-rl-integration.md)

### For DevOps & Platform Teams

- **Start here:** [Releases Documentation](releases/README.md) → [Software Versions](releases/software-versions.md)
- **Troubleshooting:** [Known Issues](releases/known-issues.md)
- **API Reference:** [API Documentation](apidocs/index.rst)

---

## 📚 Complete Documentation Index

### Getting Started

| Document | Purpose | When to Read |
|----------|---------|--------------|
| **[Bridge Guide](bridge-guide.md)** | Hugging Face ↔ Megatron conversion guide | First time converting models |
| **[Bridge Tech Details](bridge-tech-details.md)** | Technical details of the bridge system | Understanding bridge internals |
| **[Parallelisms Guide](parallelisms.md)** | Data and model parallelism strategies | Setting up distributed training |
| **[Performance Summary](performance-summary.md)** | Quick performance reference | Quick performance lookup |
| **[Performance Guide](performance-guide.md)** | Comprehensive performance optimization | Optimizing training performance |

### Model Support

| Document | Purpose | When to Read |
|----------|---------|--------------|
| **[Large Language Models](models/llm/index.md)** | LLM model documentation | Working with LLM models |
| **[Vision Language Models](models/vlm/index.md)** | VLM model documentation | Working with VLM models |
| **[Adding New Models](adding-new-models.md)** | Guide for adding model support | Extending model support |

### Training and Customization

| Document | Purpose | When to Read |
|----------|---------|--------------|
| **[Training Documentation](training/README.md)** | Comprehensive training guides | Setting up and customizing training |
| **[Configuration Container Overview](training/config-container-overview.md)** | Central training configuration | Understanding training configuration |
| **[Entry Points](training/entry-points.md)** | Training entry points and execution | Understanding training flow |
| **[Training Loop Settings](training/training-loop-settings.md)** | Training loop parameters | Configuring training parameters |
| **[Optimizer & Scheduler](training/optimizer-scheduler.md)** | Optimization configuration | Setting up optimizers |
| **[Mixed Precision](training/mixed-precision.md)** | Mixed precision training | Reducing memory usage |
| **[PEFT](training/peft.md)** | Parameter-efficient fine-tuning | Fine-tuning with limited resources |
| **[Checkpointing](training/checkpointing.md)** | Checkpoint management | Saving and resuming training |
| **[Logging](training/logging.md)** | Logging and monitoring | Monitoring training progress |
| **[Profiling](training/profiling.md)** | Performance profiling | Identifying bottlenecks |

### Recipes and Workflows

| Document | Purpose | When to Read |
|----------|---------|--------------|
| **[Recipe Usage](recipe-usage.md)** | Using pre-configured training recipes | Quick training setup |
| **[Bridge RL Integration](bridge-rl-integration.md)** | Reinforcement learning integration | RL training workflows |

### Migration Guides

| Document | Purpose | When to Read |
|----------|---------|--------------|
| **[NeMo 2 Migration Guide](nemo2-migration-guide.md)** | Migrating from NeMo 2 | Upgrading from NeMo 2 |
| **[Megatron-LM Migration Guide](megatron-lm-to-megatron-bridge.md)** | Migrating from Megatron-LM | Upgrading from Megatron-LM |

### Reference

| Document | Purpose | When to Read |
|----------|---------|--------------|
| **[API Documentation](apidocs/index.rst)** | Complete API reference | Building integrations |
| **[Releases Documentation](releases/README.md)** | Version history and known issues | Checking versions, troubleshooting |
| **[Documentation Guide](documentation.md)** | Contributing to documentation | Contributing docs |

---

## 🗺️ Common Reading Paths

### 🆕 First-Time Users

1. [Bridge Guide](bridge-guide.md) *(10 min - understand conversion)*
2. [Parallelisms Guide](parallelisms.md) *(15 min - understand distributed training)*
3. [Training Documentation](training/README.md) *(choose your training path)*
4. [Recipe Usage](recipe-usage.md) *(5 min - use pre-configured recipes)*

### 🔧 Setting Up Training

1. [Training Documentation](training/README.md) *(overview of training system)*
2. [Configuration Container Overview](training/config-container-overview.md) *(understand configuration)*
3. [Entry Points](training/entry-points.md) *(how training starts)*
4. [Training Loop Settings](training/training-loop-settings.md) *(configure parameters)*
5. [Logging](training/logging.md) *(set up monitoring)*

### ⚡ Performance Optimization

1. [Performance Guide](performance-guide.md) *(comprehensive optimization strategies)*
2. [Performance Summary](performance-summary.md) *(quick reference)*
3. [Mixed Precision](training/mixed-precision.md) *(reduce memory usage)*
4. [Communication Overlap](training/communication-overlap.md) *(optimize distributed training)*
5. [Activation Recomputation](training/activation-recomputation.md) *(reduce memory footprint)*
6. [Profiling](training/profiling.md) *(identify bottlenecks)*

### 🔄 Model Conversion Workflow

1. [Bridge Guide](bridge-guide.md) *(conversion basics)*
2. [Bridge Tech Details](bridge-tech-details.md) *(technical details)*
3. [Supported Models](models/llm/index.md) or [Vision Language Models](models/vlm/index.md) *(model-specific guides)*
4. [Adding New Models](adding-new-models.md) *(extend support)*

### 🔧 Customization and Extension

1. [Training Documentation](training/README.md) *(training customization)*
2. [PEFT](training/peft.md) *(parameter-efficient fine-tuning)*
3. [Distillation](training/distillation.md) *(knowledge distillation)*
4. [Adding New Models](adding-new-models.md) *(add model support)*
5. [Bridge RL Integration](bridge-rl-integration.md) *(RL workflows)*

### 📦 Migration Paths

1. [NeMo 2 Migration Guide](nemo2-migration-guide.md) *(from NeMo 2)*
2. [Megatron-LM Migration Guide](megatron-lm-to-megatron-bridge.md) *(from Megatron-LM)*
3. [Training Documentation](training/README.md) *(new training system)*

---

## 📁 Directory Structure

### Main Documentation

- **Guides** - Core guides for parallelisms, performance, recipes, and migration
- **Bridge Documentation** - Hugging Face ↔ Megatron conversion guides
- **Model Documentation** - Supported model families and architectures

### Subdirectories

#### [models/](models/README.md)

- **[llm/](models/llm/README.md)** - Large Language Model documentation
  - Individual model guides (Qwen, LLaMA, Mistral, etc.)
  - Conversion examples and training recipes
- **[vlm/](models/vlm/README.md)** - Vision Language Model documentation
  - VLM model guides (Qwen VL, Gemma VL, etc.)
  - Multimodal model support

#### [training/](training/README.md)

- **Configuration** - ConfigContainer, entry points, training loop settings
- **Optimization** - Optimizer, scheduler, mixed precision, communication overlap
- **Performance** - Attention optimizations, activation recomputation, CPU offloading
- **Monitoring** - Logging, profiling, checkpointing, resiliency
- **Advanced** - PEFT, packed sequences, distillation

#### [releases/](releases/README.md)

- **Software Versions** - Current versions and dependencies
- **Changelog** - Release history and changes
- **Known Issues** - Bugs, limitations, and workarounds

---

## 🔗 How Documents Connect

```mermaid
graph TD
    A[README.md<br/>Start Here] --> B[Bridge Guide<br/>Model Conversion]
    A --> C[Training Docs<br/>Training Setup]
    A --> D[Models<br/>Model Support]
    
    B --> E[Bridge Tech Details<br/>Technical Deep Dive]
    B --> F[Supported Models<br/>Model-Specific Guides]
    
    C --> G[Config Container<br/>Configuration]
    C --> H[Performance Guide<br/>Optimization]
    C --> I[Parallelisms<br/>Distributed Training]
    
    G --> J[Training Loop<br/>Training Parameters]
    G --> K[Optimizer & Scheduler<br/>Optimization Setup]
    
    H --> L[Mixed Precision<br/>Memory Efficiency]
    H --> M[Communication Overlap<br/>Performance]
    
    I --> N[Data Parallelism<br/>DDP]
    I --> O[Model Parallelism<br/>TP/PP/VPP]
    
    D --> P[LLM Models<br/>Language Models]
    D --> Q[VLM Models<br/>Vision Language Models]
    
    style A fill:#e1f5fe
    style B fill:#f3e5f5
    style C fill:#e8f5e8
    style D fill:#fff3e0
    style H fill:#fce4ec
    style I fill:#e0f2f1
```

---

## 🤝 Getting Help

- **GitHub Issues:** [Report bugs or request features](https://github.com/NVIDIA-NeMo/Megatron-Bridge/issues)
- **Documentation Issues:** Found something unclear? Let us know!
- **Community:** Join discussions and share experiences

---

## 📖 Additional Resources

- **[Examples](https://github.com/NVIDIA-NeMo/Megatron-Bridge/tree/main/examples)** - Code examples and tutorials
- **[Contributing Guide](https://github.com/NVIDIA-NeMo/Megatron-Bridge/blob/main/CONTRIBUTING.md)** - How to contribute to the project
- **[API Documentation](apidocs/index.rst)** - Complete API reference

---

**Ready to get started?** Choose your path above or dive into the [Bridge Guide](bridge-guide.md) for model conversion! 🚀
