# Ensemble Knowledge Distillation for Semantic Segmentation

## 🎯 Project Overview

This project implements an **ensemble knowledge distillation** framework for semantic segmentation on desert terrain images. We use two powerful teacher models (DeepLabV3+ and SegFormer-B3) to train a lightweight student model (SegFormer-B1), achieving competitive performance with significantly fewer parameters.

---

## 📊 Architecture Overview

```
┌─────────────────────────────────────────────────────────────────┐
│                        TRAINING PIPELINE                         │
└─────────────────────────────────────────────────────────────────┘

Phase 1: Teacher Training
─────────────────────────
┌──────────────────────┐      ┌──────────────────────┐
│  DeepLabV3+          │      │  SegFormer-B3        │
│  + ResNet50          │      │  (mit-b3)            │
│  Backbone            │      │                      │
│                      │      │                      │
│  Parameters: ~40M    │      │  Parameters: ~45M    │
└──────────┬───────────┘      └──────────┬───────────┘
           │                             │
           │ Train on Dataset            │ Train on Dataset
           │                             │
           ▼                             ▼
    ┌──────────────┐              ┌──────────────┐
    │ deep_lab.pth │              │ best_model.pth│
    └──────────────┘              └──────────────┘


Phase 2: Ensemble Knowledge Distillation
─────────────────────────────────────────
    ┌──────────────┐              ┌──────────────┐
    │ deep_lab.pth │              │ best_model.pth│
    │ (frozen)     │              │ (frozen)      │
    └──────┬───────┘              └───────┬───────┘
           │                              │
           │         ┌────────────────────┘
           │         │
           ▼         ▼
    ┌─────────────────────────┐
    │  Ensemble Teacher       │
    │  (Weighted Average)     │
    │  Weight: [0.5, 0.5]     │
    └───────────┬─────────────┘
                │
                │ Soft Labels (Temperature Scaled)
                │
                ▼
    ┌─────────────────────────┐
    │   SegFormer-B1          │
    │   (Student)             │
    │   Parameters: ~13.7M    │
    │                         │
    │   Learns from:          │
    │   • Teacher ensemble    │
    │   • Ground truth        │
    └─────────────────────────┘
                │
                ▼
    ┌─────────────────────────┐
    │  best_student.pth       │
    │  (Lightweight Model)    │
    └─────────────────────────┘
```

---

## 🏗️ Model Architecture Details

### Teacher Models

#### 1. **DeepLabV3+ with ResNet50**
- **Architecture**: DeepLabV3+ with atrous spatial pyramid pooling (ASPP)
- **Backbone**: ResNet50 (pretrained on ImageNet)
- **Parameters**: ~40M
- **Strengths**: 
  - Excellent multi-scale feature extraction
  - Strong boundary detection
  - Robust to object scale variations

#### 2. **SegFormer-B3**
- **Architecture**: Transformer-based encoder with lightweight MLP decoder
- **Backbone**: Mix Transformer (MiT-B3)
- **Parameters**: ~45M
- **Strengths**:
  - Global context understanding
  - Efficient hierarchical features
  - Better at capturing long-range dependencies

### Student Model

#### **SegFormer-B1**
- **Architecture**: Smaller Mix Transformer encoder
- **Backbone**: MiT-B1
- **Parameters**: ~13.7M (3x smaller than teachers!)
- **Target**: Learn compressed knowledge from teacher ensemble

---

## 📂 Dataset Structure

```
Offroad_Segmentation_Training_Dataset/
├── train/
│   ├── Color_Images/
│   │   ├── image_0001.png
│   │   ├── image_0002.png
│   │   └── ...
│   └── Segmentation/
│       ├── image_0001.png
│       ├── image_0002.png
│       └── ...
└── val/
    ├── Color_Images/
    └── Segmentation/
```

### Class Labels (10 classes)
```python
0: Trees
1: Lush Bushes
2: Dry Grass
3: Dry Bushes
4: Ground Clutter
5: Flowers
6: Logs
7: Rocks
8: Landscape
9: Sky
```

---

## 🔧 Training Process

### Phase 1: Train Teacher Models

Both teacher models are trained independently on the full dataset.

