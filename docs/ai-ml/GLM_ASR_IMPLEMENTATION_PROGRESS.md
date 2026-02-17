# GLM-ASR Implementation Progress Tracker

**Purpose:** Track implementation progress for GLM-ASR-Nano STT service integration.

**Related Documents:**
- `GLM_ASR_NANO_2512.md` - Model evaluation and integration roadmap
- `GLM_ASR_SERVER_TRD.md` - Server technical requirements document
- `GLM_ASR_ON_DEVICE_GUIDE.md` - On-device implementation guide

**Last Updated:** December 2025

---

## Implementation Status

| Phase | Component | Status | Notes |
|-------|-----------|--------|-------|
| **Phase 1: Tests** | Unit Tests - GLMASRSTTService | 🟢 Complete | 12 tests |
| | Unit Tests - GLMASRHealthMonitor | 🟢 Complete | 11 tests |
| | Unit Tests - STTProviderRouter | 🟢 Complete | 10 tests |
| | Unit Tests - Audio Conversion | 🟢 Complete | Included in STTService tests |
| | Integration Tests | 🟢 Complete | 7 tests (require server) |
| **Phase 2: Server Implementation** | GLMASRSTTService | 🟢 Complete | ~400 lines |
| | GLMASRHealthMonitor | 🟢 Complete | ~150 lines |
| | STTProviderRouter | 🟢 Complete | ~200 lines |
| | STTProvider enum update | 🟢 Complete | Added glmASRNano case |
| **Phase 3: On-Device Implementation** | GLMASROnDeviceSTTService | 🔄 Needs Rework | Original CoreML + llama.cpp approach |
| | CoreML Model Integration | ❌ Deprecated | Multi-component pipeline replaced by unified GGUF |
| | llama.cpp Text Decoder | 🔄 Needs Rework | Unified GGUF replaces decoder-only approach |
| | Simulator Support | 🟢 Complete | Enabled when models present |
| **Phase 4: Integration** | CI Workflow update | 🟢 Complete | Auto-picks up new tests |
| | Documentation update | 🟢 Complete | Full documentation |
| | Final verification | 🟢 Complete | `swift build` succeeds |

