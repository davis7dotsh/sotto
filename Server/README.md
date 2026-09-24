# V07 server

The server is an independent TypeScript/Fastify HTTP process that owns models, shared preferences, recordings, and history. Bun manages its dependencies and compiles standalone executables with the runtime included. Native inference helpers run separately. This guide covers model installation and running the server separately.

| Server | Speech | Proofreading |
| --- | --- | --- |
| Apple Silicon macOS | Whisper large-v3-turbo / whisper.cpp / Metal | Qwen3-4B-Instruct-2507 / Swift MLX / 4-bit |
| Linux x86_64 or ARM64 | Whisper large-v3-turbo / whisper.cpp / CPU or CUDA | Qwen3-4B-Instruct-2507 / llama.cpp / Q4_K_M |

## Models

Run these commands from the repository root. Weights use about 4 GB of disk; runtime memory also includes model state and inference buffers. The server verifies pinned files before loading and keeps models warm. It does not download large weights automatically.

### Whisper, on either platform

```sh
V07_MODEL_DIR="$PWD/.local/models" ./scripts/download-model.sh
```

This installs and verifies `ggml-large-v3-turbo.bin`. The URL, revision, and checksum are pinned in `scripts/download-model.sh` and `Sources/V07Core/SpeechModel.swift`. The server build separately downloads the pinned Silero VAD model.

### Qwen on macOS

The MLX directory must contain exactly the six files listed below. Download the pinned revision:

```sh
(
  set -e
  v07_qwen_dir="$PWD/.local/models/Qwen3-4B-Instruct-2507-MLX-4bit"
  v07_qwen_url="https://huggingface.co/mlx-community/Qwen3-4B-Instruct-2507-4bit/resolve/50d427756c6b1b2fe0c0a10f67fbda1fc8e82c1b"
  mkdir -p "$v07_qwen_dir"
  for file in model.safetensors config.json tokenizer.json tokenizer_config.json generation_config.json chat_template.jinja; do
    curl --fail --location --retry 3 --output "$v07_qwen_dir/$file" "$v07_qwen_url/$file"
  done
)
```

`Sources/V07Core/TextModel.swift` defines the six-file size/hash manifest; the MLX helper verifies it before becoming ready. Use regular files, with no extra files or symlinks in the model directory.

### Qwen on Linux

```sh
mkdir -p .local/models
curl --fail --location --retry 3 \
  --output .local/models/Qwen3-4B-Instruct-2507-Q4_K_M.gguf \
  https://huggingface.co/unsloth/Qwen3-4B-Instruct-2507-GGUF/resolve/a06e946bb6b655725eafa393f4a9745d460374c9/Qwen3-4B-Instruct-2507-Q4_K_M.gguf
```

Expected size: 2,497,281,120 bytes. SHA-256: `3605803b982cb64aead44f6c1b2ae36e3acdb41d8e46c8a94c6533bc4c67e597`. The server verifies both before loading.

## Build

Install Bun 1.4.2 and initialize submodules with `git submodule update --init --recursive`. macOS requires Apple Silicon and full Xcode with its Metal compiler for the MLX helper; the complete client/helper build uses Xcode 26+ and Swift 6.2+. If Metal is missing, run `xcodebuild -downloadComponent MetalToolchain`.

Linux requires Bun, a C/C++ toolchain, CMake, Git, curl, pkg-config, and libcurl development headers. Swift is not required. CUDA builds also need a compatible NVIDIA driver and CUDA toolkit. The [Dockerfile](Dockerfile) provides a pinned Ubuntu 24.04 build environment.

```sh
./scripts/build-server.sh                  # macOS Metal/MLX; Linux CPU
V07_CUDA=ON ./scripts/build-server.sh     # Linux with CUDA
```

Output is `build/server`: executable, native helpers, VAD, notices, and resources. Keep the package together; the Mac proofreader requires the adjacent Metal library and bundles. Large model weights and user data live outside it.

To compile only the coordinator, including its correction worker:

```sh
bun install --frozen-lockfile
bun run build:server                     # Native coordinator in build/server
bun run build:server --all               # Mac arm64, Linux x64 and Linux arm64
```

Cross builds live under `build/server-coordinators`. Bun cross-compiles the coordinator; complete installation archives combine it with helpers built on each matching platform. Installed packages need neither Bun nor Node. Full Linux release packages target Ubuntu 24.04 or a compatible glibc/libstdc++ environment; Mac packages require Apple Silicon and macOS 14+. Linux x64 coordinators use Bun's baseline CPU target. Native helper CPU/CUDA compatibility remains determined by its CMake build flags.

The release workflow produces complete platform tarballs and SHA-256 checksums. Extract a package, retain its `server` directory together, install the pinned model weights separately, then use the arguments below. Developer ID distribution still requires signing/notarization credentials; the draft Mac build is ad-hoc signed with Bun's executable entitlements.

The archive lock uses Bun FFI to call libc `flock`, matching the reference Swift server. This dependency is tested from source and compiled executables on the supported platforms. A running Swift server and Bun server must never share a data directory.

`V07_BUILD_JOBS` controls build concurrency. For another CPU/GPU host, use `V07_NATIVE=OFF` and set `V07_CUDA_ARCHITECTURES` for the destination GPU. CPU support is useful for compatibility tests; validate CUDA support, memory, and dictation latency on the selected host.

## Run

From the repository root, with the models installed above:

