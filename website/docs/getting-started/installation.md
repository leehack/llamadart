---
title: Install llamadart
sidebar_label: Installation
description: Add llamadart to a Dart or Flutter app, set up Apple and web targets, verify the install, and customize the prebuilt native runtimes.
---

For Genkit or Flutter Edge AI integration setup, see
[Choose an integration](../integrations/choosing-an-api).

## Requirements

- Dart SDK `>= 3.10.7`
- Flutter SDK `>= 3.38.0` (if you build Flutter apps)
- Flutter iOS apps: deployment target `16.4` or newer
- Flutter macOS apps: deployment target `14.0` or newer
- Windows: nothing extra for llama.cpp and LiteRT-LM, which bundle the
  Visual C++ runtime DLLs they need. Machines that run the opt-in
  `stable_diffusion` runtime need the latest Microsoft Visual C++ v14
  Redistributable (x64), which stock Windows Server lacks; see
  [Image generation](../guides/image-generation).

## Add the package

```yaml
dependencies:
  llamadart: ^0.17.0
```

Then resolve packages:

```bash
dart pub get
# or
flutter pub get
```

## Flutter iOS and macOS setup

Set the app's deployment target before running: iOS `16.4` or newer, macOS
`14.0` or newer. In Xcode, set `IPHONEOS_DEPLOYMENT_TARGET = 16.4` or
`MACOSX_DEPLOYMENT_TARGET = 14.0` for the Runner configurations. An iOS app that
still uses CocoaPods also needs the Podfile platform:

```ruby
platform :ios, '16.4'
```

The deployment target is a build requirement, not a tested floor for every
runtime. LiteRT-LM has run on a device only on iOS 18.3.2; see
[Known limitations](../platforms/known-platform-issues).

To link the Apple XCFrameworks through Swift Package Manager, add the runtime
companion packages you need:

```yaml
dependencies:
  llamadart: ^0.17.0
  llamadart_llama_cpp_flutter: ^0.17.0 # GGUF / llama.cpp
  llamadart_litert_lm_flutter: ^0.17.0 # Apple .litertlm / LiteRT-LM targets
  llamadart_stable_diffusion_flutter: ^0.17.0 # Apple image generation, opt-in
```

Companion versions released with core `0.13.0` and later share its
`MAJOR.MINOR`, depend on `llamadart`, and constrain it to that core minor, so
pub refuses a mismatched pair instead of the Apple build failing. Companion
patch versions move independently of the core's.

The companions depend on the hosted `llamadart`, and pub ignores a
dependency's own `pubspec_overrides.yaml`. An app that takes `llamadart` from
git or a path, for example with a companion from the same checkout, therefore
repeats that `llamadart` source under its own `dependency_overrides`:

```yaml
dependencies:
  llamadart:
    git: https://github.com/leehack/llamadart.git
  llamadart_llama_cpp_flutter:
    git:
      url: https://github.com/leehack/llamadart.git
      path: packages/llamadart_llama_cpp_flutter

dependency_overrides:
  llamadart:
    git: https://github.com/leehack/llamadart.git
```

Use companions with the core's `MAJOR.MINOR`; pub enforces it. The build also
checks the resolved companions' runtime pins and fails on a mismatch or on an
unverified local `Artifacts` override. The llama.cpp error names the companion
release to depend on, such as `^0.17.1` with core `0.17.1`. A companion that pins
a compatible earlier llama.cpp build is accepted with an upgrade warning; the
stable_diffusion check accepts only the core's own pin.

