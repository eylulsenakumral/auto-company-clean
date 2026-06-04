# Performance Bottleneck Analysis - NextVision
**Date:** 2026-06-03
**Author:** Werner Vogels (CTO)
**Focus:** Occupational Safety Module - Production Readiness

---

## Executive Summary

NextVision occupational_safety modülü için **3 kritik bottleneck** identifiye edilmiştir:

1. **RTSP Ingestion → Frame Buffer** (Throughput limit: 120 FPS)
2. **YOLO Inference** (GPU-bound, no horizontal scaling)
3. **MinIO Video Upload** (I/O-bound, no async queue)

**En kritik sorun:** YOLO service'in GPU bağımlılığı nedeniyle horizontal scaling desteklememesi. Bu, multi-camera deployment'da hard limit oluşturur.

---

## Bottleneck #1: RTSP Ingestion & Frame Buffer

### Current Architecture

```
RTSP Camera (30 FPS each)
    ↓
cv2.VideoCapture (blocking read)
    ↓
Redis List (frame buffer)
    ↓
YOLO Service (pull consumer)
```

### Bottleneck Analysis

**Throughput Limit Calculation:**

```python
# Current: Single RTSP consumer per camera
camera_fps ***REMOVED*** 30
num_cameras ***REMOVED*** 4
total_fps ***REMOVED*** 120

# Redis List push operation
redis_lpush_time ***REMOVED*** 0.5ms  # Optimistic local network
# Throughput ***REMOVED*** 1 / 0.0005 ***REMOVED*** 2000 FPS theoretical

# But cv2.VideoCapture.read() is BLOCKING
frame_grab_time ***REMOVED*** 33ms  # 1/30 second per camera
# Effective throughput ***REMOVED*** 4 cameras × 30 FPS ***REMOVED*** 120 FPS max
```

**Problem:** `cv2.VideoCapture.read()` **blocking call**. Eğer bir camera disconnect olursa, entire thread bloke olur.

### Failure Scenario: Camera Disconnect

```
Camera 1 disconnect → cv2.read() blocks → No frames from Camera 1
                                                ↓
                                    Redis buffer underflows
                                                ↓
                            YOLO service waits for frames → GPU idle
```

**Impact:** GPU utilization drops from 80% to 60% ***REMOVED*** wasted capacity.

### Solution: Non-Blocking RTSP Ingestion

```python
# Required: Async RTSP ingestion with frame buffering
import asyncio
import cv2
from queue import Queue

class AsyncRTSPIngestion:
    def __init__(self, url, buffer_size***REMOVED***150):
        self.url ***REMOVED*** url
        self.buffer ***REMOVED*** Queue(maxsize***REMOVED***buffer_size)  # 5 seconds @ 30 FPS
        self.running ***REMOVED*** False

    async def ingest_loop(self):
        """Non-blocking frame capture"""
        cap ***REMOVED*** cv2.VideoCapture(self.url)

        while self.running:
            if not cap.isOpened():
                await self.reconnect_with_backoff()
                continue

            ret, frame ***REMOVED*** cap.read()
            if ret:
                if not self.buffer.full():
                    self.buffer.put(frame)
                else:
                    logger.warning("Buffer full, dropping frame")

            await asyncio.sleep(0)  # Yield control

    async def reconnect_with_backoff(self):
        """Exponential backoff reconnection"""
        retry_count ***REMOVED*** 0
        while retry_count < 5:
            try:
                cap ***REMOVED*** cv2.VideoCapture(self.url)
                if cap.isOpened():
                    logger.info("Reconnected successfully")
                    return
            except Exception:
                wait ***REMOVED*** 2 ** retry_count
                logger.warning(f"Reconnect attempt {retry_count}, waiting {wait}s")
                await asyncio.sleep(wait)
                retry_count +***REMOVED*** 1
```

**Performance Gain:**
- Camera disconnect: Other cameras unaffected
- Buffer full: Oldest frame dropped (configurable policy)
- Throughput: Sustained 120 FPS even with single camera failure