**Training Configuration:**
- Image Size: 512×512
- Batch Size: 8-16
- Learning Rate: 6e-5
- Optimizer: AdamW
- Loss: Cross-Entropy with class weights
- Augmentation: Flip, rotate, color jitter

**Output Files:**
- `deep_lab.pth` - DeepLabV3+ checkpoint
- `best_model.pth` - SegFormer-B3 checkpoint

### Phase 2: Ensemble Knowledge Distillation

The student model learns from both teachers simultaneously.

#### Distillation Loss Formula

```
L_total = α × L_soft + (1 - α) × L_hard

where:
L_soft  = KL_divergence(student_logits/T, teacher_logits/T) × T²
L_hard  = CrossEntropy(student_logits, ground_truth)

T = temperature (controls softness)
α = distillation weight (balance between soft/hard loss)
```

#### Key Hyperparameters

```python
temperature = 2.0          # Temperature for softening distributions
alpha_start = 0.3          # Start with more hard loss
alpha_end = 0.7            # End with more soft loss (progressive)
teacher_weights = [0.5, 0.5]  # Equal ensemble weights
learning_rate = 6e-5
batch_size = 8
num_epochs = 50
```

#### Progressive Distillation

The distillation weight (α) increases linearly during training:
- **Early epochs**: More focus on ground truth (α=0.3)
- **Later epochs**: More focus on teacher knowledge (α=0.7)

This helps the student first learn basic features, then refine with teacher guidance.

---

## 💻 Code Structure

```
project/
├── README.md
├── ensemble_knowledge_distillation.ipynb
│   └── Main training notebook with:
│       ├── Dataset loading
│       ├── Teacher ensemble setup
│       ├── Student model initialization
│       ├── Distillation loss implementation
│       └── Training loop
│
├── models/
│   ├── deep_lab.pth          # DeepLabV3+ checkpoint
│   └── best_model.pth         # SegFormer-B3 checkpoint
│
└── outputs/
    ├── best_student.pth       # Trained student model
    ├── training_curves.png    # Training visualization
    └── checkpoints/           # Intermediate checkpoints
```

---

## 🚀 Usage

### 1. Prepare Your Data

Organize your dataset following the structure above:
```bash
/path/to/dataset/
├── train/
│   ├── Color_Images/
│   └── Segmentation/
└── val/
    ├── Color_Images/
    └── Segmentation/
```

### 2. Train Teacher Models (if not already trained)

```python
# Train DeepLabV3+
teacher_deeplab = DeepLabV3Plus(num_classes=10)
# ... train on dataset
torch.save({
    'model_state_dict': teacher_deeplab.state_dict()
}, 'deep_lab.pth')

# Train SegFormer-B3
teacher_segformer = SegformerForSemanticSegmentation.from_pretrained(
    "nvidia/mit-b3", num_labels=10
)
# ... train on dataset
torch.save({
    'model_state_dict': teacher_segformer.state_dict()
}, 'best_model.pth')
```

### 3. Run Ensemble Knowledge Distillation

```python
# Update paths in config
config.train_dir = "/path/to/train"
config.val_dir = "/path/to/val"
config.deeplab_checkpoint = "/path/to/deep_lab.pth"
config.segformer_checkpoint = "/path/to/best_model.pth"

# Run training
student_model, history = train_distillation()
```

### 4. Inference with Trained Student

```python
# Load student model
student = SegformerForSemanticSegmentation.from_pretrained(
    "nvidia/mit-b1", num_labels=10
)
checkpoint = torch.load('outputs/best_student.pth')
student.load_state_dict(checkpoint['model_state_dict'])
student.eval()

# Run inference
with torch.no_grad():
    outputs = student(image_tensor)
    predictions = outputs.logits.argmax(dim=1)
```

---

## 📈 Results

### Model Comparison

| Model | Parameters | mIoU | Inference Speed |
|-------|-----------|------|-----------------|
| DeepLabV3+ (Teacher) | ~40M | 60% | ~30 FPS |
| SegFormer-B3 (Teacher) | ~45M | 65% | ~35 FPS |
| **SegFormer-B1 (Student)** | **~13.7M** | **65.55%** | **~80 FPS** |

