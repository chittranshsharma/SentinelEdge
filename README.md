# SentinelEdge

## Edge AI Vibration Fault Detection — ESP32 TinyML → Raspberry Pi Gateway → Vercel Dashboard

---

## Research Question

> Can an ESP32-class microcontroller perform reliable vibration-based fault detection locally using TinyML while operating under strict memory and compute constraints?

This is an edge AI project. The intelligence lives on the microcontroller. Everything else — the gateway, cloud, dashboard — exists to operationalize the on-device decision. The model never touches the cloud during inference.

---

## System Architecture

```
┌─────────────────────────────────────────────────────────────┐
│                     EDGE LAYER (ESP32)                      │
│                                                             │
│  MPU6050 @ 100Hz → circular buffer (200 samples)           │
│         → 42-feature extraction (6 axes × 7 stats)         │
│         → StandardScaler normalize → int8 quantize         │
│         → TFLite Micro int8 inference (<100ms)              │
│         → if fault + confidence > 75%: MQTT publish        │
│                                                             │
│  DHT11 / MQ5 / NEO-6M → metadata only (not ML input)       │
│  Every 5s: heartbeat publish with all sensor readings       │
└─────────────────────────────────────────────────────────────┘
                            │ MQTT (paho / PubSubClient)
                            ▼
┌─────────────────────────────────────────────────────────────┐
│                  GATEWAY LAYER (Raspberry Pi 4)             │
│                                                             │
│  Mosquitto MQTT broker (port 1883)                         │
│  FastAPI backend:                                           │
│    sentineledge/anomaly   → Supabase + Groq + Telegram      │
│    sentineledge/heartbeat → Supabase sensor_readings        │
│    REST API: /api/anomalies, /api/readings, /api/status     │
└─────────────────────────────────────────────────────────────┘
                            │ HTTPS (Supabase)
                            ▼
┌─────────────────────────────────────────────────────────────┐
│                      CLOUD LAYER                            │
│                                                             │
│  Supabase — sensor_readings, anomalies, alerts             │
│             Realtime enabled for live dashboard updates     │
│                                                             │
│  Vercel — Next.js 14 dashboard                             │
│    /dashboard  — live readings + anomaly feed               │
│    /anomalies  — filterable fault log                       │
│    /map        — Leaflet GPS map with fault pins            │
│    /analytics  — Recharts time-series                       │
└─────────────────────────────────────────────────────────────┘
```

---

## Why Edge Inference (Not Cloud)

| Concern | Cloud Inference | Edge (ESP32) |
|---------|----------------|--------------|
| **Latency** | 200–800ms round-trip | **<100ms local** |
| **Network dependency** | Fails if WiFi drops | **Continues offline** |
| **Privacy** | Raw sensor stream leaves device | **Raw data never leaves node** |
| **Cost at scale** | API calls per inference | **Zero marginal cost** |

Real industrial systems (Siemens MindSphere, Bosch CTT, Honeywell Forge) all perform first-stage inference at the edge node and send only anomaly events — not raw streams — to the cloud. SentinelEdge mirrors this architecture.

---

## ML Pipeline

### Model Architecture

```
Input(42)
  └─→ Dense(32, ReLU)
        └─→ Dense(16, ReLU)
              └─→ Dense(4, Softmax)   ← 4 fault classes

Total parameters: 1,924
Post-int8 quantization size: ~8–12 KB
```

### Feature Extraction

Window: 200 samples (2s at 100Hz), 50% overlap → 1 inference/second

| Feature | Formula | Note |
|---------|---------|------|
| mean | Σx / N | Population |
| std | √(Σ(x-mean)² / N) | **ddof=0** — must match C++ |
| variance | Σ(x-mean)² / N | Population |
| rms | √(Σx² / N) | |
| peak\_to\_peak | max(x) − min(x) | |
| dominant\_freq\_bin | argmax(\|FFT(x)\|[1:N/2]) | 1-indexed, skip DC |
| spectral\_energy | Σ\|FFT(x)\|[1:N/2]² | Unnormalized, no windowing |

Total: 7 features × 6 axes = **42 features**

