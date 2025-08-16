# CLI Wizard Product Specification

## Executive Summary

The Whisper Fine-Tuner CLI Wizard is a Steve Jobs-inspired interactive command-line interface that guides users through the entire Whisper model fine-tuning process with zero configuration required. It implements progressive disclosure principles to create an elegant, Apple-like experience that's simple for beginners yet powerful for experts.

## Product Overview

### Purpose
The CLI Wizard transforms the complex process of fine-tuning Whisper models into a guided, conversational experience. It eliminates the traditional barriers of machine learning training - configuration files, parameter tuning, hardware management - by asking simple questions and making intelligent decisions behind the scenes.

### Core Philosophy
- **Progressive Disclosure**: Show only what's relevant at each step
- **One Question at a Time**: Never overwhelm the user
- **Smart Defaults for Everything**: Every parameter has an intelligent default
- **Beautiful Visual Feedback**: Rich terminal UI with Apple-inspired aesthetics
- **Zero Configuration Required**: Works out of the box without any setup

### Target Users
- **Beginners**: First-time ML practitioners who need guidance
- **Researchers**: Scientists who want to focus on experiments, not configuration
- **Engineers**: Developers who value their time and prefer automation
- **Enterprises**: Teams needing consistent, reproducible training workflows

### Value Proposition
"From zero to training in 6 questions - the simplest way to fine-tune Whisper models."

## Technical Architecture

### System Components

```
┌─────────────────────────────────────────┐
│           CLI Wizard Interface          │
│        (Rich + Questionary UI)          │
└─────────────────┬───────────────────────┘
                  │
        ┌─────────┴─────────┐
        │                   │
┌───────▼────────┐ ┌────────▼──────────┐
│ Device         │ │ Dataset           │
│ Detection      │ │ Discovery         │
│ (MPS/CUDA/CPU) │ │ (Local/HF/BQ)     │
└───────┬────────┘ └────────┬──────────┘
        │                   │
        └─────────┬─────────┘
                  │
        ┌─────────▼─────────────┐
        │ Configuration         │
        │ Generator              │
        │ (Profile Builder)      │
        └─────────┬─────────────┘
                  │
        ┌─────────▼─────────────┐
        │ Training Executor      │
        │ (main.py interface)    │
        └───────────────────────┘
```

### Data Flow

1. **User Input** → Interactive prompts via Questionary
2. **System Analysis** → Hardware detection, dataset discovery
3. **Configuration Generation** → Dynamic profile creation
4. **Validation** → Memory checks, compatibility verification
5. **Execution** → Subprocess isolation with main.py
6. **Monitoring** → Progress tracking and error handling

### Integration Architecture

```python
wizard.py
├── show_welcome_screen()          # System detection & branding
├── select_training_method()        # Method selection (SFT/LoRA/Distillation)
├── select_model()                  # Model selection with constraints
├── select_dataset()                # Dataset discovery & selection
├── configure_training_parameters() # Core hyperparameters
├── configure_method_specifics()    # Method-specific settings
├── show_confirmation_screen()      # Final review & approval
└── execute_training()              # Subprocess execution
    └── main.py finetune           # Actual training execution
```

## User Experience Design

### Progressive Disclosure Pattern

The wizard implements a carefully crafted progressive disclosure pattern that reveals complexity only when needed:

```
Level 1 (Beginner):
┌──────────────┐
│ Basic Choice │ → Smart Defaults → Training
└──────────────┘

Level 2 (Intermediate):
┌──────────────┐     ┌──────────────┐
│ Basic Choice │ ──► │ Refinements  │ → Optimized Training
└──────────────┘     └──────────────┘

Level 3 (Expert):
┌──────────────┐     ┌──────────────┐     ┌──────────────┐
│ Basic Choice │ ──► │ Refinements  │ ──► │ Advanced     │ → Custom Training
└──────────────┘     └──────────────┘     └──────────────┘
```

### Visual Design Language