### Recommended Configuration

```yaml
# docker-compose.yml - RTSP ingestion service
rtsp-ingestion:
  build: ./src/services/rtsp-ingestion
  environment:
    - CAMERA_COUNT***REMOVED***4
    - BUFFER_SIZE_PER_CAMERA***REMOVED***150  # 5 seconds
    - RECONNECT_MAX_RETRIES***REMOVED***5
    - RECONNECT_BACKOFF_BASE***REMOVED***2
  deploy:
    resources:
      limits:
        cpus: '2'  # dedicate 2 cores to RTSP ingestion
  restart: unless-stopped
```

---

## Bottleneck #2: YOLO Inference (GPU-Bound)

### Current Architecture

```
Redis List (frame buffer)
    ↓
YOLO Service (single container, GPU-required)
    ↓
Detection Result → Redis Pub/Sub
```

### Bottleneck Analysis

**GPU Utilization Calculation:**

```python
# YOLOv8n performance (NVIDIA T4 GPU)
inference_time_per_frame ***REMOVED*** 10ms  # 640x640 input
max_fps_per_gpu ***REMOVED*** 100

# Current: Single GPU, single service
num_gpus ***REMOVED*** 1
theoretical_fps ***REMOVED*** 100

# Real-world with overhead
overhead_factor ***REMOVED*** 0.8  # Data transfer, preprocessing
effective_fps ***REMOVED*** 80

# Required throughput
required_fps ***REMOVED*** 120  # 4 cameras × 30 FPS

# Gap
shortage ***REMOVED*** 120 - 80 ***REMOVED*** 40 FPS deficit
```

**Problem:** **Single GPU cannot handle 4 cameras @ 30 FPS.** Current design'de horizontal scaling yok çünkü GPU affinity var.

### Failure Scenario: GPU Overload

```
120 FPS input → 80 FPS processing capacity
    ↓
Frame backlog in Redis buffer
    ↓
Buffer grows: 150 frames → 300 frames → OOM
    ↓
Redis OOM → Frames dropped → Violations missed
```

**Impact:** Critical violations undetected ***REMOVED*** production safety risk.

### Solution #1: Frame Skipping (Quick Fix)

```python
# Add to YOLO service
class FrameSkippingStrategy:
    def __init__(self, target_fps***REMOVED***80):
        self.target_fps ***REMOVED*** target_fps
        self.last_process_time ***REMOVED*** time.time()
        self.frame_interval ***REMOVED*** 1.0 / target_fps

    def should_process(self, current_time):
        """Determine if frame should be processed"""
        elapsed ***REMOVED*** current_time - self.last_process_time
        if elapsed >***REMOVED*** self.frame_interval:
            self.last_process_time ***REMOVED*** current_time
            return True
        return False
```

**Trade-off:**
- Process every frame: Violations detected, system overloaded
- Skip frames: System stable, some violations missed

**Vogels' Principle:**
> **Degrade gracefully.** Better to process 80 FPS reliably than 120 FPS unreliably.

### Solution #2: Multi-GPU Deployment (Production)

```yaml
# docker-compose.yml - Multi-GPU setup
yolo-service-gpu-0:
  build: ./src/services/yolo
  runtime: nvidia
  environment:
    - NVIDIA_VISIBLE_DEVICES***REMOVED***0  # GPU 0
    - CAMERA_INDEXES***REMOVED***0,1  # Process cameras 0-1
  deploy:
    resources:
      reservations:
        devices:
          - driver: nvidia
            device_ids: ['0']
            capabilities: [gpu]

yolo-service-gpu-1:
  build: ./src/services/yolo
  runtime: nvidia
  environment:
    - NVIDIA_VISIBLE_DEVICES***REMOVED***1  # GPU 1
    - CAMERA_INDEXES***REMOVED***2,3  # Process cameras 2-3
  deploy:
    resources:
      reservations:
        devices:
          - driver: nvidia
            device_ids: ['1']
            capabilities: [gpu]
```