| **Phase 5: Updated On-Device (Feb 2026)** | Unified GGUF approach | 🟡 In Progress | Single Q4_K_M file (~1.06GB) |
| | llama.cpp wrapper update | ⏸️ Blocked | StanfordBDHG v0.3.3 predates audio support (PRs #17901, #18142) |
| | Audio pipeline via libmtmd | ⏸️ Blocked | Depends on wrapper update |
| | Updated unit tests (TDD) | 🟡 In Progress | GLMASROnDeviceConfigurationTests added |
| | Server backend update | 🟡 In Progress | Adding SGLang, transformers 5.0 |

**Legend:** 🔴 Not Started | 🟡 In Progress | 🟢 Complete | ⏸️ Blocked | 🔄 Needs Rework | ❌ Deprecated

---

## Files Created/Modified

### New Files - Server Implementation

| File | Purpose | Lines |
|------|---------|-------|
| `UnaMentis/Services/STT/GLMASRSTTService.swift` | Server-based STT service | ~400 |
| `UnaMentis/Services/STT/GLMASRHealthMonitor.swift` | Server health monitoring | ~150 |
| `UnaMentis/Services/STT/STTProviderRouter.swift` | Provider routing with failover | ~200 |
| `UnaMentisTests/Unit/Services/GLMASRSTTServiceTests.swift` | Unit tests for service | ~250 |
| `UnaMentisTests/Unit/Services/GLMASRHealthMonitorTests.swift` | Unit tests for health monitor | ~200 |
| `UnaMentisTests/Unit/Services/STTProviderRouterTests.swift` | Unit tests for router | ~300 |
| `UnaMentisTests/Integration/GLMASRIntegrationTests.swift` | Integration tests | ~250 |

### New Files - On-Device Implementation

| File | Purpose | Lines |
|------|---------|-------|
| `UnaMentis/Services/STT/GLMASROnDeviceSTTService.swift` | On-device STT with CoreML + llama.cpp | ~600 |

### New Documentation

| File | Purpose |
|------|---------|
| `docs/ai-ml/GLM_ASR_ON_DEVICE_GUIDE.md` | Complete on-device setup and usage guide |

### Modified Files

| File | Changes |
|------|---------|
| `UnaMentis/Services/Protocols/STTService.swift` | Added `glmASRNano` to `STTProvider` enum, cost info |
| `Package.swift` | Added llama.cpp dependency, C++ interop settings |
| `UnaMentis/Core/Persistence/ManagedObjects/*.swift` | Manual NSManagedObject subclasses for SPM |
| `UnaMentis/UnaMentis.xcdatamodeld` | Changed codegen to manual/none |

---

## Test Coverage

### Unit Tests

| Test Class | Tests | Coverage |
|------------|-------|----------|
| `GLMASRSTTServiceTests` | 12 | Configuration, format validation, message parsing, audio conversion |
| `GLMASRHealthMonitorTests` | 11 | State transitions, thresholds, monitoring lifecycle |
| `STTProviderRouterTests` | 10 | Provider selection, failover, recovery |

### Integration Tests

| Test Class | Tests | Coverage |
|------------|-------|----------|
| `GLMASRIntegrationTests` | 7 | Connection, transcription, lifecycle, concurrency |

**Note:** Integration tests require `GLM_ASR_SERVER_URL` environment variable to run.

---

## Architecture Summary

```
┌─────────────────────────────────────────────────────────────────┐
│                     STTProviderRouter                            │
│  ┌──────────────────────────┬─────────────────────────────────┐ │
│  │                          │                                 │ │
│  ▼                          ▼                                 │ │
│ GLMASRSTTService     DeepgramSTTService                      │ │
│ (Primary)            (Fallback)                               │ │
│  │                                                            │ │
│  └─────────── GLMASRHealthMonitor ────────────────────────────┘ │
│                (Status: healthy/degraded/unhealthy)             │
└─────────────────────────────────────────────────────────────────┘
```

### Key Components

1. **GLMASRSTTService** - WebSocket-based STT service
   - Connects to self-hosted GLM-ASR-Nano server
   - 16kHz mono PCM audio input
   - Streaming transcription with interim results
   - Automatic reconnection with exponential backoff

2. **GLMASRHealthMonitor** - Server health monitoring
   - Periodic HTTP health checks
   - State machine: healthy → degraded → unhealthy
   - Configurable thresholds

3. **STTProviderRouter** - Intelligent routing
   - Routes to GLM-ASR when healthy
   - Automatic failover to Deepgram when unhealthy
   - Recovery back to GLM-ASR when restored

---

## Configuration

### Environment Variables

| Variable | Purpose | Required |
|----------|---------|----------|
| `GLM_ASR_SERVER_URL` | WebSocket URL for GLM-ASR server | Yes |
| `GLM_ASR_AUTH_TOKEN` | Optional authentication token | No |
| `GLM_ASR_HEALTH_URL` | HTTP health check endpoint | No (defaults to /health) |

### Default Configuration

```swift
GLMASRSTTService.Configuration.default
- serverURL: from GLM_ASR_SERVER_URL env
- language: "auto"
- interimResults: true
- punctuate: true
- reconnectAttempts: 3
- reconnectDelayMs: 1000

GLMASRHealthMonitor.Configuration.default
- checkIntervalSeconds: 30
- unhealthyThreshold: 3
- healthyThreshold: 2
```

---

## Usage Example

```swift
// Initialize services
let telemetry = TelemetryEngine()

let glmASR = GLMASRSTTService(
    configuration: .default,
    telemetry: telemetry
)

let deepgram = DeepgramSTTService(apiKey: "...")

let healthMonitor = GLMASRHealthMonitor(configuration: .default)

// Create router
let router = STTProviderRouter(
    glmASRService: glmASR,
    deepgramService: deepgram,
    healthMonitor: healthMonitor
)

// Use router as your STT service
let format = AVAudioFormat(standardFormatWithSampleRate: 16000, channels: 1)!
let results = try await router.startStreaming(audioFormat: format)

for await result in results {
    print("Transcript: \(result.transcript)")
    if result.isFinal {
        break
    }
}
```

---

## Detailed Task Breakdown (Completed)

### Phase 1: Tests (TDD Approach)

#### 1.1 GLMASRSTTService Unit Tests
**File:** `UnaMentisTests/Unit/Services/GLMASRSTTServiceTests.swift`

- [x] Test audio format validation (16kHz mono required)
- [x] Test audio buffer conversion (Float32 → Int16 PCM)
- [x] Test WebSocket message parsing (partial results)
- [x] Test WebSocket message parsing (final results)
- [x] Test error message parsing
- [x] Test connection state management
- [x] Test configuration validation
- [x] Test costPerHour returns 0 (self-hosted)
- [x] Test metrics tracking

#### 1.2 GLMASRHealthMonitor Unit Tests
**File:** `UnaMentisTests/Unit/Services/GLMASRHealthMonitorTests.swift`

- [x] Test health check success path
- [x] Test health check failure path
- [x] Test consecutive failures trigger unhealthy status
- [x] Test consecutive successes restore healthy status
- [x] Test degraded state transitions
- [x] Test configuration validation
- [x] Test monitoring start/stop

#### 1.3 STTProviderRouter Unit Tests
**File:** `UnaMentisTests/Unit/Services/STTProviderRouterTests.swift`

- [x] Test routes to GLM-ASR when healthy
- [x] Test fails over to Deepgram when unhealthy
- [x] Test returns to GLM-ASR when recovered
- [x] Test metrics passthrough
- [x] Test cost passthrough

#### 1.4 Integration Tests
**File:** `UnaMentisTests/Integration/GLMASRIntegrationTests.swift`

- [x] Test connection to server
- [x] Test end-to-end transcription (requires server)
- [x] Test streaming session lifecycle
- [x] Test concurrent sessions
- [x] Test latency metrics

### Phase 2: Implementation

#### 2.1 GLMASRSTTService
**File:** `UnaMentis/Services/STT/GLMASRSTTService.swift`

- [x] Configuration struct with all parameters
- [x] WebSocket connection management
- [x] Audio format conversion (toGLMASRPCMData)
- [x] Message sending (binary audio)
- [x] Message receiving and parsing
- [x] Result streaming via AsyncStream
- [x] Reconnection with exponential backoff
- [x] Cleanup and resource management
- [x] Message parser utility

#### 2.2 GLMASRHealthMonitor
**File:** `UnaMentis/Services/STT/GLMASRHealthMonitor.swift`

- [x] Configuration struct
- [x] Health check HTTP request
- [x] State machine (healthy/degraded/unhealthy)
- [x] Monitoring loop with configurable interval
- [x] Status stream via AsyncStream

#### 2.3 STTProviderRouter
**File:** `UnaMentis/Services/STT/STTProviderRouter.swift`

- [x] Provider selection logic
- [x] Health monitoring integration
- [x] Automatic failover
- [x] STTService protocol conformance

#### 2.4 STTProvider Enum Update
**File:** `UnaMentis/Services/Protocols/STTService.swift`

- [x] Add `.glmASRNano` case
- [x] Add display name and identifier
- [x] Add costPerHour property
- [x] Add isSelfHosted property

---

## On-Device Architecture

```
┌─────────────────────────────────────────────────────────────────┐
│               GLMASROnDeviceSTTService Pipeline                 │
├─────────────────────────────────────────────────────────────────┤
│                                                                 │
│  Audio Input (16kHz PCM)                                        │
│       │                                                         │
│       ▼                                                         │
│  ┌─────────────────────────────────────────┐                   │
│  │     GLMASRWhisperEncoder (CoreML)       │ 1.2 GB            │
│  └─────────────────────────────────────────┘                   │
│       │                                                         │
│       ▼                                                         │
│  ┌─────────────────────────────────────────┐                   │
│  │     GLMASRAudioAdapter (CoreML)         │ 56 MB             │
│  └─────────────────────────────────────────┘                   │
│       │                                                         │
│       ▼                                                         │
│  ┌─────────────────────────────────────────┐                   │
│  │     GLMASREmbedHead (CoreML)            │ 232 MB            │
│  └─────────────────────────────────────────┘                   │
│       │                                                         │
│       ▼                                                         │
│  ┌─────────────────────────────────────────┐                   │
│  │     GLM-4 Decoder (llama.cpp Q4_K_M)    │ 935 MB            │
│  └─────────────────────────────────────────┘                   │
│       │                                                         │
│       ▼                                                         │
│  Transcribed Text                                               │
│                                                                 │
└─────────────────────────────────────────────────────────────────┘

Total Model Size: ~2.4 GB
Supported Devices: iPhone 15 Pro+ (8GB+ RAM)
Optimal Device: iPhone 17 Pro Max (12GB RAM)
```

---

## Next Steps (Production)

### Server Deployment (Optional)

1. **Server Deployment**
   - [ ] Set up GPU server (RunPod/AWS/GCP)
   - [ ] Deploy vLLM with GLM-ASR-Nano model
   - [ ] Configure TLS/SSL certificates
   - [ ] Set up monitoring (Prometheus/Grafana)

### On-Device Setup (Required for Local Testing)

1. **Model Files**
   - [ ] Download models from Hugging Face (~2.4GB)
   - [ ] Place in `models/glm-asr-nano/`
   - [ ] Add to Xcode target (Copy Bundle Resources)

2. **Testing**
   - [ ] Test on physical iPhone 15 Pro or later
   - [ ] Profile performance and latency
   - [ ] Verify thermal management under load

---

## Session Log

### Session 1 - December 2025
- Created implementation progress tracker
- Wrote all unit tests (TDD approach)
- Implemented GLMASRSTTService, GLMASRHealthMonitor, STTProviderRouter
- Updated STTProvider enum with glmASRNano case
- Wrote integration tests
- Updated documentation

### Session 2 - December 2025
- Implemented GLMASROnDeviceSTTService
- Added CoreML model integration (Whisper encoder, adapter, embed head)
- Integrated llama.cpp for text decoding
- Fixed Core Data SPM compatibility (manual NSManagedObject subclasses)
- Fixed macOS API compatibility (#if os(iOS) guards)
- Enabled simulator support when models present
- Created comprehensive on-device guide
- Updated all documentation

### Session 3 - February 2026
- Discovered Z.AI updated model weights on Dec 27, 2025 for transformers 5.0.0 and SGLang compatibility
- Identified that the original multi-component CoreML pipeline is no longer the correct approach
- Community GGUF available at Mungert/GLM-ASR-Nano-2512-GGUF with Q4_K_M at ~1.06GB (vs ~2.4GB multi-component)
- Actual BF16 safetensors weight is 4.52GB (not ~3.0GB as originally estimated)
- Confirmed SGLang dev Docker as the recommended inference backend
- vLLM now requires transformers >= 5.0.0 (dev install from source)
- StanfordBDHG/llama.cpp v0.3.3 predates upstream audio support (PRs #17901, #18142), blocking on-device inference
- Revised on-device architecture to unified GGUF via llama.cpp libmtmd
- Added GLMASROnDeviceConfigurationTests.swift (TDD for new architecture)
- Updated all GLM-ASR documentation to reflect current state

---

## How to Resume Work

1. Check this document for current status
2. Run build to verify compilation: `swift build`
3. Run tests to verify passing: `swift test`
4. For on-device testing: See `GLM_ASR_ON_DEVICE_GUIDE.md`

---

*Last Updated: December 2025*
