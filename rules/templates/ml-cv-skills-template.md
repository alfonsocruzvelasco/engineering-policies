# ML/CV Engineer Skills Package

Complete skill set for production ML/CV engineering. These skills work together with the ML/CV Engineer MCP to enforce best practices and provide instant access to production-grade patterns.

**Understanding Claude Skills:** For a comprehensive overview of what Claude Skills are, their use cases, limitations, and architectural implications, see: [`claude-skills-definition-use-cases-and-limitations.md`](../references/claude-skills-definition-use-cases-and-limitations.md)

## 📦 Included Skills

### 1. **pytorch-cv-patterns** (7.4 KB)
Architecture patterns, loss functions, and dataloader configurations for PyTorch CV.

**Use when:**
- Choosing backbone architectures (ResNet, EfficientNet, MobileNet)
- Implementing custom loss functions (focal loss, dice loss)
- Configuring dataloaders for optimal performance
- Handling class imbalance
- Implementing common CV training patterns

**Key contents:**
- Backbone selection matrix by optimization priority
- Focal loss, weighted cross-entropy, dice loss implementations
- Optimal DataLoader configurations
- Variable-sized image handling
- Weighted sampling for imbalance
- Memory optimization (gradient checkpointing, accumulation)
- ONNX export guide (in references/)

### 2. **cv-data-pipeline** (5.9 KB)
Dataset splitting, augmentation, and preprocessing best practices.

**Use when:**
- Preventing data leakage in train/val/test splits
- Choosing domain-appropriate augmentation strategies
- Handling class imbalance in datasets
- Preprocessing for different image types (medical, satellite, industrial)
- Creating efficient PyTorch datasets

**Key contents:**
- Data splitting decision tree (IID vs temporal vs grouped)
- Leakage prevention and validation
- Domain-specific augmentation (medical, satellite, industrial)
- Augmentation validation visualizations
- Safe dataset implementations
- Class imbalance strategies

### 3. **model-training-debugging** (5.5 KB)
Systematic debugging procedures for training failures.

**Use when:**
- Encountering NaN or Inf losses
- Models not converging (loss stuck)
- Overfitting or underfitting issues
- Gradient problems (vanishing/exploding)
- Poor validation performance despite good training metrics
- Unstable training dynamics

**Key contents:**
- NaN loss diagnostic procedure (step-by-step)
- Convergence diagnostic (can model learn?)
- Overfitting detection and fixes
- Gradient checking utilities
- Sanity checks (overfit single batch)
- Training monitoring dashboard
- Auto-fix scripts

### 4. **mlops-experiment-tracking** (5.8 KB)
Experiment tracking, reproducibility, and versioning.

**Use when:**
- Setting up ML project structure
- Ensuring reproducibility (seeds, versions, configs)
- Managing model checkpoints
- Organizing experiment results
- Comparing experiments
- Preparing for deployment with proper versioning

**Key contents:**
- Standard directory structure
- Complete experiment metadata tracking
- Random seed management
- Metrics logging system
- Checkpoint manager
- YAML config system
- Experiment comparison tools
- Model versioning for deployment

### 5. **model-deployment** (6.4 KB)
Model deployment patterns for production CV systems.

**Use when:**
- Exporting to ONNX format
- Applying quantization (int8, fp16)
- Optimizing inference performance
- Benchmarking latency
- Deploying to edge devices (TensorRT, ONNX Runtime)
- Building production inference pipelines

**Key contents:**
- Deployment decision tree (cloud vs edge vs mobile)
- ONNX export with validation
- Dynamic and static quantization
- Production inference pipeline with error handling
- Comprehensive latency benchmarking
- TensorRT optimization
- Batch inference patterns

---

## 🚀 Installation

**Official skill structure reference:** See [The Complete Guide to Building Skills for Claude](../references/the-complete-guide-to-building-skill-for-claude.pdf) and `ai-workflow-policy.md` "Claude Code Skills Management" for full governance.

### Method 1: Upload Skills to Claude.ai

1. Each skill is a **folder** containing `SKILL.md` (required) + optional `scripts/`, `references/`, `assets/`
2. Zip each skill folder:
   - `pytorch-cv-patterns/` → `pytorch-cv-patterns.zip`
   - `cv-data-pipeline/` → `cv-data-pipeline.zip`
   - `model-training-debugging/` → `model-training-debugging.zip`
   - `mlops-experiment-tracking/` → `mlops-experiment-tracking.zip`
   - `model-deployment/` → `model-deployment.zip`