### Performance Metrics

| Metric | Target | Achieved |
|--------|--------|---------|
| Keras accuracy | >85% | *fill after training* |
| TFLite accuracy (int8) | >85% | *fill after training* |
| Keras→TFLite drop | <5pp | *fill after training* |
| False positive rate | <10% | *fill after training* |
| Model size | <100KB | *fill after training* |
| Est. SRAM (inference path) | <200KB | *fill after training* |
| Feature extraction latency | <30ms | *measure on hardware* |
| TFLite inference latency | <70ms | *measure on hardware* |
| Total pipeline latency | <100ms | *measure on hardware* |

> Run `ml/05_validate_tflite.py` — it prints all metrics and saves to `ml/models/model_report.json`.

### Fault Classes

| Class | Label | Physical Description |
|-------|-------|---------------------|
| 0 | Normal | Fan running cleanly. Low amplitude vibration (~0.1g), smooth 25Hz sine. |
| 1 | Imbalance | Mass imbalance (debris or coin on blade). High amplitude (~0.8g) at 25Hz. Centrifugal force at rotational frequency. |
| 2 | Obstruction | Physical contact against rotating assembly. Medium amplitude (~0.3g) + high-frequency random impulse transients. |
| 3 | Loose Mount | Fan on unstable surface. Medium amplitude (~0.5g), lower dominant frequency (~12Hz) with 2nd harmonic from chassis resonance. |

---

## Feature Drift Warning

The model trains on Python-computed features. The ESP32 C++ must compute **identical** values.

Run drift validation before deploying a retrained model:

```bash
# 1. Generate Python reference values
python ml/06_feature_drift_validation.py

# 2. Flash firmware with drift check enabled
# platformio.ini: build_flags = -D DRIFT_CHECK_ENABLED=1
pio run -e drift_check --target upload

# 3. Send 'd' via serial → ESP32 prints 42 features per class
# 4. Save to file, compare
python ml/06_feature_drift_validation.py --compare esp32_drift.txt
```

Maximum allowed deviation: **1% relative error** per feature.

Known drift sources:
- `std/variance`: Python uses ddof=0 (÷N). C++ must also divide by N.
- FFT windowing: arduinoFFT must use `FFT_WIN_TYP_RECTANGLE`.
- `dominant_freq_bin`: 1-indexed, skips DC bin 0.

---

## Hardware Bill of Materials

| Component | Spec | Approx. Cost (INR) |
|-----------|------|-------------------|
| ESP32 Dev Board | 38-pin, CP2102 USB | ₹350 |
| MPU6050 | I2C, ±2g–16g, ±250–2000°/s | ₹80 |
| DHT11 | Digital, ±2°C, ±5% RH | ₹60 |
| MQ5 | Analog gas sensor | ₹90 |
| NEO-6M GPS | UART, 9600 baud | ₹450 |
| Raspberry Pi 4 (2GB) | 64-bit, 4-core ARM | ₹5,500 |
| Breadboard + jumpers | Full-size | ₹150 |
| **Total** | | **~₹6,680** |

### Pin Assignments

```
MPU6050:  SDA → GPIO21    SCL → GPIO22
DHT11:    DATA → GPIO4
MQ5:      AOUT → GPIO34   (ADC1_CH6, input only)
NEO-6M:   TX → GPIO16     RX → GPIO17   (UART2)
```

---

## Quick Start

### Phase 1: ML Pipeline

```bash
cd sentineledge/ml
pip install numpy pandas scikit-learn tensorflow

python 01_generate_synthetic_data.py    # 24,000-row CSV
python 02_feature_engineering.py        # 42 features per window
python 03_train_model.py                # train + evaluate (>85% target)
python 04_convert_to_tflite.py          # int8 quantize + generate headers
python 05_validate_tflite.py            # verify <5% accuracy drop
```

This generates:
- `ml/models/fault_model.tflite`
- `firmware/src/model/fault_model.h`
- `firmware/src/model/model_settings.h`  (quantization params + scaler params)
- `ml/models/model_report.json`          (all metrics)

### Phase 2: ESP32 Firmware

