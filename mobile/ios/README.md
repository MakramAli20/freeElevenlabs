# VoiceStudio for iOS

Native SwiftUI app for iOS 17+, iPhone and iPad. Speak, voice cloning, Dictate and dubbing run downloaded models on the phone, offline. Pairing a VoiceStudio computer is optional and adds its engines. Every task remembers its own phone/computer choice; the segmented control appears only while paired. All five tabs work without pairing. Settings contains Connect and Models.
## Build and checks

Swift 6 Command Line Tools, Python 3.9+ and CMake run the macOS package checks. XcodeGen 2.46 generates the app project. Full Xcode with the iOS SDK is required for the app, native xcframeworks and UI tests. Device signing uses your own development team. The root `package.json` supplies the app version; there is no mobile version mirror.

Run from the repository root:

```sh
mobile/ios/scripts/check-swift.sh build
mobile/ios/scripts/check-swift.sh test
mobile/ios/scripts/check-platform.sh
python3 mobile/ios/scripts/prepare_resources.py \
  --output mobile/ios/.generated/bundle \
  --info-output mobile/ios/.generated/Info.plist
python3 mobile/ios/scripts/test_resources.py
swiftc -frontend -parse mobile/ios/VoiceStudio/App/*.swift \
  mobile/ios/VoiceStudio/Features/*.swift mobile/ios/VoiceStudio/Platform/*.swift \
  mobile/ios/VoiceStudioUITests/*.swift
```

`check-swift.sh` keeps build/module caches inside `mobile/ios/` and supplies the installed Testing.framework on CLT-only installations. Package tests do not download models. The optional `VOICESTUDIO_SWIFT_SCRATCH` selects a separate scratch directory. `check-platform.sh` type-checks the production host media loader, smoke transport and phone model coordinator against macOS; it does not compile SwiftUI/UIKit.

Explicit preparation and real inference (model terms are printed; test acceptance stays in the isolated fixture store):

```sh
mobile/native/ios/build.sh macos-runtimes
python3 mobile/ios/scripts/fetch-smoke-models.py --accept-test-licences
mobile/ios/scripts/real-inference.sh
mobile/ios/scripts/native-load-test.sh
# Cloning, translation, phone voice creation and complete phone audio dubbing:
python3 mobile/ios/scripts/fetch-smoke-models.py --accept-test-licences --extended
mobile/ios/scripts/auxiliary-inference.sh
```

The smoke fetcher verifies every file's size and SHA-256 from the actual shared catalogue, then stores files under ignored `.cache/inference-models/`. Inference tests themselves use only these local files. Kitten produces actual audio, Whisper transcribes it back, and Zipformer emits incremental and final text. The same smoke cancels real TTS after observing native progress. The auxiliary script runs three real native workflows sequentially to limit peak memory: OmniVoice/Qwen adapters, phone reference creation through ASR followed by cloned Speak, and the full Whisper → Qwen → OmniVoice audio dub pipeline with verified export and completed-checkpoint resume. These tests do not grant acceptance in the app's model store.

With full Xcode, prepare the native frameworks before generating or building the app:

```sh
mobile/native/ios/build.sh ios
xcodegen generate --spec mobile/ios/VoiceStudio/project.yml
xcodebuild -project mobile/ios/VoiceStudio/VoiceStudio.xcodeproj \
  -scheme VoiceStudio -sdk iphonesimulator -destination 'generic/platform=iOS Simulator' \
  CODE_SIGNING_ALLOWED=NO build
xcodebuild -project mobile/ios/VoiceStudio/VoiceStudio.xcodeproj \
  -scheme VoiceStudio -destination 'platform=iOS Simulator,name=iPhone 16' test
```

Choose an installed simulator name. The native build verifies pinned artifacts, builds missing simulator slices and exposes the frameworks expected by `project.yml`; see `mobile/native/ios/README.md` for integrity details and transitive checksum limits. No native libraries or model binaries are committed.

## Phone inference and models