3. Go to Claude.ai → Settings → Capabilities → Skills → Upload each zip

### Method 2: Use with Claude Code

Place each skill folder in your Claude Code skills directory:
```bash
# Copy each skill folder directly (not zipped)
cp -r pytorch-cv-patterns/ ~/.claude/skills/
cp -r cv-data-pipeline/ ~/.claude/skills/
```

### Method 3: Use via API

Skills can be managed programmatically via the `/v1/skills` endpoint and added to Messages API requests via the `container.skills` parameter. Requires Code Execution Tool beta.

---

## ⚙️ API Temperature Configuration

**When using these skills with Ollama's Anthropic API compatibility:**

### Recommended Settings

```python
import anthropic

client = anthropic.Anthropic(
    base_url='http://localhost:11434',
    api_key='ollama',
)

# Temperature for ML/CV engineering tasks (industry best practices)
TASK_TEMPERATURES = {
    "pytorch_code": 0.2,          # Architecture definitions, training loops
    "data_pipeline": 0.2,         # Dataset classes, augmentation code
    "debugging": 0.2,             # Bug analysis, error fixes
    "deployment": 0.2,            # ONNX export, optimization scripts
    "experiment_tracking": 0.2,   # Logging, metrics, config management
    "architecture_exploration": 0.3,  # Comparing ResNet vs EfficientNet (still analytical)
}

# Example: Generating PyTorch CV code
response = client.messages.create(
    model='qwen3-coder',
    max_tokens=4096,
    temperature=0.2,  # Deterministic for production code
    messages=[
        {
            'role': 'user',
            'content': 'Generate a PyTorch dataset class for defect detection...'
        }
    ]
)
```

### Why Temperature 0.2 for ML/CV?

Per **Table 2-3** industry standards:
- **Code generation**: 0.2-0.3 (deterministic, reliable, adheres to conventions)
- **Bug fixing**: 0.2 or less (accurate solutions)
- **Data analysis**: 0.2 or less (precise outputs)

ML/CV engineering is **99% analytical**:
- Writing training loops → deterministic code
- Debugging OOM errors → precise diagnosis
- Implementing loss functions → correct math
- Optimizing inference → measured performance

**When to increase temperature:**
- **Architecture brainstorming** (0.7-0.8): "What are 10 novel ways to handle class imbalance?"
- **Never** for production code generation

### Integration with Skills

These skills assume **temperature=0.2** throughout:

```python
# When skill generates code
client.messages.create(
    model='qwen3-coder',
    temperature=0.2,  # Matches skill content (tested patterns)
    system="You are using the pytorch-cv-patterns skill...",
    messages=[...]
)
```

**Result:** Code generated matches tested patterns in skills (no creative hallucinations).

### Applicability Note

**Temperature configuration applicability:**
- ✅ **85% of this document works universally** (skill patterns, decision trees, debugging procedures)
- ✅ **API examples work with**: Ollama, Anthropic API, OpenAI API (just change client setup)
- ✅ **Temperature values (0.2) apply everywhere** (industry standard from Table 2-3)

**Using these skills without API access (Claude.ai web UI)?**
- ❌ Cannot programmatically set temperature
- ✅ **But skills still provide:**
  - Architecture patterns (ResNet vs EfficientNet selection)
  - Debugging procedures (NaN loss diagnostics)
  - Deployment guides (ONNX export)
  - Data pipeline best practices
- ✅ **Prompt-based control:** Reference that these skills assume "deterministic mode" (temperature=0.2)

**Key insight:** Skills contain verified patterns and code templates. Temperature configuration ensures those patterns are generated accurately when using APIs. In web UIs, you reference the skills and request "production-grade, tested implementations" to achieve similar results.

**When you need APIs:** All temperature configs are ready to copy-paste. Just change the endpoint (Ollama, Anthropic, OpenAI, etc.).

---

## Integration with Spec-Driven Development

**When to use skills vs specs:**