On macOS, `llamadart_litert_lm_flutter` links and embeds the complete LiteRT-LM
runtime, including the GPU accelerators. The build uses it only when the
resolved companion's `Package.swift` is the one this core release expects; any
other companion keeps macOS LiteRT-LM in the hook cache with a build warning,
and the app then needs the
[build phase below](#flutter-macos-litert-lm-build-phase). A maintained
companion pinning an earlier build of the core's LiteRT-LM release still embeds
and loads its complete macOS arm64 runtime and needs no build phase; the build
only warns to upgrade it. On iOS the build does not check the LiteRT-LM
companion pin.

The companion's macOS XCFrameworks are published for arm64 only, so a
universal `flutter build macos` prints
`ld: warning: ignoring file ... found architecture 'arm64', required
architecture 'x86_64'` for each of them. The arm64-only build that
[Intel Macs](#intel-macs) describes removes those warnings.

Add `llamadart_stable_diffusion_flutter` at the core's `MAJOR.MINOR` for Apple image generation. Adding it opts iOS and
macOS builds into the image generation runtime (about 37 MB per Apple
target) on its own and leaves the other
runtimes on their current path, so leave it out unless the app uses
`ImageGenerationEngine`. An app that uses image generation without it gets the
hook-bundled runtime, whose iOS framework `MinimumOSVersion` App Store Connect
rejects; only Xcode and `xcodebuild` show the build warning about it.

An app bound for the App Store should use the companion for each runtime it
ships: a companion's XCFramework carries the Apple privacy manifest, and the
hook path does not. An app that runs llama.cpp, stable_diffusion or LiteRT-LM on
the hook path, or whose embedded framework has no `PrivacyInfo.xcprivacy`,
declares that runtime's required-reason API use in its own
`PrivacyInfo.xcprivacy`. Copy the categories and codes from
[Apple privacy manifest](../platforms/native-build-hooks#apple-privacy-manifest).

### Intel Macs

LiteRT-LM is not available on x86_64 macOS, on an Intel Mac or under Rosetta.
`litert-lm-native` publishes macOS runtimes for arm64 only
([litert-lm-native#72](https://github.com/leehack/litert-lm-native/issues/72)).
llama.cpp runs on both architectures. On x86_64, Rosetta included,
llama.cpp `GpuBackend.auto` runs on the CPU, because Metal returns garbled
output on Intel Macs with AMD GPUs ([#1597](https://github.com/leehack/llamadart/issues/1597)); `GpuBackend.metal` or
`ComputeDevice.gpu` still loads on Metal, with a warning.

A universal Flutter macOS app that depends on `llamadart_litert_lm_flutter`
builds and launches on x86_64. The build hook leaves LiteRT-LM out of the
x86_64 slice and prints a `warning: llamadart:` build warning. On x86_64,
loading a `.litertlm` model or LiteRT-LM speech recognition throws
`LlamaUnsupportedException`. A Dart program on x86_64 macOS gets the same
exception. The build fails only when a `macos-x86_64` or `macos-x64` entry in
`llamadart_native_runtimes` names `litert_lm`. The same holds for an app
without the companion that uses the
[build phase](#flutter-macos-litert-lm-build-phase).

Building for arm64 only is optional. It only silences the
`ignoring file ... required architecture 'x86_64'` linker warnings for the
arm64-only LiteRT-LM XCFrameworks. To do it, add this line to
`macos/Runner/Configs/Release.xcconfig`, which the Release and Profile
configurations use:

```
EXCLUDED_ARCHS = x86_64
```

An Intel Mac then refuses to open the app. Debug builds already target only
the build Mac's architecture. For a one-off build,
`FLUTTER_MACOS_ARM64_ONLY=true flutter build macos` has the same effect.

### Fresh macOS SwiftPM bootstrap

If a fresh build reports that a companion requires macOS 14.0 but
`FlutterGeneratedPluginSwiftPackage` supports 12.0, use this bootstrap with
Flutter 3.47.1 ([#1139](https://github.com/leehack/llamadart/issues/1139)).
Keep Runner's deployment target at **14.0 or newer** for every configuration.
The companions' 14.0 requirement reflects the shipped binaries.

Flutter generates the plugin package at 12.0, then queries Xcode project
information and build settings before raising that package's floor to Runner's
target. Those queries resolve Swift packages too. If resolution rejects the
12.0 package, Flutter cannot reach its deployment-target update. Runner settings
and a CocoaPods Podfile do not set the generated Swift package's platform.
Changing the companions' metadata to 12.0 would misrepresent their requirements.

Run the following from the **consumer app directory** (the chat example uses
`example/chat_app`). It requires Python 3 and changes only the ignored generated
package, preserving all companion manifests, URLs and checksums:

```bash
(
set -e
flutter pub get
python3 - <<'PY'
from pathlib import Path

manifest = Path("macos/Flutter/ephemeral/Packages/FlutterGeneratedPluginSwiftPackage/Package.swift")
contents = manifest.read_text()
old = '.macOS("12.0")'
if contents.count(old) != 1:
    raise SystemExit("Expected one generated macOS 12.0 floor; inspect the manifest and Flutter version.")
manifest.write_text(contents.replace(old, '.macOS("14.0")', 1))
PY
flutter build macos --debug --no-pub
)
```

Use `--no-pub` for this build: ordinary Flutter commands can regenerate the
12.0 manifest before building. Run the **whole sequence** again after
`flutter clean`, deleting `macos/Flutter/ephemeral`, changing dependencies or
running `flutter pub get`; do not commit generated files. The guard stops on
an unexpected SDK manifest instead of silently claiming to repair it. This is
a consumer bootstrap, not a Flutter SDK fix; the upstream defect is tracked in
[flutter/flutter#186804](https://github.com/flutter/flutter/issues/186804) and
[flutter/flutter#162196](https://github.com/flutter/flutter/issues/162196).

iOS still requires Runner's 16.4 floor; no iOS manifest workaround is needed.

### Flutter macOS LiteRT-LM build phase

Skip this section if the app depends on `llamadart_litert_lm_flutter`; it
embeds the runtime. Only without that companion, the build hook leaves the
LiteRT-LM libraries in its cache inside the resolved `llamadart` package, and
the app loads them from there only when it runs unsandboxed, on the build
machine, from inside the project. Under the App Sandbox, which `flutter create`
turns on, and in any copied or distributed app, the first LiteRT-LM generation
on CPU or GPU throws `Failed to load dynamic library 'libCLiteRTLM_mac.dylib'`
([#1029](https://github.com/leehack/llamadart/issues/1029)). llama.cpp is not
affected.

Add a build phase that copies the runtime into the app:

1. Open `macos/Runner.xcworkspace` in Xcode and select the **Runner** target.
2. In **Build Phases**, add a **New Run Script Phase** and drag it to the end
   of the list, after **Bundle Framework** and Flutter's own script phase.
3. Set **Shell** to `/bin/bash`, clear **Based on dependency analysis**, and
   paste:

```bash
set -euo pipefail
config=
dir="$PROJECT_DIR"
while [ "$dir" != / ]; do
  if [ -f "$dir/.dart_tool/package_config.json" ]; then
    config="$dir/.dart_tool/package_config.json"
    break
  fi
  dir="$(dirname "$dir")"
done
if [ -z "$config" ]; then
  echo "error: no .dart_tool/package_config.json above $PROJECT_DIR; run flutter pub get" >&2
  exit 1
fi
root=
count="$(plutil -extract packages raw -o - "$config")"
for ((i = 0; i < count; i++)); do
  if [ "$(plutil -extract "packages.$i.name" raw -o - "$config")" = llamadart ]; then
    root="$(plutil -extract "packages.$i.rootUri" raw -o - "$config")"
    break
  fi
done
if [ -z "$root" ]; then
  echo "error: llamadart is not resolved in $config" >&2
  exit 1
fi
case "$root" in
  file://*) root="${root#file://}" ;;
  *) root="$(dirname "$config")/$root" ;;
esac
root="$(printf '%b' "${root//%/\\x}")"
bash "$root/tool/macos_litert_lm_prepare_app.sh" "$TARGET_BUILD_DIR/$WRAPPER_NAME"
```

The script finds the resolved `llamadart` package through
`.dart_tool/package_config.json`, so it works for hosted, path and git
dependencies and in pub workspaces, and runs that package's
`tool/macos_litert_lm_prepare_app.sh`. That script copies the arm64 libraries
into `Contents/Frameworks/LiteRtLmRuntime` and signs them with the build's
signing identity, and replaces a runtime already copied by an earlier
version. It picks the architecture from Xcode's `ARCHS`, or from the
build Mac when `ARCHS` is unset, so a universal build on an Intel Mac gets the
arm64 runtime. A build for x86_64 only, such as a Debug build on an Intel Mac,
gets a `warning:` line naming
[litert-lm-native#72](https://github.com/leehack/litert-lm-native/issues/72)
and no LiteRT-LM runtime. Once the companion embeds
the runtime, the script detects it and copies nothing, so the phase can be
removed.

## Web

Web apps must load the WebGPU bridge script in their `web/index.html`; the
package does not inject it. From the app root, run:

```bash
dart run llamadart:web_setup
```

It vendors the pinned bridge assets into `web/webgpu_bridge/`, verifies their
checksums and adds the bootstrap to `web/index.html`; rerun it after upgrading
llamadart. See
[Add the bridge to your app](../platforms/webgpu-bridge#add-the-bridge-to-your-app).

## AI agent skills

The package ships [agent skills](https://dart.dev/tools/pub/package-skills)
that teach coding agents llamadart's APIs. After `pub get`, run this from your
app's root and pick the skills and agent to install them for:

```bash
dart run skills@ get
```

Rerun it after upgrading llamadart to update the installed skills.

## Verify it works

Run the [Quickstart](./quickstart) example with `maxTokens: 1`. If the runtime
initializes and the model loads, your setup is complete.

## What happens on first build

On the first `dart run` / `flutter run` for a native target, `llamadart`:

1. Detects platform and architecture.
2. Resolves matching runtime artifacts from `leehack/llamadart-native` and
   `leehack/litert-lm-native`.
3. Wires them into your app through native assets. Flutter iOS builds use
   SwiftPM-linked XCFrameworks when the matching companion packages are present;
   without the LiteRT-LM companion, Flutter macOS LiteRT-LM keeps its libraries
   in the hook cache and needs the
   [build phase](#flutter-macos-litert-lm-build-phase) in the app. The
   opt-in image generation runtime comes from `leehack/stable-diffusion-native`
   the same way.

No local C++ toolchain setup is required for consumers.

## Customize native runtimes

Native builds bundle llama.cpp and LiteRT-LM by default; image generation is opt-in. To ship only one model
format, or to test another native build, set `hooks.user_defines` in your
`pubspec.yaml`:

```yaml
hooks:
  user_defines:
    llamadart:
      llamadart_native_runtimes: [llama_cpp] # or [litert_lm]
      # Compatibility testing only; omit to use the tested pin.
      # llamadart_native_tag: v0.8.0
```

A `llamadart_native_backends` request that names any backend module the target
bundle lacks is discarded whole: the hook logs a warning and bundles the
defaults instead.

Override tags name a `leehack/llamadart-native` release: stable
`vMAJOR.MINOR.PATCH`, stable wrapper rebuilds `vMAJOR.MINOR.PATCH-N`,
historical `bNNNN`, nightly wrapper rebuilds `bNNNN-N`, or consume-only
`bNNNN-llamadart.N`. Nightly cores are written without leading zeros, and
rebuild counters start at 1. Build-hook overrides must always name an explicit
tag; `latest` is limited to maintainer synchronization and header/binding
regeneration. An override does not regenerate the Dart bindings, so its
binary must stay ABI-compatible with the default
`leehack/llamadart-native@v0.8.0` runtime.

Every key, per-target backend and Android CPU variant selection, local bundle
paths, and fallback rules:
[Configuring native backend modules](../platforms/native-build-hooks#choose-llamacpp-backend-modules).
How the hook resolves runtimes and the Apple SwiftPM path:
[Native build hooks](../platforms/native-build-hooks).