**Performance Gain:**
- 2 GPUs: 160 FPS capacity (40 FPS headroom)
- 4 GPUs: 320 FPS capacity (200 FPS headroom)

### Solution #3: CPU Fallback (Emergency)

```yaml
# docker-compose.yml - CPU fallback
yolo-service-cpu:
  build: ./src/services/yolo
  environment:
    - YOLO_DEVICE***REMOVED***cpu  # Force CPU inference
    - YOLO_MODEL_PATH***REMOVED***/models/yolov8n.pt
  deploy:
    resources:
      limits:
        cpus: '8'
  restart: unless-stopped
  # Active only when GPU services fail (via health check)
```

**Performance Penalty:**
- CPU inference: ~100ms per frame vs 10ms GPU
- Effective FPS: 10 FPS vs 80 FPS
- Use case: Emergency only (GPU crash)

---

## Bottleneck #3: MinIO Video Upload (I/O-Bound)

### Current Architecture

```
Violation Detected → Video Clip Upload → MinIO
    ↓
Direct PUT operation (blocking)
```

### Bottleneck Analysis

**I/O Throughput Calculation:**

```python
# Video clip: 10 seconds @ 30 FPS, 640x480, H.264
clip_size_mb ***REMOVED*** 5  # Approximate
upload_time ***REMOVED*** 2s  # MinIO PUT operation (local network)
throughput ***REMOVED*** 2.5 MB/s

# Concurrent uploads (worst case: 4 violations simultaneously)
total_bandwidth ***REMOVED*** 4 × 2.5 ***REMOVED*** 10 MB/s
```

**Problem:** Video upload **blocking call**. Eğer MinIO slow veya unreachable olursa, entire request bloke olur.

### Failure Scenario: MinIO Slow/Down

```
Violation detected → Upload to MinIO (blocks)
    ↓
MinIO slow (10s PUT time)
    ↓
API request hangs → Database write blocked
    ↓
Violation detection stalled
```

**Impact:** Real-time monitoring stops during MinIO issues.

### Solution: Async Upload Queue

```python
# Required: Async video upload with Redis queue
import asyncio
from aiobotocore import AiobotocoreSession

class AsyncMinIOUploader:
    def __init__(self, redis_client, minio_config):
        self.redis ***REMOVED*** redis_client
        self.config ***REMOVED*** minio_config
        self.upload_queue ***REMOVED*** "minio:upload:queue"

    async def enqueue_upload(self, video_path, metadata):
        """Enqueue video for async upload"""
        payload ***REMOVED*** {
            "video_path": video_path,
            "metadata": metadata,
            "enqueued_at": time.time()
        }
        await self.redis.rpush(self.upload_queue, json.dumps(payload))

    async def upload_worker(self):
        """Background worker for uploads"""
        session ***REMOVED*** AiobotocoreSession()

        while True:
            # Blocking pop with timeout
            item ***REMOVED*** await self.redis.blpop(self.upload_queue, timeout***REMOVED***5)

            if item:
                payload ***REMOVED*** json.loads(item[1])
                await self.upload_to_minio(payload, session)

    async def upload_to_minio(self, payload, session):
        """Upload video with retry logic"""
        retry_count ***REMOVED*** 0
        while retry_count < 3:
            try:
                # Async upload
                await session.put_object(
                    Bucket***REMOVED***"nextvision-videos",
                    Key***REMOVED***payload["video_path"],
                    Filename***REMOVED***payload["video_path"]
                )
                logger.info(f"Uploaded: {payload['video_path']}")
                return
            except Exception as e:
                retry_count +***REMOVED*** 1
                wait ***REMOVED*** 2 ** retry_count
                logger.warning(f"Upload failed, retry {retry_count}: {e}")
                await asyncio.sleep(wait)
```

**Performance Gain:**
- API response time: 2s → 50ms (enqueue only)
- MinIO failure: No impact on real-time detection
- Throughput: Limited only by network bandwidth

### Recommended Configuration

