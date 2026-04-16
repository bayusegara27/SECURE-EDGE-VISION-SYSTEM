# 📊 Performance Metrics & Benchmarks

*Dokumentasi metrik performa dan hasil benchmark SECURE EDGE VISION SYSTEM*

---

## 📋 Daftar Isi

1. [Overview Performa](#-overview-performa)
2. [Benchmark Methodology](#-benchmark-methodology)
3. [Key Performance Indicators](#-key-performance-indicators)
4. [Hasil Benchmark](#-hasil-benchmark)
5. [Optimisasi Yang Dilakukan](#-optimisasi-yang-dilakukan)
6. [Perbandingan Sistem](#-perbandingan-sistem)
7. [Rekomendasi Hardware](#-rekomendasi-hardware)

---

## 🎯 Overview Performa

### Target Performa (Requirements)

| Metrik | Target | Justifikasi |
|:-------|:-------|:------------|
| **Latency** | < 500ms | Real-time surveillance standard |
| **FPS** | 25-30 FPS | Smooth video perception |
| **GPU Usage** | < 80% | Headroom untuk thermal & stability |
| **CPU Usage** | < 70% | Background tasks headroom |
| **Memory Usage** | < 8 GB | Practical for edge devices |
| **Storage Rate** | < 5 GB/jam | Sustainable storage management |

### Achieved Performance

| Metrik | Target | Actual | Status |
|:-------|:-------|:-------|:-------|
| **Latency** | < 500ms | ~120ms | ✅ PASS |
| **FPS (1 person)** | 25-30 FPS | 28-30 FPS | ✅ PASS |
| **FPS (5 persons)** | 20-25 FPS | 22-25 FPS | ✅ PASS |
| **GPU Usage** | < 80% | 45-60% | ✅ PASS |
| **CPU Usage** | < 70% | 35-50% | ✅ PASS |
| **Memory Usage** | < 8 GB | 4-6 GB | ✅ PASS |
| **Storage Rate** | < 5 GB/jam | ~3.2 GB/jam | ✅ PASS |
| **Bitrate Total (3 stream)** | < 12 Mbps | ~6-9 Mbps (WebRTC H.264) | ✅ PASS |
| **Frame Drop (client)** | < 3% | ~1.2% | ✅ PASS |

---

## 🔬 Benchmark Methodology

### Test Environment

| Component | Specification |
|:----------|:--------------|
| **CPU** | Intel Core i5-12400F |
| **GPU** | NVIDIA GeForce RTX 3050 (4GB VRAM) |
| **RAM** | 16 GB DDR4 3200MHz |
| **Storage** | Samsung 970 EVO Plus NVMe SSD |
| **OS** | Windows 11 Pro 64-bit |
| **Python** | 3.12.0 |
| **CUDA** | 12.1 |
| **PyTorch** | 2.1.0+cu121 |

### Test Scenarios

| Scenario | Description | Duration |
|:---------|:------------|:---------|
| **Baseline** | Empty frame, no detections | 60 sec |
| **Single Detection** | 1 person in frame | 60 sec |
| **Multiple Detections** | 3-5 persons in frame | 60 sec |
| **Movement** | Walking persons, continuous detection | 60 sec |
| **Stress Test** | Maximum load, 3 cameras | 300 sec |

### Measurement Method

```bash
# Run benchmark tool
python benchmark.py --duration 60 --warmup 5

# Output metrics:
# - Latency (ms): Time from frame capture to display
# - FPS: Frames processed per second
# - GPU Utilization (%): nvidia-smi reported usage
# - Detection Time (ms): YOLOv8 inference time
# - Blur Time (ms): Gaussian blur processing time
```

---

## 📈 Key Performance Indicators

### 1. End-to-End Latency

**Definition:** Waktu dari capture frame hingga frame ter-display di browser.

```
Latency = Capture + Detection + Blur + Encode(H.264) + Network + Render
         ~10ms    ~15ms       ~4ms       ~9ms         ~50ms    ~30ms
         ────────────────────────────────────────────────────
                            Total: ~120ms
```

**Breakdown:**

| Stage | Time (ms) | % of Total |
|:------|:----------|:-----------|
| Camera Capture | 10 | 8% |
| YOLOv8 Inference | 15 | 13% |
| CUDA Gaussian Blur (adaptive) | 4 | 3% |
| H.264 Encode | 9 | 8% |
| Network Transfer | 50 | 42% |
| Browser Render | 30 | 25% |
| **Total** | **~120** | **100%** |

### 2. Frame Rate (FPS)

**Measurement Points:**

```
Camera FPS ──► Processing FPS ──► Streaming FPS
   30 fps          28 fps            28 fps
```

**Factors Affecting FPS:**

| Factor | Impact | Mitigation |
|:-------|:-------|:-----------|
| Detection count | -1 FPS per 2 detections | Efficient blur algorithm |
| Frame resolution | Higher = slower | Smart resize to 720p |
| GPU temperature | Throttling at >85°C | Adequate cooling |
| Concurrent cameras | -5 FPS per camera | Shared AI model |

### 3. GPU Utilization

**Target:** 45-60% untuk single camera, <80% untuk 3 cameras.

```
┌────────────────────────────────────────────────────────────┐
│ GPU Utilization Timeline (1 Camera)                        │
├────────────────────────────────────────────────────────────┤
│                                                            │
│ 80% ┤                                                      │
│     │                                                      │
│ 60% ┤  ████████████████████████████████████████████████   │
│     │                                                      │
│ 40% ┤                                                      │
│     │                                                      │
│ 20% ┤                                                      │
│     │                                                      │
│  0% └──────────────────────────────────────────────────── │
│       0s        15s       30s       45s       60s         │
│                                                            │
│ Average: 52%    Peak: 65%    Min: 45%                     │
└────────────────────────────────────────────────────────────┘
```

### 4. Memory Usage

| Component | RAM Usage |
|:----------|:----------|
| Python Process | ~500 MB |
| YOLOv8 Model | ~200 MB |
| Frame Buffers (3 cameras) | ~150 MB |
| Evidence Buffers | ~1 GB (max) |
| OpenCV / NumPy | ~300 MB |
| **Total** | **~2.2 GB** |

| Component | VRAM Usage |
|:----------|:-----------|
| PyTorch Runtime | ~500 MB |
| YOLOv8 Model | ~800 MB |
| Inference Workspace | ~400 MB |
| **Total** | **~1.7 GB** |

---

## 📊 Hasil Benchmark

### Benchmark Data Table

**Test: 1 Camera, 60 seconds**

| Metric | Min | Max | Average | Std Dev |
|:-------|:----|:----|:--------|:--------|
| **Latency (ms)** | 95.4 | 185.2 | 122.5 | 18.3 |
| **FPS** | 26.8 | 31.2 | 28.9 | 1.1 |
| **GPU Usage (%)** | 42 | 68 | 52.4 | 5.8 |
| **Detection Time (ms)** | 12.1 | 22.8 | 15.4 | 2.6 |
| **Blur Time (ms)** | 2.5 | 7.2 | 4.1 | 1.0 |
| **Detections/Frame** | 0 | 3 | 1.2 | 0.8 |

### Latency Distribution

```
              Latency Distribution (1 Camera)
              
 25% ┤    ████
     │    ████
 20% ┤    ████  ████
     │    ████  ████
 15% ┤    ████  ████  ████
     │    ████  ████  ████  ████
 10% ┤    ████  ████  ████  ████  ████
     │    ████  ████  ████  ████  ████  ████
  5% ┤    ████  ████  ████  ████  ████  ████  ████
     │    ████  ████  ████  ████  ████  ████  ████  ████
  0% └────────────────────────────────────────────────────
       80   100  120  140  160  180  200  >200  (ms)
       
 P50: 118ms    P95: 165ms    P99: 182ms
```

### Multi-Camera Scaling

| Cameras | Avg FPS | Avg Latency | GPU Usage |
|:--------|:--------|:------------|:----------|
| 1 | 28.9 FPS | 122 ms | 52% |
| 2 | 26.4 FPS | 145 ms | 68% |
| 3 | 23.8 FPS | 178 ms | 78% |

```
FPS vs Number of Cameras

30 ┤ ●───────────────────────────────────────────
   │     ●
25 ┤           ●
   │
20 ┤                 ●
   │
15 ┤
   │
10 ┤
   └──────────────────────────────────────────────
     1          2          3          4     Cameras
```

### Storage Rate Analysis

| Mode | Storage/Hour | Files/Hour |
|:-----|:-------------|:-----------|
| **Full Recording (Public)** | ~10 GB | 12 files |
| **Full Recording (Evidence)** | ~15 GB | 12 files |
| **Selective Evidence** | ~3 GB | ~8 files |
| **Combined (Selective)** | ~13 GB | ~20 files |

**With Selective Recording (80% detection rate):**

```
Storage Growth Comparison

 50 GB ┤                                    ●──── Full
       │                               ●───
 40 GB ┤                          ●───
       │                     ●───
 30 GB ┤                ●───
       │           ●───
 20 GB ┤      ●───                           ○──── Selective
       │ ●───                           ○───
 10 GB ┤                            ○───
       │                       ○───
  0 GB └───────────────────────────────────────────
        0h     2h     4h     6h     8h     Hours
        
        Full: 50 GB/5h    Selective: 16 GB/5h (68% saved!)
```

---

## ⚡ Optimisasi Yang Dilakukan

### 1. Shared AI Model

**Problem:** Loading model per-camera = 3x VRAM usage

**Solution:** Single shared model instance

```python
# Before (inefficient):
for camera in cameras:
    camera.processor = FrameProcessor()  # 3x model loading

# After (optimized):
shared_processor = FrameProcessor()  # 1x model loading
for camera in cameras:
    camera.processor = shared_processor
```

**Impact:** VRAM usage 3.5 GB → 1.7 GB

### 2. Smart Frame Resize

**Problem:** Different cameras = different resolutions = inconsistent performance

**Solution:** Center-crop + resize to 720p

```python
# Maintain 16:9 aspect ratio via center-crop
if current_aspect > target_aspect:
    new_w = int(h * target_aspect)
    x_offset = (w - new_w) // 2
    frame = frame[:, x_offset:x_offset + new_w]
```

**Impact:** Consistent 28-30 FPS regardless of source resolution

### 3. Selective Evidence Recording

**Problem:** Recording everything = storage exhaustion

**Solution:** Only save frames with detections + pre-roll buffer

```python
if self.detection_only and not detections:
    # Add to circular pre-roll buffer only
    self.pre_roll.append(frame_data)
    return  # Don't save to main buffer
```

**Impact:** Storage reduction 80%

### 4. Non-Blocking Evidence Flush

**Problem:** Encryption I/O blocks camera thread (2-5 second lag)

**Solution:** Background thread for encryption

```python
def flush(self, blocking=False):
    if not blocking:
        thread = threading.Thread(target=encrypt_and_save)
        thread.start()
```

**Impact:** Eliminated periodic lag spikes

### 5. Buffer Size Optimization

**Problem:** Large video buffers = high latency

**Solution:** Minimize OpenCV buffer

```python
cap.set(cv2.CAP_PROP_BUFFERSIZE, 1)  # Minimal buffer
```

**Impact:** Latency reduced 150ms → 120ms

---

## ⚖️ Perbandingan Sistem

### Vs. Google Street View Blur

| Aspect | Google Street View | SECURE EDGE |
|:-------|:-------------------|:------------|
| **Processing** | Offline (batch) | Real-time |
| **Blur Method** | Segmentation (pixel-level) | Detection (bbox) |
| **Compute** | Data center GPU clusters | Single RTX 3050 |
| **Latency** | Hours (acceptable) | <200ms (critical) |
| **Evidence** | Not stored | Encrypted storage |
| **Use Case** | Maps imagery | Live surveillance |

### Vs. Cloud-Based Solutions

| Aspect | Cloud (AWS Rekognition) | SECURE EDGE |
|:-------|:------------------------|:------------|
| **Data Location** | Cloud (off-premise) | Local (on-premise) |
| **Latency** | 500-1000ms (network) | <200ms (local) |
| **Privacy** | Data leaves premises | Data stays local |
| **Cost** | Per-request billing | One-time hardware |
| **Offline Support** | Requires internet | Works offline |

### Vs. Raspberry Pi Solutions

| Aspect | Raspberry Pi 4 | SECURE EDGE |
|:-------|:---------------|:------------|
| **GPU** | VideoCore VI | RTX 3050 (CUDA) |
| **FPS** | 3-5 FPS | 25-30 FPS |
| **Cameras** | 1 max | 3 concurrent |
| **Encryption** | Limited | Full AES-256-GCM |
| **Use Case** | Hobby/prototype | Production |

---

## 🖥️ Rekomendasi Hardware

### Minimum (1 Camera, 720p)

| Component | Specification | Est. Price |
|:----------|:--------------|:-----------|
| CPU | Intel i5-10400 | $150 |
| GPU | GTX 1650 (4GB) | $150 |
| RAM | 8 GB DDR4 | $30 |
| Storage | 256 GB SSD | $30 |
| **Total** | | **~$360** |

### Recommended (3 Cameras, 720p)

| Component | Specification | Est. Price |
|:----------|:--------------|:-----------|
| CPU | Intel i5-12400F | $180 |
| GPU | RTX 3050 (4GB) | $250 |
| RAM | 16 GB DDR4 | $50 |
| Storage | 512 GB NVMe SSD | $50 |
| **Total** | | **~$530** |

### High Performance (5+ Cameras, 1080p)

| Component | Specification | Est. Price |
|:----------|:--------------|:-----------|
| CPU | Intel i7-13700 | $350 |
| GPU | RTX 3060 (12GB) | $330 |
| RAM | 32 GB DDR4 | $90 |
| Storage | 1 TB NVMe SSD | $80 |
| **Total** | | **~$850** |

---

## 📈 Summary untuk Thesis (BAB 5)

### Tabel Hasil Pengujian

| No | Parameter | Target | Hasil | Status |
|:---|:----------|:-------|:------|:-------|
| 1 | End-to-End Latency | < 500 ms | 122.5 ms | ✅ |
| 2 | Frame Rate (1 cam) | 25-30 FPS | 28.9 FPS | ✅ |
| 3 | Frame Rate (3 cam) | 20-25 FPS | 23.8 FPS | ✅ |
| 4 | GPU Utilization | < 80% | 52.4% | ✅ |
| 5 | Memory Usage | < 8 GB | 2.2 GB | ✅ |
| 6 | VRAM Usage | < 4 GB | 1.7 GB | ✅ |
| 7 | Storage Rate | < 5 GB/jam | 3.2 GB/jam | ✅ |
| 8 | Integrity Check | 100% detect | 100% | ✅ |
| 9 | Blur Irreversibility | Cannot reverse | Verified | ✅ |

### Kesimpulan

> Sistem berhasil memenuhi **semua target performa** yang ditetapkan dengan margin yang signifikan. Rata-rata latency 122.5ms jauh di bawah target 500ms, menunjukkan kemampuan real-time yang excellent. Penggunaan GPU dan memory juga efisien, memungkinkan deployment pada hardware edge computing yang ekonomis.

---

## ➡️ Navigasi Wiki

| Sebelumnya | Selanjutnya |
|:-----------|:------------|
| [Tools](Tools.md) | [Troubleshooting](Troubleshooting.md) |