### Advantages of Ensemble Distillation

✅ **3x smaller model** with competitive performance  
✅ **2-3x faster inference** - ideal for deployment  
✅ **Better generalization** - learns from multiple teachers  
✅ **Improved rare class performance** - teachers complement each other  

---

## 🔬 Technical Details

### Why Ensemble Teachers?

1. **Complementary Strengths**: 
   - DeepLabV3+ excels at fine boundaries
   - SegFormer captures global context
   - Ensemble combines both advantages

2. **Robustness**: 
   - Multiple teachers provide more stable soft labels
   - Reduces overfitting to single model biases

3. **Knowledge Diversity**:
   - Different architectures learn different features
   - Student benefits from richer supervision

### Key Implementation Details

#### 1. **Stable Loss Computation**
```python
# Clamp logits to prevent numerical overflow
student_logits = torch.clamp(student_logits / T, -10, 10)
teacher_logits = torch.clamp(teacher_logits / T, -10, 10)

# Clamp KL divergence to prevent explosion
soft_loss = torch.clamp(soft_loss, 0, 100)
```

#### 2. **Class Weight Balancing**
```python
# Compute weights from RAW masks (before augmentation)
class_weights = compute_class_weights_from_raw(dataset)

# Cap extreme weights to prevent instability
class_weights = np.clip(class_weights, 0.1, 10.0)
```

#### 3. **Teacher Output Alignment**
```python
# Interpolate SegFormer output to match input size
logits_sf = F.interpolate(
    segformer_logits, 
    size=(H, W), 
    mode='bilinear', 
    align_corners=False
)

# Ensemble: weighted average
ensemble = 0.5 * logits_sf + 0.5 * logits_dl
```

---

## 🐛 Common Issues & Solutions

### Issue 1: Missing Classes in Weight Computation
**Problem**: Rare classes show 0 pixels  
**Cause**: Computing weights after augmentation destroys rare classes  
**Solution**: Use `get_raw_mask()` to read masks before augmentation

### Issue 2: Exploding Loss (>1000)
**Problem**: Training loss becomes extremely large  
**Cause**: Numerical instability in KL divergence  
**Solution**: Clamp logits and soft loss values

### Issue 3: Only Few Classes Have IoU
**Problem**: Validation shows IoU only for 2-3 classes  
**Cause**: Model collapsing to dominant classes  
**Solution**: 
- Use proper class weights
- Start with lower α (more hard loss)
- Reduce temperature for sharper distributions

---

## 📚 References

### Papers
1. **DeepLabV3+**: [Encoder-Decoder with Atrous Separable Convolution](https://arxiv.org/abs/1802.02611)
2. **SegFormer**: [Simple and Efficient Design for Semantic Segmentation](https://arxiv.org/abs/2105.15203)
3. **Knowledge Distillation**: [Distilling the Knowledge in a Neural Network](https://arxiv.org/abs/1503.02531)

### Code References
- [Hugging Face Transformers](https://github.com/huggingface/transformers)
- [Torchvision Models](https://pytorch.org/vision/stable/models.html)
- [Albumentations](https://albumentations.ai/)

---

## 🤝 Contributing

Contributions are welcome! Areas for improvement:
- [ ] Add more teacher models to ensemble
- [ ] Experiment with different ensemble weights
- [ ] Try feature-level distillation
- [ ] Implement attention-based distillation
- [ ] Add model quantization for edge deployment

---

## 📄 License

This project is for educational purposes. Please cite the original papers if you use this code for research.

---

## 👥 Authors

**Vedansh / Krackheads**  
Contact: vedanshtyagi999@gmail.com


## 📊 Citation

If you use this code in your research, please cite:

```bibtex
@misc{ensemble_distillation_2024,
  author = {Vedansh Tyagi},
  title = {Ensemble Knowledge Distillation for Semantic Segmentation},
  year = {2026},
  publisher = {GitHub},
  url = {https://github.com/VedanshTyagi/krackhack_offroad_segmentation_hackathon}
}
```

---

**Last Updated**: February 2026  
**Version**: 1.0.0