`VoiceStudioKit/LocalEngine` is the single feature-facing interface: synthesize, clone, transcribe, streamTranscribe and translate. C runtime handles remain on detached workers; an atomic cancellation token crosses tasks. TTS uses sherpa Kitten/Kokoro, offline ASR uses Whisper, and streaming ASR uses the catalogue's Zipformer family. Streaming preserves endpoint finals, produces a final session transcript and rejects sample-rate changes. Whisper handles long input in 20-second windows while reusing the recognizer. Its native decode has no abort callback: cancellation is checked between windows and the current decode must return before cleanup. TTS and OmniVoice cancel through their native callbacks; llama checks between tokens and through its CPU abort callback. Progress reports loading/running/finished; native APIs without fractional callbacks remain indeterminate during the current step. Every locally generated WAV passes `markSynthetic`, which adds a synthetic-audio INFO comment.

Speak, clone, Dictate and Dub remember independent This phone / Computer choices. Without a choice, a compatible installed and accepted phone model wins; otherwise a paired computer wins; otherwise a compact download card offers Get and links to Models. A remembered computer choice falls back to the phone or Models prompt while unpaired, matching Android, and applies again after pairing. Speak offers three compact pickers (voice, model, language), a text box, Generate and the existing playback, waveform, seeking, sharing and saving controls. Its phone voice picker includes presets and saved references; reference voices select OmniVoice rather than preset TTS. Phone generations persist locally and can be played or deleted in Recent. Dictate captures mono PCM16 at 16 kHz and sends it directly to `LocalEngine` on the phone route. Neither phone path requires a computer or makes a network request.

Models decodes the generated `mobile/contract/models.json`, bundled at build time alongside the locale catalogs. Unknown fields are ignored. Missing or blank product names, invalid revisions, hashes, unsafe file paths, sizes, duplicate IDs and runtime/capability mismatches are rejected. Cards show product name, size, localized capability and one Download/Cancel/Delete action. Feature screens and model cards hide IDs, repository names and licence codes; licence details are in the acceptance sheet. Languages, licence terms and per-model storage are in the licence sheet. Unsupported RAM requirements stay visible with an explanation and cannot download or load. Models has Download, Cancel, Delete, a total storage counter and an explicit mobile-data toggle.

Downloads start only from a user action. Four-MiB HTTP ranges persist across cancellation and relaunch; servers ignoring ranges can return a complete file. Hugging Face is attempted first, then hf-mirror.com. A dedicated cookie/credential-free session permits only HTTPS HF/mirror delivery domains (including signed HF CDN redirects); host credentials and referrers are never forwarded. Wi-Fi-only is enforced by both the local path check and URLSession's cellular/expensive-network policy unless mobile data was allowed. Files stay under private Application Support, excluded from backup. Each file is size/SHA-256 verified before installation and hashed again before native loading. Active leases prevent delete/replacement during inference. Downloads interrupted by suspension resume from persisted ranges when the user starts them again; continuous background model downloading is not promised.

Every non-commercial, conditional, unidentified or explicitly gated model requires acceptance before download and load. The phone shows all supplied licence metadata and full catalogue terms, records the supplied terms fingerprint, actual app version and time, and retains the latest 20 actions locally. Changed terms block loading again; withdrawal immediately blocks new use and downloads. Acceptance is independent of the computer. Delete removes weights and partial files, preserving licence history.

OmniVoice's `tokenizer` role is its audio codec. The clone adapter takes mono 24-kHz reference audio plus its transcript. Translation uses the catalogue's prompt template and a bounded 2,048-token context. All features call this boundary; screens never invoke C runtimes directly.

## Phone voices and dubbing

Voices lists phone and computer voices together, with initials, a location badge, preview and rename/delete actions. The toolbar plus opens cloning: name, consent, record or pick a sample, Create clone. The consent details are behind an info button. Phone creation requires a downloaded, accepted Whisper model; it extracts mono 24-kHz reference audio (0.1–30 seconds), transcribes it and atomically publishes reference PCM/WAV plus transcript, creation time and consent time in private, backup-excluded storage. Empty speech and cancelled creation never publish a voice. Recording stops at 30 seconds. OmniVoice must be downloaded and accepted before Speak can synthesize with that reference. Renaming/deleting a phone voice never changes a computer voice.

Phone Dub follows Source → Languages → Voice. Pick a local audio/video file, choose up to 20 target languages and either the original speaker or a saved phone voice, give voice permission and tap Dub. More contains model choices and audio-only export. Pasted links remain a computer workflow: phone processing never fetches media from a URL. The three required models (Whisper, Qwen translation and OmniVoice) must be installed, fit the device and have current licence acceptance.

