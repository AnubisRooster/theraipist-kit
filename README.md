# OnDeviceKit

**OnDeviceKit** (ODK) — reusable Swift Package Manager components extracted from [therAIpist](https://github.com/AnubisRooster/therAIpist) (a private on-device iOS therapy companion app) and [CompyPal](https://github.com/AnubisRooster/CompyPal) (a sibling on-device AI companion app). These modules are domain-agnostic — nothing here is specific to therapy, journaling, or mental health — and are split out so other iOS/macOS projects can use them independently.

## Modules

### BYOKLLMKit

A "bring your own key" multi-provider LLM client. One `LLMSending` protocol, one `LLMService` actor implementation, routing to OpenRouter, OpenAI, Anthropic, DeepSeek, Groq, or Together AI based on a provider string — handling both the shared OpenAI-compatible chat-completions schema and Anthropic's distinct message schema. API keys are stored in the Keychain via `LLMKeychainStore`, never in `UserDefaults`.

```swift
import BYOKLLMKit

let keychain = LLMKeychainStore.shared
keychain.set("sk-...", for: .openai)

let llm = LLMService(keychain: keychain)
let reply = try await llm.sendMessage(
    provider: "openai",
    model: "gpt-4o-mini",
    messages: [LLMMessage(role: "user", content: "Hello!")]
)

// Or stream token-by-token (OpenAI-compatible providers only — throws
// .streamingNotSupported for Anthropic):
for try await delta in llm.streamMessage(provider: "openai", model: "gpt-4o-mini",
                                         messages: [LLMMessage(role: "user", content: "Hello!")]) {
    print(delta, terminator: "")
}
```

### VoiceLoopKit

A hands-free, continuous voice-conversation loop: listen → (natural pause) → hand off → speak → resume listening. Wraps `SFSpeechRecognizer` + `AVAudioEngine` with silence-based endpointing, and stitches long monologues across `SFSpeechRecognizer`'s ~1-minute segment cap. `SpeechService` wraps `AVSpeechSynthesizer` for the speaking half.

```swift
import VoiceLoopKit

let controller = VoiceConversationController(
    config: VoiceLoopConfig(silenceInterval: 4, ttsRate: 0.5)
)
controller.start()

// Observe `controller.pendingUtterance`, run your own reply pipeline,
// then hand the reply back:
controller.deliverResponse("Here's my reply.")
```

Also includes `ElevenLabsTTSEngine` and `OpenAITTSEngine`, two cloud-TTS alternatives to the on-device `SpeechService` (from [CompyPal](https://github.com/AnubisRooster/CompyPal)), and `PCMEnergyAnalyzer`, a pure utility that turns synthesized/recorded PCM audio into per-chunk amplitude "energies" for driving audio-reactive UI (waveform visualizers, lip-sync, speaking indicators) from any engine.

```swift
let tts = ElevenLabsTTSEngine()
tts.speak("Hello there!", voiceId: ElevenLabsTTSEngine.defaultVoiceId, modelId: "", apiKey: key,
          onStart: { energies, duration in /* drive a waveform/lip-sync view */ },
          onProgress: { range in /* highlight spoken text */ },
          completion: { },
          onError: { error in })

// Or OpenAI's TTS API — `speed` is applied server-side, unlike ElevenLabs's client-side `rate`:
let openaiTTS = OpenAITTSEngine()
openaiTTS.speak("Hello there!", voice: OpenAITTSEngine.defaultVoice, model: OpenAITTSEngine.defaultModel, apiKey: key,
                onStart: { energies, duration in /* drive a waveform/lip-sync view */ },
                onProgress: { range in /* highlight spoken text */ },
                completion: { },
                onError: { error in })
```

### PINLockKit

Keychain-backed PIN storage (`PINService`) plus a fully decoupled `PINLockout` state machine implementing escalating brute-force lockout (30s → 60s → 5m → 15m).

```swift
import PINLockKit

let pin = PINService()
pin.save("1234")

switch pin.attempt("0000") {
case .success: break
case .incorrect(let remaining): print("\(remaining) attempts left")
case .lockedOut(let seconds): print("locked for \(seconds)s")
}
```

### BiometricLockKit

A standalone Face ID / Touch ID / Optic ID unlock primitive over Apple's `LocalAuthentication`. It does **no** face matching itself — the camera, the neural match, and the biometric templates never leave the Secure Enclave; `BiometricService` only ever receives an opaque success/failure. Uses `.deviceOwnerAuthenticationWithBiometrics` (biometrics only, not the device passcode) so a failure routes to *your* fallback, plus a **domain-state anti-tamper check**: if someone enrolls a new face/finger in Settings, the next unlock returns `.biometryChanged` instead of `.success`.

The module owns no fallback UI and has **no dependency on `PINLockKit`** — any non-`.success` result is your cue to present a fallback (e.g. the `PINLockKit` screen).

> **Host requirement:** add an `NSFaceIDUsageDescription` string to your app's `Info.plist`, or Face ID evaluation crashes at runtime.

```swift
import BiometricLockKit

let biometrics = BiometricService()   // defaults: LAContext + Keychain baseline

switch await biometrics.unlock(reason: "Unlock your journal") {
case .success:
    openApp()

case .biometryChanged:
    // Enrolled biometrics changed since we last trusted this device.
    if presentPINScreenAndVerify() {          // your PINLockKit UI
        biometrics.acceptCurrentBiometry()    // re-baseline to the new set
        openApp()
    }

case .fallback, .lockout, .failed, .unavailable, .canceled:
    presentPINScreen()                        // your PINLockKit UI
}
```

Pairs with `PINLockKit`: treat biometrics as the fast path and the PIN as the always-present fallback (iOS *requires* a non-biometric path — it locks biometry after repeated failures). A ready-to-adapt composition of the two lives in [`Examples/AppLockCoordinator.swift`](Examples/AppLockCoordinator.swift) — kept out of the build so `BiometricLockKit` stays dependency-free. For the details behind `.biometryChanged` (and why an iOS upgrade can trigger it), see [`docs/biometric-domain-state.md`](docs/biometric-domain-state.md).

### ContentSafetyKit

Keyword-based crisis detection (`CrisisDetector`) and boundary-violation detection (`BoundaryDetector`) for assistant replies that must avoid diagnostic/prescriptive language. Both ship with sensible defaults and accept custom pattern lists.

```swift
import ContentSafetyKit

let crisis = CrisisDetector()
let result = crisis.check(userMessage)   // (isCrisis, level, pattern)

let boundary = BoundaryDetector()
let violation = boundary.check(replyText, context: .standard)
```

### GraphKit

Heuristic knowledge-graph extraction (`KnowledgeGraphExtractor`: emotions, people, and belief statements from free text, with edges wired between co-occurring entities) plus cross-session aggregation and export to Cytoscape/Neo4j JSON and GraphML (Gephi) via `GraphExporter`. Persistence-agnostic — pass your own node/edge value types via `SessionGraph`.

```swift
import GraphKit

let extraction = KnowledgeGraphExtractor().analyze("I feel anxious around my mother")
// extraction.nodes / extraction.edges — persist however you like

let graph = GraphExporter.aggregate(sessions: sessionGraphs)
let json = GraphExporter.cytoscapeJSON(graph: graph)
```

### AgentRouteKit

A generic confidence-scored routing primitive: register handlers that each report how confident they are about a context, and `Router` dispatches to the best match (with a fallback when nothing claims it).

```swift
import AgentRouteKit

let router = Router<String, String>(handlers: [myHandlerA, myHandlerB])
let output = await router.route(input, fallback: myDefaultHandler)
```

### GraphViewKit

An offline `WKWebView` wrapper (`GraphVisualizationView`) rendering a Cytoscape.js graph with no CDN/network dependency — a pinned Cytoscape.js build ships as a bundled SPM resource. Pairs naturally with `GraphKit`'s `GraphExporter.cytoscapeJSON(graph:)`. Also includes a thin `ShareSheet` wrapper for exporting the underlying GraphML/JSON files.

```swift
import GraphViewKit

GraphVisualizationView(cytoscapeJSON: json, onNodeTap: { tappedNodeID in
    // look up the tapped node in your own graph model
})
```

### LocalLLMKit

On-device GGUF inference via [LLM.swift](https://github.com/eastriverlee/LLM.swift) (a Swift wrapper around llama.cpp). `LocalLLMEngine` keeps a single model loaded, serializes concurrent load calls, races generation against a hard timeout, and picks the right chat template (Llama 3, Phi, Gemma, or a ChatML fallback) from the model ID. Depends on `BYOKLLMKit` for the shared `LLMMessage` type.

```swift
import LocalLLMKit
import BYOKLLMKit

let engine = LocalLLMEngine()
await engine.loadModel(id: "llama-3.2-1b", url: ggufFileURL)
let reply = try await engine.generate(
    modelID: "llama-3.2-1b",
    messages: [LLMMessage(role: "user", content: "Hello!")]
)
```

### ModelCatalogKit

Live model catalog fetching, TTL disk caching, and cost-first selection for OpenAI-compatible provider APIs — ported from [CompyPal](https://github.com/AnubisRooster/CompyPal). Instead of hardcoding a model ID, fetch the provider's live catalog and let `SelectionPolicy` rank it: free models first, then cheapest-paid, with an optional pinned override. Pairs naturally with `BYOKLLMKit` — pass the winning `CatalogEntry.id` as the `model:` argument.

```swift
import ModelCatalogKit

let fetcher = CatalogFetcher()          // defaults to OpenRouter's API
let cache = CatalogCache()
if await cache.isStale() {
    let entries = try await fetcher.fetch(apiKey: key)
    try await cache.save(entries: entries)
}
let catalog = (await cache.load())?.entries ?? []

let policy = SelectionPolicy(role: .chat, catalog: catalog, pinnedModelId: nil)
let candidates = policy.rank()   // walk this list for 429/5xx fallback rotation
```

## Requirements

- iOS 17+ (all modules currently require iOS — `VoiceLoopKit` depends on `Speech`/`AVAudioSession`, which don't exist on macOS)
- Swift 5.9+

## Installation

Add via Swift Package Manager:

```swift
.package(url: "https://github.com/AnubisRooster/OnDeviceKit", from: "0.1.0")
```

Then depend on whichever product(s) you need — `BYOKLLMKit`, `VoiceLoopKit`, `PINLockKit`, `BiometricLockKit`, `ContentSafetyKit`, `GraphKit`, `AgentRouteKit`, `GraphViewKit`, `LocalLLMKit`, `ModelCatalogKit` — in your target.

### Repository structure

Each module also lives as its own standalone package under `Packages/<Name>/` — own `Package.swift`, own `Sources/`, own `Tests/`, declaring only *that module's* actual dependencies (e.g. `Packages/PINLockKit` has none; `Packages/LocalLLMKit` depends on `../BYOKLLMKit` locally plus `LLM.swift`). The root `Package.swift` is an umbrella manifest whose targets point at those same source directories, so remote consumers get the exact experience above — pick any product(s) from one `.package(url:)` — while local development, standalone testing, or lifting a single module into its own repo can all be done directly from its `Packages/<Name>/` folder without touching anything else.

## Status

Early extraction — API surface may still shift before `1.0`. All modules planned from the initial [therAIpist](https://github.com/AnubisRooster/therAIpist) review are present, plus `ModelCatalogKit`, streaming support in `BYOKLLMKit`, and `ElevenLabsTTSEngine`/`PCMEnergyAnalyzer` in `VoiceLoopKit`, ported from a comparison against [CompyPal](https://github.com/AnubisRooster/CompyPal), plus `OpenAITTSEngine` as a second cloud-TTS option.

## License

Apache License 2.0 — see [LICENSE](LICENSE).