```yaml
# docker-compose.yml - Async upload worker
minio-upload-worker:
  build: ./src/services/minio-upload-worker
  environment:
    - MINIO_ENDPOINT***REMOVED***minio:9000
    - REDIS_URL***REMOVED***redis://:${REDIS_PASSWORD}@redis:6379
    - UPLOAD_CONCURRENCY***REMOVED***5  # 5 parallel uploads
    - UPLOAD_RETRY_LIMIT***REMOVED***3
  deploy:
    resources:
      limits:
        cpus: '2'
        memory: 2G
  restart: unless-stopped
```

---

## Bottleneck #4: PostgreSQL Write Throughput

### Current Architecture

```
Detection Result → Rule Engine → PostgreSQL Write
    ↓
Synchronous INSERT (blocking)
```

### Bottleneck Analysis

**Write Throughput Calculation:**

```python
# Detection write: Single row insert
insert_time ***REMOVED*** 5ms  # PostgreSQL on local network
max_writes_per_second ***REMOVED*** 200

# Current: 120 FPS × 50% violation rate ***REMOVED*** 60 writes/second
utilization ***REMOVED*** 60 / 200 ***REMOVED*** 30%
```

**Assessment:** PostgreSQL **NOT** a bottleneck for pilot scale (4 cameras). However, scaling risk exists.

### Scaling Risk: Multi-Factory Deployment

```python
# 10 factories, 4 cameras each
total_cameras ***REMOVED*** 40
total_fps ***REMOVED*** 1200
violation_rate ***REMOVED*** 0.5
writes_per_second ***REMOVED*** 600

# PostgreSQL capacity exceeded
shortage ***REMOVED*** 600 - 200 ***REMOVED*** 400 writes/second deficit
```

**Problem:** Synchronous writes don't scale beyond 200 writes/second.

### Solution: Batch Writes + Write-Ahead Log

```python
# Required: Batch write optimization
class BatchDetectionWriter:
    def __init__(self, batch_size***REMOVED***100, flush_interval***REMOVED***1s):
        self.batch ***REMOVED*** []
        self.batch_size ***REMOVED*** batch_size
        self.flush_interval ***REMOVED*** flush_interval

    def add_detection(self, detection):
        """Add to batch, flush if full"""
        self.batch.append(detection)

        if len(self.batch) >***REMOVED*** self.batch_size:
            self.flush()

    def flush(self):
        """Batch INSERT to PostgreSQL"""
        if not self.batch:
            return

        # Single INSERT with multiple rows
        query ***REMOVED*** """
            INSERT INTO detections (frame_id, timestamp, class_id, confidence, bbox)
            VALUES %s
        """
        values ***REMOVED*** [(d.frame_id, d.timestamp, d.class_id, d.confidence, d.bbox)
                  for d in self.batch]

        # Execute batch
        cursor.executemany(query, values)
        self.batch ***REMOVED*** []
```

**Performance Gain:**
- Single write: 5ms
- Batch of 100: 50ms total ***REMOVED*** 0.5ms per write
- Throughput: 200 → 2000 writes/second

---

## End-to-End Performance Model

### Current System Performance

```
┌─────────────────────────────────────────────────────────────┐
│                  Performance Chain                            │
├─────────────────────────────────────────────────────────────┤
│                                                             │
│  RTSP Ingestion     →  120 FPS  ✓ (sufficient)              │
│  Redis Buffer       →  2000 FPS ✓ (sufficient)              │
│  YOLO Inference     →  80 FPS   ✗ (bottleneck)              │
│  Rule Engine        →  1000 FPS ✓ (sufficient)              │
│  PostgreSQL Write   →  200 FPS  ✓ (sufficient)              │
│  MinIO Upload       →  2 MB/s   ⚠ (blocking)               │
│                                                             │
│  SYSTEM BOTTLENECK: YOLO Inference (80 FPS vs 120 FPS)      │
└─────────────────────────────────────────────────────────────┘
```

### Optimized System Performance