| Scenario | Use | Example |
|----------|-----|---------|
| Choosing architecture | **Skills** | "Which backbone for 500 images?" |
| Defining system requirements | **Spec Kit** | "Detection accuracy SHALL be mAP ≥ 0.75" |
| Implementing loss function | **Skills** | Provides focal loss code |
| Planning multi-component system | **Spec Kit** | Breaks into preprocessing → inference → postprocessing |
| Debugging NaN loss | **Skills** | Step-by-step diagnostic |
| Updating existing pipeline | **OpenSpec** | Explicit delta: MODIFIED training loop |

**Workflow:**
1. Spec defines WHAT (requirements, metrics)
2. Skills provide HOW (implementations, patterns)
3. Verification checks spec compliance

**Example:**

```markdown
# Spec (Spec Kit)
### Requirement: Inference Latency
SHALL process 1920×1080 in ≤ 40ms on RTX 4070

# Implementation (Skill provides)
model = torch.jit.script(model)  # TorchScript optimization
torch.backends.cudnn.benchmark = True
```

**See:** `~/policies/references/spec-protocols-guide.md` for protocol selection

---

## 📖 Usage Examples

### Example 1: Starting a New CV Project

**You say:**
```
I want to build a defect detection system for PCB boards.
Data: 500 images, 4096×4096, 1:100 defect ratio.
Priority: Max accuracy.
```

**Skills triggered:**
1. ✅ `pytorch-cv-patterns` → Recommends EfficientNet-B0 (small data)
2. ✅ `cv-data-pipeline` → Suggests focal loss for 1:100 imbalance
3. ✅ `mlops-experiment-tracking` → Sets up proper directory structure

**Claude provides:**
- Architecture choice with rationale (EfficientNet-B0, not ResNet50)
- Dataset splitting strategy (grouped by PCB ID to prevent leakage)
- Augmentation pipeline (industrial-specific, no color jitter)
- Complete experiment tracking setup

### Example 2: Debugging Training Failure

**You say:**
```
My model training produces NaN loss after 10 epochs.
Using ResNet50, Adam optimizer, lr=0.01.
```

**Skills triggered:**
1. ✅ `model-training-debugging` → Runs NaN diagnostic procedure

**Claude provides:**
- Step-by-step diagnostic (checks data → model → gradients)
- Identifies: LR too high (0.01 → 0.001)
- Auto-fix script to test solution
- Gradient clipping implementation

### Example 3: Deploying Model to Production

**You say:**
```
I need to deploy my trained model for real-time inference.
Target: <50ms latency on NVIDIA GPU.
```

**Skills triggered:**
1. ✅ `model-deployment` → Provides ONNX export + TensorRT optimization

**Claude provides:**
- Complete ONNX export with validation
- TensorRT conversion commands
- Latency benchmarking suite
- Production inference pipeline with error handling

### Example 4: Combining Multiple Skills

**You say:**
```
My validation accuracy is 20% lower than training accuracy.
Train: 95%, Val: 75%. What should I do?
```

**Skills triggered:**
1. ✅ `model-training-debugging` → Detects SEVERE overfitting
2. ✅ `cv-data-pipeline` → Suggests stronger augmentation
3. ✅ `pytorch-cv-patterns` → Provides dropout implementation

**Claude provides:**
- Overfitting diagnosis (severity assessment)
- Stronger augmentation pipeline (domain-appropriate)
- Dropout + early stopping implementations
- L2 regularization configuration

---

## 🎯 Skill Selection Guide

**Which skill will Claude use?**

| Your Request | Primary Skill | Supporting Skills |
|--------------|---------------|-------------------|
| "Choose model architecture" | pytorch-cv-patterns | - |
| "Split my dataset properly" | cv-data-pipeline | mlops-experiment-tracking |
| "Model won't converge" | model-training-debugging | pytorch-cv-patterns |
| "Setup experiment tracking" | mlops-experiment-tracking | - |
| "Deploy model to production" | model-deployment | mlops-experiment-tracking |
| "Data augmentation strategy" | cv-data-pipeline | - |
| "Loss is NaN" | model-training-debugging | pytorch-cv-patterns |
| "Compare experiments" | mlops-experiment-tracking | - |
| "Optimize inference speed" | model-deployment | pytorch-cv-patterns |

---

## 🔗 Integration with MCP

These skills are designed to work with the **ML/CV Engineer MCP** (Master Control Program):