```sh
./build/server/v07-server \
  --host 127.0.0.1 --port 8391 \
  --data-dir "$PWD/.local/server" \
  --speech-helper "$PWD/build/server/helpers/v07-engine" \
  --speech-model "$PWD/.local/models/ggml-large-v3-turbo.bin" \
  --vad-model "$PWD/build/server/resources/silero-vad.bin" \
  --proof-helper "$PWD/build/server/helpers/v07-text-engine" \
  --proof-model "$PWD/.local/models/Qwen3-4B-Instruct-2507-MLX-4bit"
```

On Linux, replace the last path with the GGUF file. Add `--dev` for a development label in health responses. If using the packaged distribution elsewhere, point helper/resource paths at that package and choose durable model/data paths.

Check `curl http://localhost:8391/v1/health`; HTTP reachability alone does not mean inference is available. The `ready` field means the server can accept a recording, including while other recordings are uploading or processing. Finished uploads queue for serial inference; model runtime fields separately report whether helpers are loaded. Quitting a client does not stop this process. Use launchd, systemd, or container supervision for boot/restart behavior; the scripts do not install a service.

For server-only development alongside an installed V07 instance, use `--port 8392 --data-dir "$PWD/.local/typescript-server" --dev` with your helper/model arguments. Start the executable directly or use `bun run dev:server` with those arguments. The client dev runner starts the app and defaults to port 8391; avoid it when preserving a running installation.

| Argument | Environment variable |
| --- | --- |
| `--host`, `--port` | `V07_SERVER_HOST`, `V07_SERVER_PORT` |
| `--data-dir`, `--token-file` | `V07_SERVER_DATA_DIR`, `V07_SERVER_TOKEN_FILE` |
| `--speech-helper`, `--speech-model` | `V07_ENGINE_PATH`, `V07_SPEECH_MODEL` |
| `--vad-model` | `V07_VAD_PATH` |
| `--proof-helper`, `--proof-model` | `V07_TEXT_ENGINE_PATH`, `V07_TEXT_MODEL` |
| `--dev` | `V07_DEV=1` |

The dev runner fixes its host to loopback and defaults to port 8391, `.local/server` for data, and `.local/server.log` for logs. Set `V07_SPEECH_MODEL` and `V07_TEXT_MODEL` when using the paths above. Without those overrides, macOS searches the existing locations `~/Library/Application Support/V07/Models/ggml-large-v3-turbo.bin` and `~/.v07/models/Qwen3-4B-Instruct-2507-MLX-4bit`.

## Remote access

Bind to a reachable address and pass `--token-file /absolute/path/to/token`. Nonloopback listeners require a token of at least 32 characters with no internal whitespace. In the Mac app, enter the endpoint and token under **This Mac**; tokens are stored in Keychain.

- Use an HTTPS reverse proxy for hosted servers and hostnames, including Tailscale MagicDNS names. The runner itself serves HTTP.
- HTTP is accepted for localhost and literal Tailscale IPs in `100.64.0.0/10` or `fd7a:115c:a1e0::/48` on your connected tailnet. V07 checks the address range, not routing; use HTTPS if that private route cannot be assured.
- Ordinary LAN IPs require HTTPS. Endpoints cannot contain credentials, queries, or fragments. Credential-bearing redirects are not followed.

Keep the data directory on persistent storage and back it up. Only one runner can own it. See [storage](../docs/architecture.md#storage) and the [HTTP API](../docs/client-server-contract.md).

## Containers

Build from the repository root with initialized submodules:

```sh
docker build -f Server/Dockerfile --target cpu -t v07-server:cpu .
docker build -f Server/Dockerfile --target cuda -t v07-server:cuda .
```

`CUDA_ARCHITECTURES`, `CUDA_IMAGE`, `BUN_IMAGE`, `UBUNTU_IMAGE`, and `BUILD_JOBS` are build arguments. Choose CUDA architectures/toolkit/driver versions for your GPU. GPU containers require NVIDIA Container Toolkit and `--gpus all`; Linux containers on a Mac do not have Metal access.

Mount a directory containing the Whisper `.bin` and Qwen `.gguf` files, plus a token file:

```sh
docker run --rm --name v07-server \
  -p 127.0.0.1:8391:8391 \
  --mount type=volume,source=v07-data,target=/data \
  --mount type=bind,source=/absolute/path/to/models,target=/models,readonly \
  --mount type=bind,source=/absolute/path/to/token,target=/run/secrets/v07-token,readonly \
  v07-server:cpu
```

For a GPU server, use `v07-server:cuda` and add `--gpus all`. The example exposes only host loopback; use the remote-access setup above for clients on other machines. The container runs as UID 10001, which must be able to read model/token files and write `/data`. The named volume preserves history across container replacement.

## Verify

```sh
bun install --frozen-lockfile
bun run fmt
bun run fmt:check
bun run check
bun run test
bun run generate:api --check
swift test
./scripts/smoke-test.sh
V07_TEXT_MODEL=/absolute/path/to/qwen ./scripts/test-corrections.sh
```

API generation/Swift checks need Swift 6.2+. Linux-only development can check TypeScript bindings with `bun run generate:api --check --typescript-only`. The reference Swift server/domain remain as a parity oracle; packaged server builds use TypeScript. See the [contract guide](api/README.md) for generated bindings and the [implementation plan](../docs/typescript-server-plan.md) for the migration.

The HTTP smoke test needs an idle Dev server with proofreading enabled. It uses public sample audio, checks progress/artifacts, temporarily changes and restores retention settings, and removes its test generations. The helper test accepts the MLX directory on Mac or GGUF file on Linux and uses synthetic text. Neither opens a microphone. These checks do not establish live cursor-insertion behavior or GPU performance on a different machine.