```
┌─────────────────────────────────────────────────────────────┐
│             Post-Optimization Performance Chain             │
├─────────────────────────────────────────────────────────────┤
│                                                             │
│  RTSP Ingestion (async)     →  150 FPS  ✓ (improved)        │
│  Redis Buffer               →  2000 FPS ✓ (unchanged)        │
│  YOLO Inference (2 GPUs)    →  160 FPS  ✓ (resolved)        │
│  Rule Engine                →  1000 FPS ✓ (unchanged)        │
│  PostgreSQL (batch writes)  →  2000 FPS ✓ (improved)        │
│  MinIO Upload (async)       →  50 MB/s  ✓ (resolved)        │
│                                                             │
│  SYSTEM BOTTLENECK: None (160 FPS > 120 FPS required)      │
└─────────────────────────────────────────────────────────────┘
```

---

## Performance Testing Plan

### Load Testing Scenarios

#### Scenario 1: Baseline (Single Camera)

```python
# Test: 1 camera @ 30 FPS, 10 minutes
camera_count ***REMOVED*** 1
fps_per_camera ***REMOVED*** 30
duration_minutes ***REMOVED*** 10

# Expected metrics
expected_detections ***REMOVED*** 30 × 60 × 10 ***REMOVED*** 18,000 frames
expected_violations ***REMOVED*** 18,000 × 0.1 ***REMOVED*** 1,800 violations  # 10% violation rate

# Acceptance criteria
- CPU utilization < 70%
- GPU utilization < 50%
- Redis memory < 500MB
- PostgreSQL latency < 10ms
- Zero frame drops
```

#### Scenario 2: Pilot Load (4 Cameras)

```python
# Test: 4 cameras @ 30 FPS, 1 hour
camera_count ***REMOVED*** 4
fps_per_camera ***REMOVED*** 30
duration_minutes ***REMOVED*** 60

# Expected metrics
expected_detections ***REMOVED*** 4 × 30 × 60 × 60 ***REMOVED*** 432,000 frames
expected_violations ***REMOVED*** 432,000 × 0.1 ***REMOVED*** 43,200 violations

# Acceptance criteria
- CPU utilization < 90%
- GPU utilization < 85%
- Redis memory < 2GB
- PostgreSQL latency < 20ms
- < 1% frame drops (graceful degradation)
```

#### Scenario 3: Stress Test (8 Cameras)

```python
# Test: 8 cameras @ 30 FPS, 10 minutes (beyond pilot scope)
camera_count ***REMOVED*** 8
fps_per_camera ***REMOVED*** 30
duration_minutes ***REMOVED*** 10

# Expected behavior
- System degrades gracefully (frame skipping)
- No crashes or OOM
- Alerts triggered for overload

# Acceptance criteria
- No service crashes
- Auto-scaling triggered (if configured)
- Clear overload alerts
```

### Performance Monitoring Dashboard

**Required Metrics:**

```yaml
# Prometheus metrics to expose
metrics:
  # System metrics
  - cpu_usage_percent
  - gpu_usage_percent
  - memory_usage_bytes
  - disk_io_percent

  # Application metrics
  - rtsp_frames_ingested_total
  - rtsp_frames_dropped_total
  - yolo_inference_duration_seconds
  - yolo_fps_current
  - redis_buffer_size
  - postgresql_write_duration_seconds
  - minio_upload_duration_seconds
  - minio_upload_queue_size

  # Business metrics
  - violations_detected_total
  - violations_by_severity{severity***REMOVED***"CRITICAL|HIGH|MEDIUM|LOW"}
  - cameras_connected_total
  - cameras_disconnected_total
```

**Grafana Dashboard Panels:**

