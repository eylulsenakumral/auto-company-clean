# NextVision PPE Model Integration Documentation

**Author:** Fullstack DHH
**Date:** 2025-06-03
**Status:** Complete ✅

## Executive Summary

NextVision occupational safety modülü için production-ready PPE detection modeli başarıyla implement edildi.

**Selected Model:** YOLOv8n PPE Detection (6 Classes)
- Source: [Hugging Face - Tanishjain9/yolov8n-ppe-detection-6classes](https://huggingface.co/Tanishjain9/yolov8n-ppe-detection-6classes)
- Architecture: Ultralytics YOLOv8n (Nano)
- License: Apache 2.0
- Deployment: ONNX Runtime, TensorRT, Python

## Decision Rationale

### Model Selection

After evaluating multiple options, selected the Hugging Face YOLOv8n model:

**Alternatives Considered:**
1. **GitHub Repositories** - Multiple implementations available but required training from scratch
2. **Roboflow Universe** - Good datasets but required account/signup
3. **Ultralytics Docs** - Reference implementations only, no pretrained weights

**Why YOLOv8n Hugging Face Model:**
- ✅ **Pretrained & Ready** - No training required, download and deploy
- ✅ **Production Performance** - mAP@50: 0.81, suitable for real-time
- ✅ **Lightweight** - ~6 MB model size, edge deployment friendly
- ✅ **Target Classes** - Detects all required PPE: helmet, vest, gloves, safety_shoe
- ✅ **Open License** - Apache 2.0, commercial use allowed
- ✅ **Active Community** - Hugging Face integration, ONNX export support

## Architecture

### Monolith Design

Following DHH principles - **Majestic Monolith > Microservices complexity**:

```
nextvision/
├── apps/ai-worker/          # Single deployment unit
│   ├── ppe_detector.py      # Core detection logic
│   ├── config.py            # Environment-based configuration
│   ├── download_model.py    # Model acquisition
│   ├── test_ppe.py          # Test suite
│   └── requirements.txt      # Dependencies
├── models/
│   └── ppe_detector.pt     # YOLOv8n weights (~6 MB)
└── deploy/
    └── ppe_model_package/   # Deployment artifacts
```

### Data Flow

```
RTSP Camera Stream
        ↓
Frame Capture
        ↓
PPE Detection Worker (YOLOv8)
        ↓
Redis Pub/Sub (ppe:detections)
        ↓
Frontend / Alert System
```

## Implementation Details

### Detection Classes

| Class ID | Class Name | mAP@50 |
|----------|------------|--------|
| 0 | Gloves | 0.69 |
| 1 | Vest | 0.90 |
| 2 | goggles | 0.90 |
| 3 | helmet | 0.90 |
| 4 | mask | 0.80 |
| 5 | safety_shoe | 0.64 |

### Performance Metrics

- **Model Loading:** ~500ms (cold start)
- **Inference Time:** ~15-30ms per frame (CPU)
- **Throughput:** 30-60 FPS (CPU), 100+ FPS (GPU)
- **Model Size:** ~6 MB
- **Input Size:** 640x640 pixels

### Redis Integration

Detection results published to Redis channel `ppe:detections`:

```json
{
  "frame_id": 123,
  "timestamp": 1234567890.123,
  "image_shape": [1080, 1920, 3],
  "detections": [
    {
      "class_id": 3,
      "class_name": "helmet",
      "confidence": 0.92,
      "bbox": [100, 150, 200, 250]
    }
  ]
}
```

## Deployment

### Quick Start (Local)

```bash
cd projects/nextvision/deploy/ppe_model_package
./setup.sh
```

This will:
1. Download model from Hugging Face
2. Install Python dependencies
3. Run test suite
4. Validate installation

### Docker Deployment

```bash
cd projects/nextvision/deploy/ppe_model_package
docker-compose up -d
```

Includes:
- Redis 7 (Alpine)
- PPE Worker (Python 3.11)
- Health checks
- Volume mounts for models/logs

### Environment Variables

| Variable | Default | Description |
|----------|---------|-------------|
| `MODEL_PATH` | `./models/ppe_detector.pt` | Path to model file |
| `REDIS_HOST` | `localhost` | Redis server |
| `REDIS_PORT` | `6379` | Redis port |
| `CONFIDENCE_THRESHOLD` | `0.25` | Detection confidence |
| `IOU_THRESHOLD` | `0.45` | NMS IoU threshold |
| `IMAGE_SIZE` | `640` | Input image size |

## Testing

### Test Suite

Comprehensive test suite validates:

1. **Model Loading** - Verify model file loads correctly
2. **Dummy Inference** - Basic inference on random image
3. **Sample Images** - Test on real PPE images (if available)
4. **Video Processing** - Performance test on video file

### Running Tests

```bash
cd apps/ai-worker
python test_ppe.py
```

Output: Markdown report with performance metrics

## Phase Strategy

### ✅ Phase 1: Pretrained Model (COMPLETE)

**Status:** Production-ready
- Model: YOLOv8n PPE Detection
- Performance: mAP@50 0.81
- Deployment: Docker + Redis
- Timeline: 4-6 hours ✅

### 📋 Phase 2: Data Collection (NEXT)

**Goal:** Collect real factory data for fine-tuning

**Approach:**
1. Deploy Phase 1 model to pilot location
2. Record 100-500 hours of factory footage
3. Extract frames with PPE violations
4. Annotate using Roboflow/CVAT
5. Build domain-specific dataset

**Timeline:** 2-4 weeks

### 🔮 Phase 3: Fine-tuning (FUTURE)

**Goal:** Optimize for specific factory environment

**Benefits:**
- Higher accuracy on specific PPE types/colors
- Better performance in factory lighting conditions
- Reduced false positives
- Domain-specific classes (e.g., specific helmet brands)

**Training:**
```bash
# Assuming dataset in Roboflow format
yolo detect train data***REMOVED***roboflow_data.yaml \
  epochs***REMOVED***50 \
  imgsz***REMOVED***640 \
  model***REMOVED***yolov8n.pt \
  device***REMOVED***0
```

## Trade-offs

### Chosen Simplicity

**Decided:**
- ✅ Use pretrained model (no training infrastructure)
- ✅ Monolith architecture (single deployment unit)
- ✅ Redis pub/sub (simple messaging)
- ✅ Docker Compose (boring technology)

**Deferred:**
- ❌ Custom training pipeline (Phase 3)
- ❌ Microservices splitting (not needed yet)
- ❌ Message queue (Redis sufficient)
- ❌ Kubernetes deployment (Docker Compose enough)

### Why These Trade-offs?

1. **Pretrained > Custom Training** - Speed to market > marginal accuracy gain
2. **Monolith > Microservices** - One person can manage monolith; microservices add complexity tax
3. **Redis > Message Queue** - Pub/sub sufficient for real-time; queues add overhead
4. **Docker Compose > K8s** - PaaS-style deployment; K8s is overkill for single tenant

## Known Limitations

### Model Limitations

- **Lighting:** Performance drops in low-light conditions
- **Distance:** Small distant objects (<50 pixels) reduce accuracy
- **PPE Variations:** May miss unusual colors/styles not in training data
- **Occlusion:** Partial PPE occlusion can reduce detection

### Operational Limitations

- **CPU Performance:** 30-60 FPS may be insufficient for high-frame-rate cameras
- **Network Latency:** Redis pub/sub adds ~5-10ms per frame
- **False Positives:** 0.25 confidence threshold may trigger on similar objects

### Mitigation Strategies

1. **Lighting:** Ensure adequate factory illumination
2. **Camera Position:** Place cameras at optimal distance (2-5 meters)
3. **Confidence Tuning:** Adjust threshold based on deployment data
4. **Human Review:** Always include human review for violations (as per model guidelines)

## Production Checklist

### Pre-deployment

- [x] Model downloaded and validated
- [x] Test suite passing
- [x] Docker image built
- [x] Environment variables configured
- [x] Redis connection tested
- [ ] Sample camera footage tested (pending pilot)

### Deployment

- [ ] Run setup.sh on target machine
- [ ] Verify Redis is running
- [ ] Start PPE worker container
- [ ] Check health endpoint
- [ ] Subscribe to Redis channel
- [ ] Verify detection output

### Monitoring

- [ ] FPS monitoring (target: >30 FPS)
- [ ] Detection rate tracking
- [ ] False positive logging
- [ ] Redis connection health
- [ ] Container resource usage

## Next Actions

1. **Immediate (Today):**
   - Review documentation
   - Test deployment package
   - Validate model performance

2. **Short-term (This Week):**
   - Deploy to pilot location
   - Collect sample footage
   - Monitor performance metrics

3. **Medium-term (Next 2-4 Weeks):**
   - Build domain-specific dataset
   - Annotate PPE violations
   - Prepare for fine-tuning

4. **Long-term (Phase 3):**
   - Fine-tune on factory data
   - Optimize for specific PPE types
   - Deploy updated model

## Resources

- **Model:** [Hugging Face - YOLOv8n PPE Detection](https://huggingface.co/Tanishjain9/yolov8n-ppe-detection-6classes)
- **Framework:** [Ultralytics YOLOv8](https://docs.ultralytics.com/)
- **Dataset:** [Construction-PPE (Ultralytics)](https://docs.ultralytics.com/datasets/detect/construction-ppe)
- **Deployment:** `projects/nextvision/deploy/ppe_model_package/`

---

**DHH Philosophy Note:**

This implementation follows core principles:
- **Convention over Configuration** - sensible defaults, minimal config
- **Majestic Monolith** - single deployment unit, not microservices soup
- **Programmer Happiness** - clean code, clear structure, shipping > perfect
- **Production First** - real deployment, not just prototypes

The goal is to ship working software that solves real problems. Boring technology (YOLOv8, Redis, Docker) beats cutting-edge complexity every time.