```bash
# Install PlatformIO CLI or use VSCode extension
pip install platformio

cd sentineledge/firmware

# Edit src/main.cpp: set WIFI_SSID, WIFI_PASSWORD, MQTT_HOST
# Then flash:
pio run -e inference --target upload
pio device monitor --baud 115200
```

### Phase 3: Raspberry Pi Setup

```bash
# On Raspberry Pi:
sudo apt update && sudo apt install -y mosquitto mosquitto-clients

# Configure Mosquitto (see docs/setup_pi.md)
sudo systemctl enable mosquitto && sudo systemctl start mosquitto

cd sentineledge/backend
python -m venv venv && source venv/bin/activate
pip install -r requirements.txt

cp .env.example .env
# Edit .env with your Supabase, Groq, Telegram credentials

# Run Supabase schema
# (copy supabase_schema.sql → Supabase SQL Editor → Run)

python main.py  # test run

# Install as systemd service for auto-start:
sudo cp systemd/sentinel-backend.service /etc/systemd/system/
sudo systemctl enable sentinel-backend
sudo systemctl start sentinel-backend
```

### Phase 4: Dashboard

```bash
cd sentineledge/dashboard
cp .env.local.example .env.local
# Edit .env.local with your Supabase URL and anon key

npm run dev     # local development
# Deploy to Vercel:
npx vercel --prod
```

---

## Project Structure

```
sentineledge/
├── README.md
├── supabase_schema.sql
├── ml/
│   ├── feature_utils.py              ← canonical feature algorithm
│   ├── 01_generate_synthetic_data.py
│   ├── 02_feature_engineering.py
│   ├── 03_train_model.py
│   ├── 04_convert_to_tflite.py       ← generates firmware headers
│   ├── 05_validate_tflite.py         ← quantization accuracy gate
│   ├── 06_feature_drift_validation.py ← Python↔ESP32 parity check
│   ├── serial_logger.py              ← real data collection
│   ├── data/
│   └── models/
│       └── model_report.json
├── firmware/
│   ├── platformio.ini
│   └── src/
│       ├── main.cpp
│       ├── features.cpp / features.h
│       ├── mqtt_handler.cpp / mqtt_handler.h
│       └── model/
│           ├── fault_model.h         ← auto-generated
│           └── model_settings.h      ← auto-generated
├── backend/
│   ├── main.py         (FastAPI)
│   ├── mqtt_client.py  (paho + asyncio bridge)
│   ├── supabase_client.py
│   ├── groq_client.py
│   ├── telegram_client.py
│   ├── models.py / config.py
│   └── requirements.txt
└── dashboard/
    └── src/
        ├── app/
        │   ├── dashboard/page.tsx
        │   ├── anomalies/page.tsx
        │   ├── map/page.tsx
        │   └── analytics/page.tsx
        └── components/
            ├── DeviceStatus.tsx
            ├── LiveReadings.tsx
            ├── AnomalyFeed.tsx
            ├── AnomalyMap.tsx
            └── AnalyticsChart.tsx
```

---

## Resume Bullets

Fill in metrics after running on real hardware:

```
1. Deployed TensorFlow Lite Micro fault classification model on ESP32
   (520KB SRAM) achieving [X]% accuracy across 4 vibration fault classes
   with [Y]ms on-device inference latency — no cloud dependency for detection.

2. Architected 3-tier edge-gateway-cloud IoT pipeline: ESP32 TinyML inference
   → MQTT → Raspberry Pi FastAPI → Supabase, mirroring production industrial
   IoT topology used in smart manufacturing (Siemens MindSphere pattern).

3. Integrated Groq LLM (llama-3.3-70b-versatile) explanation layer generating
   actionable maintenance recommendations from anomaly context, delivered via
   Telegram with GPS fault location and [Y]ms on-device inference confidence score.
```

---

## Demo

*[Demo video link — add after recording]*

---

## Docs

- [Architecture details](docs/architecture.md)
- [Pi setup guide](docs/setup_pi.md)
- [ESP32 flash guide](docs/setup_esp32.md)
- [Real data collection protocol](docs/dataset_collection.md)