**MCP handles:**
- Socratic questioning
- Verification protocols
- Refusal of vague prompts
- Production standards enforcement

**Skills provide:**
- Concrete implementations
- Domain-specific patterns
- Decision trees
- Code templates

**Together they ensure:**
- ✅ No hallucinations (grounded in verified patterns)
- ✅ Production-grade code (tested implementations)
- ✅ Best practices enforced (automatic skill triggering)
- ✅ Portfolio-ready work (Israeli robotics company standard)

---

## 📊 Coverage Map

```
ML/CV Project Lifecycle:
│
├─ Setup & Planning
│  └─ mlops-experiment-tracking ✅
│
├─ Data Pipeline
│  └─ cv-data-pipeline ✅
│
├─ Model Selection
│  └─ pytorch-cv-patterns ✅
│
├─ Training
│  ├─ pytorch-cv-patterns ✅
│  └─ mlops-experiment-tracking ✅
│
├─ Debugging
│  └─ model-training-debugging ✅
│
├─ Evaluation
│  └─ mlops-experiment-tracking ✅
│
└─ Deployment
   └─ model-deployment ✅
```

**100% coverage of production ML/CV workflow.**

---

## 🛠️ Maintenance & Updates

### When to Update Skills

**Update pytorch-cv-patterns when:**
- New architecture becomes standard (e.g., ConvNeXt → Swin Transformer)
- PyTorch API changes
- Better loss functions discovered

**Update cv-data-pipeline when:**
- New augmentation libraries (albumentations updates)
- Better splitting strategies
- Domain-specific preprocessing needs

**Update model-training-debugging when:**
- New common failure modes discovered
- Better diagnostic procedures developed

**Update mlops-experiment-tracking when:**
- New versioning requirements
- Better tracking tools emerge

**Update model-deployment when:**
- New deployment targets (e.g., Apple Silicon)
- Better optimization techniques
- Framework updates (ONNX, TensorRT)

### Version Control

Each skill includes version info in frontmatter:
```yaml
# Future versions will include:
version: 1.0.0
last_updated: 2026-03-11
```

---

## ⚠️ Known Limitations

1. **PyTorch-specific**: All implementations use PyTorch, not TensorFlow/JAX
2. **Computer Vision focus**: Not optimized for NLP, RL, or other domains
3. **Linux/Fedora bias**: Paths and commands assume Fedora Workstation 41
4. **ImageNet preprocessing**: Defaults assume ImageNet-pretrained models
5. **English only**: All documentation and error messages in English

---

## 📚 Additional Resources

**Referenced in skills:**
- `pytorch-cv-patterns/references/DEPLOYMENT.md` - Complete ONNX deployment guide
- Future: More reference files as skills grow

**Recommended external docs:**
- PyTorch documentation: https://pytorch.org/docs/
- Albumentations docs: https://albumentations.ai/
- ONNX Runtime docs: https://onnxruntime.ai/

---

## 🤝 Contributing

These skills are designed for **your personal use**. Customize them:

1. Add your company-specific patterns
2. Include project-specific architectures
3. Add your preferred tools (W&B, MLflow, etc.)
4. Extend with new domains (3D vision, video, etc.)

**To modify:**
1. Edit `SKILL.md` in the skill folder directly
2. If uploading to Claude.ai: re-zip the folder and upload
3. If using Claude Code: changes take effect on next session start

---

## 🎓 Learning Path

**If you're new to production ML/CV:**

1. Start with **mlops-experiment-tracking** to set up proper structure
2. Use **cv-data-pipeline** to avoid data leakage from day 1
3. Rely on **pytorch-cv-patterns** for proven architectures
4. Keep **model-training-debugging** handy for inevitable issues
5. Use **model-deployment** when ready to ship

**If you're experienced:**

- These skills serve as quick reference and prevent mistakes
- They enforce best practices automatically
- They save time by providing tested implementations
- They ensure nothing is forgotten (checklists at end of each skill)

---

## 📝 License

These skills are for your personal use with Claude. Modify as needed for your workflow.

---

**Created:** 2026-01-22
**For:** Alfonso (ML/CV Engineer)
**Context:** Production robotics/CV work, portfolio preparation for Israeli companies
**Optimization:** Dev velocity → Max accuracy → Low latency → Interpretability