Extraction uses AVAssetReader with 24-kHz mono PCM, preserving gaps and soundtrack offsets. Uncompressed audio files use AVAudioFile/AVAudioConverter to stream and resample directly without a media-reader service. A disk-backed pipeline bounds native ASR input to 20 seconds; sherpa token timestamps define each window's speech envelope (falling back to the window duration when unavailable), matching Android. Each segment is translated with the catalogue prompt and cloned from at most eight seconds cut from the source; the reference clip gets its own matching ASR transcript. A chosen saved voice supplies its reference and transcript instead. Short speech is padded, long speech is compressed by waveform overlap-add, segments are mixed at their timestamps and clipped to the original duration. Tiny windows use interpolation. WAV output passes `markSynthetic`; video uses AVAssetWriter to retain the original video/rotation and replace the soundtrack with AAC, with synthetic provenance in MP4 metadata. The original music is not retained as a separate stem.

Progress cards show stage, percent and Cancel. Backgrounding cancels ongoing work; Whisper's current native decode must finish before cancellation returns. Sources, exact model identities (including terms/configuration), original PCM, segment translations, reference transcripts, render hashes and outputs are checkpointed atomically under private storage. Resume on a pending card continues after interruption/relaunch without translating or mixing completed segments twice. Corrupt cached renders are rebuilt; corrupt completed outputs and changed catalogue identities are blocked. Licence permission is rechecked between stages and by each native load. Multiple target outputs commit separately. Phone history plays video/audio, shares, saves via the system document picker and deletes completed jobs. Completed phone dubs use the same opt-in local notifications setting as computer dubs. Pending jobs can also be deleted when idle. Deleting a job removes its source, checkpoints and outputs; files are retained until explicit deletion. Media is bounded to four hours, references to 30 seconds, and ASR state to 10,000 segments.

The screen layout uses short labels and semantic icons with one primary action, compact history rows, a round dictation microphone, expandable manual pairing and grouped Settings rows. Each feature has one compact missing-model card: product name and size for one model, or feature, count and combined size for several. Get starts the required downloads and presents separate unchecked acceptance sheets for every gated model; declining or dismissing stops the remaining queue. Already installed models are not downloaded again after acceptance. Tap the card label or Settings → Models to manage models. Clone model selection is under More. Pickers mark their current selection; palettes show token-based color swatches and normal text colors. Dictate copy/share controls sit above the tab bar in a bottom safe-area inset. Explanations and privacy details are in info sheets; full legal terms remain visible in licence sheets.

The app icon and launch logo are generated from `docs/logo.png` by `scripts/generate-brand-assets.swift` through `prepare_resources.py`. The icon is opaque; its canvas and the light/dark launch background come from shared tokens. XcodeGen prepares the ignored asset catalog before discovering resources, and each app build refreshes it. No generated artwork is committed. First-run consent says the choice is saved on this phone and sends nothing.

## Computer workflows

Connect accepts the desktop Network QR or manual URL/PIN/API key. Health validation rejects unrelated services. API keys are exchanged once for bearer sessions and never saved. Keychain uses `AfterFirstUnlockThisDeviceOnly`; host metadata and job checkpoints use local preferences. PIN-only pairing authorizes HTTP consumption, not remote dictation. Disconnect revokes bearer sessions and clears local credentials even when the host is unavailable. Failed pairing preserves the current host; host changes cancel old operations and clear host-scoped media/data. Redirects are rejected for every paired-host request. Public hosts require HTTPS and system certificate validation; private/LAN/Tailnet hosts may use HTTP.

Computer Speak retains engine/language/profile choices, generation, authenticated playback, waveform/seeking, sharing/saving and history star/delete. Voices retains search, previews, consent-gated recording/file cloning, rename and delete. Dub retains device file/URL ingest, multiple target tracks, voice selection, persisted upload/job monitoring, abort/history/download/share and completion notifications. Computer Dictate uses authenticated WebSocket tickets, PCM16/16 kHz and EOF finalization. Remote or undiscoverable LLM translation destinations require equal-weight consent per host/job/provider; only verified host-loopback endpoints avoid this prompt.