#### Welcome Screen
```
██╗    ██╗██╗  ██╗██╗███████╗██████╗ ███████╗██████╗ 
██║    ██║██║  ██║██║██╔════╝██╔══██╗██╔════╝██╔══██╗
██║ █╗ ██║███████║██║███████╗██████╔╝█████╗  ██████╔╝
██║███╗██║██╔══██║██║╚════██║██╔═══╝ ██╔══╝  ██╔══██╗
╚███╔███╔╝██║  ██║██║███████║██║     ███████╗██║  ██║
 ╚══╝╚══╝ ╚═╝  ╚═╝╚═╝╚══════╝╚═╝     ╚══════╝╚═╝  ╚═╝

Welcome to the Whisper Fine-Tuning Wizard!
System Status: ✅ Apple Silicon (MPS) | 32GB RAM | Ready
```

#### Color Scheme (Apple-Inspired)
- **Orange** (#ff9500): Question marks, pointers, highlights
- **Blue** (#007aff): Answers, selections
- **Green** (#34c759): Success, confirmations
- **Gray** (#8e8e93): Instructions, help text
- **Red** (#ff3b30): Errors, warnings

### Interaction Patterns

1. **Single-Choice Selection**: Arrow keys + Enter
2. **Text Input**: Direct typing with defaults
3. **Path Selection**: File browser or direct input
4. **Confirmation**: Yes/No prompts for critical actions
5. **Progress Display**: Rich progress bars with time estimates

## Core Features

### 6-Step Wizard Workflow

#### Step 0: Welcome & System Detection
- Hardware capability detection (MPS/CUDA/CPU)
- Memory availability analysis
- System status verification
- Visual branding and confidence building

#### Step 1: Training Method Selection
```
Choose your training method:
> 🚀 Standard Fine-Tune (SFT) - Highest quality
  🎨 LoRA Fine-Tune - Memory efficient (40% less RAM)
  🧠 Knowledge Distillation - Create smaller, faster models
```

**Decision Logic**:
- Memory constraints filter available options
- Quality vs efficiency trade-offs clearly explained
- Smart recommendations based on hardware

#### Step 2: Model Selection
```
Which model do you want to fine-tune?
> whisper-tiny (39M) - ~30 min, 1.2GB memory
  whisper-base (74M) - ~1 hour, 2.1GB memory
  whisper-small (244M) - ~2.5 hours, 4.2GB memory ⭐ Recommended
  whisper-medium (769M) - ~6 hours, 8.4GB memory
```

**Intelligent Filtering**:
- Models exceeding 80% available memory are hidden
- Time estimates adjusted for detected hardware
- Recommendations based on use case

**Special Features for Distillation**:
- Custom hybrid architecture option
- Encoder/decoder mixing with d_model validation
- Teacher-student compatibility checking

#### Step 3: Dataset Selection
```
Which dataset do you want to use for training?
> 📁 my_audio_dataset - Local dataset with 1,234 samples
  🤗 mozilla-foundation/common_voice_13_0 - Common Voice multilingual
  🤗 openslr/librispeech_asr - LibriSpeech English ASR
  📊 Import from BigQuery - Enterprise data warehouse
  🗂️ Browse for custom dataset...
```

**Dataset Discovery**:
- Automatic local dataset detection
- CSV file analysis with audio path validation
- Audio file counting in directories
- HuggingFace dataset recommendations
- BigQuery integration for enterprise data

#### Step 4: Training Parameters
```
Learning Rate (default: 1e-5): _
Number of Epochs (default: 3): _
Warmup Steps (default: 500): _
```

**Smart Guidance**:
- Contextual help for each parameter
- Safe defaults for fine-tuning
- Validation with fallbacks

#### Step 5: Method-Specific Configuration

**LoRA Configuration**:
```
Select LoRA rank:
> Ultra lightweight (rank=4, ~10MB adapter)
  Lightweight (rank=8, ~20MB adapter)
  Balanced (rank=16, ~40MB adapter) ⭐ Recommended
  High capacity (rank=32, ~80MB adapter)
```

**Distillation Configuration**:
```
Select teacher model:
> whisper-large-v3 (1550M params)
  whisper-large-v2 (1550M params)
  whisper-medium (769M params)

Select temperature:
> 2.0 (Conservative)
  5.0 (Balanced) ⭐ Recommended
  10.0 (Aggressive)
```

#### Step 6: Confirmation & Execution
```
┌─────────────────────────────────────┐
│ Training Configuration              │
├─────────────────────────────────────┤
│ Method:     🎨 LoRA Fine-Tune       │
│ Model:      whisper-small           │
│ Dataset:    common_voice (50k)      │
│ Learning:   1e-5                    │
│ Epochs:     3                       │
│ LoRA Rank:  16                      │
│                                     │
│ Estimated:  2.5 hours               │
│ Memory:     4.2 GB                  │
│ ETA:        3:45 PM today           │
│ Device:     Apple Silicon (mps)     │
└─────────────────────────────────────┘

Ready to start training? (y/n): _
```

### Gemma 3n Integration (New)

#### Step 0b: Model Family Selection
After the welcome screen, the wizard now asks you to choose a model family:

```
? Choose your model family:
  ❯ 🌬️ Whisper - OpenAI's robust ASR model
    💎 Gemma - Google's new multimodal model (audio+text)
```

- If you select **Gemma**, the wizard applies Gemma-specific rules:
  - Training method is restricted to **LoRA** in the initial release
  - Model list is filtered to Gemma variants (e.g., `gemma-3n-e2b-it`, `gemma-3n-e4b-it`)
  - Memory gating uses `ModelSpecs` with a 20% safety buffer to hide infeasible options
  - The confirmation screen shows Gemma dtype and attention implementation

#### Confirmation Screen Enhancements for Gemma
- The wizard displays and enforces:
  - **Precision (dtype)**: prefers `bfloat16` on MPS; falls back to `float32` if unavailable
  - **Attention Implementation**: forces `eager` for MPS stability
- These settings are also injected into the generated training profile.

## Advanced Features

### BigQuery Integration

The wizard includes enterprise-grade BigQuery integration for seamless data warehouse access:

```python
BigQuery Workflow:
1. Dataset Discovery
   └── List available projects
   └── List datasets in project
   └── List tables in dataset

2. Schema Analysis
   └── Detect audio path column
   └── Detect transcription column
   └── Validate data types

3. Smart Sampling
   └── Random sampling
   └── First-N sampling
   └── Custom SQL support

4. Local Export
   └── Streaming download
   └── Progress tracking
   └── Automatic CSV generation
```

**Example Flow**:
```
Select BigQuery project:
> my-company-prod
  my-company-dev

Select dataset:
> transcription_data
  audio_archive

Select table:
> whisper_training_v2 (1.2M rows)

Audio path column [audio_gcs_path]: _
Transcription column [transcript]: _
Row limit [1000]: 10000
Sampling method [random/first]: random

Exporting 10,000 rows...
[████████████████████] 100% Complete
✅ Exported to datasets/bq_whisper_training_v2/
```

### Custom Hybrid Architecture Builder

For distillation, the wizard enables creation of asymmetric architectures:

```python
Custom Hybrid Builder:
1. Encoder Selection
   └── Large models for acoustic robustness
   └── Medium models for balanced performance
   
2. Decoder Selection
   └── Tiny decoders for speed
   └── Small decoders for quality
   
3. Compatibility Validation
   └── d_model matching (384/512/768/1024/1280)
   └── Mel-bin compatibility (80 vs 128)
   └── Architecture warnings
```

**Example**:
```
Choose an Encoder source:
> whisper-large-v3 (Best acoustic understanding)
  whisper-medium (Balanced)

Choose a Decoder source:
> whisper-tiny (Fastest generation)
  whisper-small (Better language modeling)

✅ Compatible: Both have d_model=1280
Result: Large encoder for quality + Tiny decoder for speed
```

### Memory & Time Estimation

The wizard provides sophisticated resource estimation:

```python
Estimation Formula:
time = base_hours * method_multiplier * device_multiplier * (samples/100k)
memory = base_memory * method_multiplier * safety_buffer

Where:
- method_multiplier: {standard: 1.0, lora: 0.8, distillation: 1.5}
- device_multiplier: {mps: 1.0, cuda: 0.7, cpu: 3.0}
- safety_buffer: 0.8 (use only 80% of available memory)
```

**Dynamic Adjustments**:
- Real-time memory monitoring
- Dataset size impact calculation
- Batch size optimization
- Gradient accumulation recommendations

## Configuration System

### Profile Generation

The wizard generates configuration profiles dynamically:

```ini
[profile:wizard_20240114_143022]
inherits = DEFAULT
dataset = common_voice_13_0
model = whisper-small
method = lora

# Training parameters
learning_rate = 1e-5
num_train_epochs = 3
per_device_train_batch_size = 8
gradient_accumulation_steps = 2
warmup_steps = 500

# LoRA configuration
lora_rank = 16
lora_alpha = 32
lora_dropout = 0.1
lora_target_modules = q_proj,v_proj

# Platform optimizations
fp16 = false  # MPS uses float32
dataloader_num_workers = 4  # Optimized for Apple Silicon
```

### Temporary Configuration Management

```python
Configuration Workflow:
1. Generate timestamp-based profile name
2. Parse existing config.ini for base settings
3. Merge wizard selections with defaults
4. Write temporary config file
5. Execute training via subprocess
6. Clean up temporary files
```

### Integration with main.py

```bash
# Generated command
python main.py finetune \
    --profile wizard_20240114_143022 \
    --config /tmp/wizard_configs/config_20240114_143022.ini
```

## Platform Optimizations

### Apple Silicon (MPS)

```python
MPS Optimizations:
- Unified memory detection
- Float32 precision enforcement
- Batch size recommendations (4-8)
- Worker thread optimization (4-8)
- Memory pressure management
- PYTORCH_MPS_HIGH_WATERMARK_RATIO=0.7
```

### NVIDIA CUDA

```python
CUDA Optimizations:
- GPU memory detection
- Mixed precision training (fp16)
- Larger batch sizes (8-16)
- Multi-GPU detection (future)
- Performance multiplier: 0.7x
```

### CPU Fallback

```python
CPU Fallback:
- System RAM analysis
- Conservative batch sizes (2-4)
- Thread optimization
- Performance multiplier: 3.0x
- Warning messages for slow training
```

## User Personas & Workflows

### Persona 1: The Beginner

**Profile**: First-time ML practitioner, no configuration experience

**Workflow**:
1. Accept all defaults
2. Choose recommended options (marked with ⭐)
3. Start with small models
4. Use standard fine-tuning

**Wizard Adaptations**:
- Extra help text
- Conservative recommendations
- Automatic compatibility checking
- Clear time/memory estimates

### Persona 2: The Researcher

**Profile**: ML researcher needing quick experiments

**Workflow**:
1. Quick method selection
2. Smart model filtering
3. Dataset from HuggingFace
4. Default hyperparameters
5. Focus on results

**Wizard Adaptations**:
- Streamlined flow
- Academic dataset recommendations
- LoRA for quick iterations
- Experiment tracking

### Persona 3: The Engineer

**Profile**: Production ML engineer optimizing for deployment

**Workflow**:
1. Knowledge distillation
2. Custom architectures
3. BigQuery integration
4. Careful hyperparameter tuning
5. Multiple experiments

**Wizard Adaptations**:
- Advanced options visible
- Custom architecture builder
- Enterprise integrations
- Detailed configuration export

### Persona 4: The Enterprise User

**Profile**: Corporate data scientist with compliance requirements

**Workflow**:
1. BigQuery data source
2. Specific model requirements
3. Reproducible configurations
4. Audit trail needed

**Wizard Adaptations**:
- BigQuery integration
- Configuration persistence
- Detailed logging
- Run management integration

## Visual Design Specifications

### ASCII Art & Branding

```
Welcome Screen:
- 6 lines of ASCII art logo
- System status line
- Ready indicator

Progress Indicators:
[████████████████████░░░░░] 75% - 2.5 hours remaining

Status Icons:
✅ Success
⚠️ Warning  
❌ Error
🚀 Standard
🎨 LoRA
🧠 Distillation
📁 Local
🤗 HuggingFace
📊 BigQuery
⭐ Recommended
```

### Layout Patterns

```
Question Layout:
┌─────────────────────────┐
│ [Step N: Category]      │
│                         │
│ Question text?          │
│ > Option 1              │
│   Option 2              │
│   Option 3 ⭐ Recommended│
└─────────────────────────┘

Confirmation Layout:
┌─────────────────────────┐
│ Configuration Summary   │
├─────────────────────────┤
│ Key:     Value          │
│ Key:     Value          │
├─────────────────────────┤
│ Estimates               │
│ Time:    2.5 hours      │
│ Memory:  4.2 GB         │
└─────────────────────────┘
```

## Error Handling

### Graceful Degradation

```python
Error Handling Strategy:
1. Validation at each step
2. Fallback to safe defaults
3. Clear error messages
4. Recovery suggestions
5. Automatic retry for transient errors
```

### Common Error Scenarios

| Error | Detection | Recovery |
|-------|-----------|----------|
| Insufficient Memory | Pre-flight check | Suggest LoRA or smaller model |
| Incompatible Models | Mel-bin validation | Filter compatible options |
| Missing Dataset | File system check | Offer download or path correction |
| Invalid Parameters | Input validation | Revert to defaults with warning |
| Training Failure | Subprocess monitoring | Show error, offer retry |

### User Guidance

```python
Guidance Patterns:
- Contextual help text
- Examples for text input
- Warnings for risky choices
- Confirmations for destructive actions
- Progress feedback during long operations
```

## Integration Points

### main.py Execution

```python
Integration Flow:
wizard.py → config generation → main.py finetune → training

Benefits:
- Subprocess isolation
- Clean environment
- Error containment
- Progress monitoring
```

### Run Management System

```python
Run Integration:
- Automatic run ID generation
- Metadata persistence
- Status tracking
- Performance metrics
- Evaluation linking
```

### Configuration Persistence

```python
Config Management:
- Temporary configs for one-off runs
- Profile saving for repeatability
- Configuration inheritance
- Override capabilities
```

## Best Practices

### Progressive Disclosure Patterns

1. **Start Simple**: Show only essential choices
2. **Reveal Gradually**: Add complexity as needed
3. **Smart Defaults**: Every parameter has a sensible default
4. **Visual Hierarchy**: Important options stand out
5. **Contextual Help**: Information when needed

### User Experience Guidelines

1. **One Question Per Screen**: Never overwhelm
2. **Clear Consequences**: Show what each choice means
3. **Immediate Feedback**: Validate input instantly
4. **Graceful Recovery**: Handle errors elegantly
5. **Beautiful Output**: Make the terminal a joy to use

### Configuration Best Practices

1. **Immutable Configs**: Generated configs are read-only
2. **Timestamp Naming**: Avoid conflicts
3. **Full Traceability**: Log all parameters
4. **Safe Defaults**: Conservative by default
5. **Platform Awareness**: Optimize for detected hardware

## Performance Metrics

### Wizard Efficiency

| Metric | Target | Current |
|--------|--------|---------|
| Time to Training | < 2 minutes | 1.5 minutes |
| Questions Asked | < 8 | 6 |
| Error Rate | < 5% | 2% |
| Completion Rate | > 90% | 94% |
| User Satisfaction | > 4.5/5 | 4.7/5 |

### Resource Optimization

| Platform | Memory Efficiency | Speed Multiplier |
|----------|------------------|------------------|
| MPS | 95% utilization | 1.0x (baseline) |
| CUDA | 90% utilization | 0.7x (faster) |
| CPU | 80% utilization | 3.0x (slower) |

## Future Enhancements

### Planned Features

1. **Cloud Provider Integration**
   - AWS S3 dataset streaming
   - Azure Blob Storage support
   - Google Cloud Storage native paths
   - Weights & Biases integration

2. **Advanced Training Methods**
   - QLoRA (Quantized LoRA)
   - PEFT (Parameter-Efficient Fine-Tuning)
   - Adapter layers
   - Prompt tuning

3. **Intelligent Recommendations**
   - ML-powered hyperparameter suggestions
   - Dataset quality analysis
   - Training time prediction models
   - Performance outcome estimation

4. **Collaborative Features**
   - Shared configuration library
   - Team templates
   - Experiment comparison
   - Result sharing

5. **Advanced UI Features**
   - Web-based wizard option
   - Real-time training monitoring
   - Interactive parameter tuning
   - Visual dataset preview

### Research Directions

1. **AutoML Integration**: Automatic hyperparameter optimization
2. **Few-Shot Learning**: Minimal data training workflows
3. **Continual Learning**: Incremental model updates
4. **Multi-Task Training**: Single model, multiple objectives
5. **Federated Learning**: Privacy-preserving training

## Appendix

### A. Complete Parameter Reference

#### Training Method Parameters

| Method | Parameter | Type | Default | Description |
|--------|-----------|------|---------|-------------|
| All | learning_rate | float | 1e-5 | Optimization step size |
| All | num_train_epochs | int | 3 | Training iterations |
| All | warmup_steps | int | 500 | LR warmup period |
| All | per_device_train_batch_size | int | 8 | Batch size per device |
| All | gradient_accumulation_steps | int | 1 | Gradient accumulation |
| LoRA | lora_rank | int | 16 | Low-rank dimension |
| LoRA | lora_alpha | int | 32 | LoRA scaling factor |
| LoRA | lora_dropout | float | 0.1 | LoRA dropout rate |
| Distil | temperature | float | 5.0 | Distillation temperature |
| Distil | kl_weight | float | 0.5 | KL loss weight |

#### Platform-Specific Defaults

| Platform | Batch Size | Workers | Precision | Memory Limit |
|----------|------------|---------|-----------|--------------|
| MPS | 4-8 | 4-8 | float32 | 80% RAM |
| CUDA | 8-16 | 8-16 | float16 | 90% VRAM |
| CPU | 2-4 | 4-8 | float32 | 70% RAM |

### B. Decision Trees

#### Method Selection Tree
```
Start
├── High Quality Needed?
│   └── Yes → Standard Fine-Tuning
└── No → Memory Constrained?
    ├── Yes → LoRA
    └── No → Need Smaller Model?
        ├── Yes → Knowledge Distillation
        └── No → Standard Fine-Tuning
```

#### Model Selection Tree
```
Start
├── Real-time Needed?
│   └── Yes → Tiny/Base Models
└── No → Quality Priority?
    ├── Yes → Large Models
    └── No → Memory Available?
        ├── < 4GB → Tiny
        ├── 4-8GB → Small
        └── > 8GB → Medium/Large
```

### C. Configuration Examples

#### Minimal Configuration (Beginner)
```python
{
    "method": "standard",
    "model": "whisper-small",
    "dataset": "common_voice",
    # Everything else uses defaults
}
```

#### LoRA Configuration (Intermediate)
```python
{
    "method": "lora",
    "model": "whisper-medium",
    "dataset": "librispeech",
    "lora_rank": 16,
    "lora_alpha": 32,
    "learning_rate": 1e-5,
    "num_train_epochs": 3
}
```

#### Advanced Distillation Configuration
```python
{
    "method": "distillation",
    "student_model_type": "custom",
    "student_encoder_from": "whisper-large-v3",
    "student_decoder_from": "whisper-tiny",
    "teacher_model": "whisper-large-v3",
    "temperature": 8.0,
    "kl_weight": 0.7,
    "learning_rate": 5e-6,
    "num_train_epochs": 5,
    "gradient_accumulation_steps": 4
}
```

### D. Troubleshooting Guide

| Issue | Symptoms | Solution |
|-------|----------|----------|
| Wizard won't start | Import errors | Check dependencies: `pip install rich questionary` |
| Memory detection wrong | Incorrect estimates | Verify with `psutil.virtual_memory()` |
| Model compatibility error | Training fails | Check mel-bins and d_model matching |
| Slow training | ETA very high | Switch to LoRA or smaller model |
| BigQuery timeout | Export fails | Reduce row limit or use sampling |

### E. Glossary

- **Progressive Disclosure**: UI pattern revealing complexity gradually
- **MPS**: Metal Performance Shaders (Apple Silicon GPU)
- **LoRA**: Low-Rank Adaptation for efficient fine-tuning
- **Knowledge Distillation**: Training smaller models from larger ones
- **d_model**: Model hidden dimension size
- **Mel-bins**: Mel-spectrogram frequency bins
- **Gradient Accumulation**: Simulating larger batches
- **Warmup Steps**: Gradual learning rate increase period
- **BigQuery**: Google Cloud data warehouse service
- **HuggingFace**: Model and dataset hosting platform