```
┌─────────────────────────────────────────────────────────────┐
│                    Grafana Dashboard                         │
├─────────────────────────────────────────────────────────────┤
│                                                             │
│  [Panel 1] Real-time FPS                                    │
│  ┌──────────────────────────────────────────────────────┐  │
│  │ YOLO FPS: 75 / 80 (94%)                               │  │
│  │ Target: 120 FPS                                       │  │
│  └──────────────────────────────────────────────────────┘  │
│                                                             │
│  [Panel 2] Camera Status                                   │
│  ┌──────────────────────────────────────────────────────┐  │
│  │ Camera 1: ✓ Connected (30 FPS)                       │  │
│  │ Camera 2: ✓ Connected (30 FPS)                       │  │
│  │ Camera 3: ⚠ Reconnecting (0 FPS, 2s ago)             │  │
│  │ Camera 4: ✓ Connected (30 FPS)                       │  │
│  └──────────────────────────────────────────────────────┘  │
│                                                             │
│  [Panel 3] Violations (Last 24h)                           │
│  ┌──────────────────────────────────────────────────────┐  │
│  │ CRITICAL: 1,234                                        │  │
│  │ HIGH:    567                                          │  │
│  │ MEDIUM:  890                                          │  │
│  │ LOW:     2,345                                        │  │
│  └──────────────────────────────────────────────────────┘  │
│                                                             │
│  [Panel 4] System Resources                                │
│  ┌──────────────────────────────────────────────────────┐  │
│  │ CPU:  68% | GPU: 82% | Memory: 4.2GB / 16GB         │  │
│  │ Redis: 1.2GB | PostgreSQL: 890MB                    │  │
│  └──────────────────────────────────────────────────────┘  │
│                                                             │
└─────────────────────────────────────────────────────────────┘
```

---

## Recommendations Summary

### Immediate Actions (Pre-Pilot)

1. **Implement RTSP Reconnection Logic**
   - Async ingestion with frame buffer
   - Exponential backoff reconnector
   - Camera isolation (one camera failure doesn't affect others)
   - **Effort:** 4 hours

2. **Optimize YOLO Throughput**
   - Frame skipping strategy (target 80 FPS)
   - Multi-GPU deployment (2 GPUs for pilot)
   - CPU fallback service (emergency only)
   - **Effort:** 6 hours

3. **Implement Async MinIO Upload**
   - Redis-backed upload queue
   - Background worker with retry logic
   - Non-blocking API responses
   - **Effort:** 6 hours

### Post-Pilot Optimizations

4. **Batch PostgreSQL Writes**
   - Accumulate detections in memory
   - Flush every 100 detections or 1 second
   - 10x throughput improvement
   - **Effort:** 4 hours

5. **Add Performance Monitoring**
   - Prometheus metrics endpoint
   - Grafana dashboard
   - Alertmanager configuration
   - **Effort:** 8 hours

### Long-Term Scalability

6. **Consider Cloud Offload**
   - RTSP ingestion at edge (thin client)
   - Stream frames to cloud GPU cluster
   - Horizontal scaling without GPU limits
   - **Effort:** 40 hours (Phase 2)

---

## Conclusion

NextVision performance bottleneck'ları **identifiye edildi ve çözüm önerileri sunuldu**. En kritik bottleneck, YOLO inference'ın GPU bağımlılığı nedeniyle horizontal scaling yapılamamasıdır.

**Pilot deployment için yeterli mi?**
- Evet, 2 GPU ile 160 FPS kapasite ***REMOVED*** 120 FPS required
- Frame skipping strategy ile graceful degradation garanti
- Async MinIO upload ile I/O blocking kaldırıldı

**Multi-factory deployment için yeterli mi?**
- Hayır, her fabrikaya 2 GPU tahsis etmek maliyetli
- Phase 2: Cloud offload veya hybrid edge/cloud mimarisi gerekli

**Vogels' Final Assessment:**
> "Performance bottleneck'ları teknik olarak çözülebilir. Asıl sorun operational: GPU failure, camera disconnect, MinIO down senaryolarında sistemi nasıl ayağa tutacağımız? Failure handling design eksik."

---

**Owner:** Werner Vogels (CTO)
**Date:** 2026-06-03
**Next Action:** Implement recommended optimizations before pilot deployment