Background URLSession persists computer uploads and completion receipts through relaunch. A refused background session falls back to a foreground transfer with retained staging; that fallback needs app runtime. BGProcessing monitoring is opportunistic and resumes at the next foreground/granted runtime; there is no push relay or guarantee while force-quit. Original media filenames persist through picker display, multipart staging, checkpoints and history. The host pipeline follows upload/ingest → prep events → transcribe → translate → generate → render events; backend task IDs and dub media job IDs are distinct. A crash between host acceptance and client checkpoint persistence can require host inspection before retrying because render has no client idempotency key.

## Resources, privacy and accessibility

Theme roles are generated from Electron; never edit `Tokens.generated.swift`. The maintainer regenerates shared inputs with `bun scripts/export-mobile-tokens.ts`, `uv run python scripts/export_openapi.py` and `uv run python scripts/export_mobile_models.py`. These affect both platforms and are not iOS build steps. Resource preparation copies the actual Electron catalogs, shared/platform mobile additions, desktop language catalog and models catalogue. On-device screens use the canonical `mobile/contract/strings.mobile.en.json` keys; iOS needs no platform additions. Active-work errors reuse the desktop wait message. The microphone permission prompt combines the desktop microphone reason with the shared phone/computer privacy notice. Licence codes, categories, credits, terms and fingerprints appear only in the licence sheet, matching Android. Localization supports interpolation, plurals, language/English fallback and Chinese script/region selection. Package checks cover source key availability and reject platform overrides of shared strings.

Settings, appearance and language work without pairing. Permissions are requested at first use. No analytics SDK, push service, Bonjour discovery, account or crash reporter is linked; analytics consent records only a local preference. On-device tasks send nothing; networking is limited to explicitly started model downloads and paired-host requests. Inter and the app/runtime licences are shown under About. All colors come from theme tokens; controls use Dynamic Type, minimum 44-point targets, scrollable layouts and localized accessibility labels.

## Verification limits and interpretations

Verified with CLT: the strict Swift 6 package suite, macOS platform-wrapper type-checks, resource generation, XcodeGen generation and app/UI-test syntax parsing. Separate opt-in runs exercise all three actual native libraries, Kitten/Whisper/Zipformer inference, phone reference creation and cloned Speak, and the complete audio dub workflow with native translation/cloning and checkpoint reuse. The complete native dub smoke currently fails its French-output assertion on a misrecognized tiny Whisper transcript; audio export and checkpoint reuse pass. Clean English translation, voice creation and cloned Speak pass. The tiny Zipformer recognizes the ending phrase of the synthetic smoke sentence; this is an inference check, not a transcription-accuracy claim.

`VoiceStudioUITests/PhoneScreens.swift` covers unpaired screens, compact download cards, product names, licence consent, picker selection, dictation action placement and collapsed details; `ScreenshotTour` captures phone and computer screens plus palette/language pickers as retained Xcode test attachments. These tests are authored, not run on this CLT-only host. The iOS xcframework build/link, SwiftUI compilation, simulator UI tests, physical-device model RAM/thermal behavior, download/cellular transitions, microphone/local-network/QR permissions, VoiceOver/largest Dynamic Type, signing, background uploads and real-host end-to-end workflows require full Xcode/device validation. macOS inference does not prove iOS execution.

Contract interpretations: Get starts a queue with separate per-model acceptance; declining or dismissing stops the unstarted remainder while already authorized transfers continue. The compact card links to Models through its label. The optional catalogue `licence.terms` contains the full disclosure and is displayed when supplied; the fingerprint remains catalogue-authoritative. HF's signed delivery CDNs are allowed only within its HF-owned delivery domains, because normal model resolve URLs redirect there. Downloads resume at verified range boundaries rather than URLSession opaque resume blobs. The pinned llama prebuilt lacks a simulator slice, so that slice is built from the same pinned source. Missing transitive SHA-256 fields in shared pins are documented in the native README. For dubbing, “segments + timestamps” means one timed speech envelope per bounded Whisper window, matching Android; it does not imply diarization. A remembered computer route falls back while unpaired because its segmented control is hidden. A cancelled dub stays resumable; deletion is explicit. iOS background resume is a user-started Resume after foregrounding, not guaranteed background compute. Video mux and compressed-source extraction need full Xcode/device validation; macOS audio tests exercise the real uncompressed-file conversion and export paths.
