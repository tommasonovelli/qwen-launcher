# Installation and first run

## 1. Requirements

`bora-workbench` supports:

- Ubuntu 22.04 or later, x86-64;
- Windows 11, x86-64;
- the CPU backend, or a single NVIDIA GPU detected through `nvidia-smi`;
- CPython 3.12; the installers pin `3.12.13` and uv `0.11.28`.

For the default model the preflight requires at least **28 GiB of total RAM** and **22 GiB
available**. You also need roughly 22.7 GB for the GGUF, roughly 0.9 GB for the vision projector,
and extra space for the engine, the download cache, and logs.

`bora engine install` also installs the DeepSeek Harness browser interface. One Ubuntu x86-64
machine resolved it to **360 MB** over 532 packages, on top of the above. Treat that as an order of
magnitude rather than a promise — the closure differs by platform and was measured once. It needs
**Node.js 22.19 or newer** on `PATH`, which is checked before anything is downloaded, and on Linux a
C/C++ toolchain, because one dependency ships no prebuilt binary there and is compiled during the
install. Pass `--no-ui` to skip it, in which case `studio` and `vstudio` keep using the integrated
llama.cpp interface and `bora ui install` can add it later.

CUDA on a machine with more than one GPU is detected, but startup is blocked: physical isolation has
only been verified on single-GPU hosts. If `nvidia-smi` is missing, fails, or produces unreadable
data, the launcher uses the CPU backend and shows why.

## 2. Installing bora-workbench 0.5.1

`bora-workbench` is distributed through GitHub Releases. These commands download the `v0.5.1`
manifest, verify the installer and wheel, and install with pinned uv `0.11.28` and CPython
`3.12.13`. They require no administrator privileges.

### Ubuntu

Open a terminal in a new directory and copy the complete block:

```bash
version="0.5.1"
base="https://github.com/tommasonovelli/bora-workbench/releases/download/v${version}"
wheel="bora_workbench-${version}-py3-none-any.whl"

curl --fail --location --proto '=https' --tlsv1.2 \
  "$base/install.sh" --output install.sh
curl --fail --location --proto '=https' --tlsv1.2 \
  "$base/$wheel" --output "$wheel"
curl --fail --location --proto '=https' --tlsv1.2 \
  "$base/SHA256SUMS" --output SHA256SUMS
installer_sha256="$(awk '$2 == "install.sh" { print $1 }' SHA256SUMS)"
wheel_sha256="$(awk -v wheel="$wheel" '$2 == wheel { print $1 }' SHA256SUMS)"
test "${#installer_sha256}" -eq 64
test "${#wheel_sha256}" -eq 64
printf '%s  %s\n' "$installer_sha256" install.sh | sha256sum --check -
printf '%s  %s\n' "$wheel_sha256" "$wheel" | sha256sum --check -
sh ./install.sh --wheel "./$wheel" --sha256 "$wheel_sha256"
```

### Windows

Open PowerShell in a new directory and copy the complete block:

```powershell
$Version = "0.5.1"
$Base = "https://github.com/tommasonovelli/bora-workbench/releases/download/v$Version"
$Wheel = "bora_workbench-$Version-py3-none-any.whl"

Invoke-WebRequest -Uri "$Base/install.ps1" -OutFile install.ps1
Invoke-WebRequest -Uri "$Base/$Wheel" -OutFile $Wheel
Invoke-WebRequest -Uri "$Base/SHA256SUMS" -OutFile SHA256SUMS

$Expected = @{}
Get-Content .\SHA256SUMS | ForEach-Object {
    if ($_ -match '^([0-9a-f]{64})\s+(.+)$') {
        $Expected[$Matches[2]] = $Matches[1]
    }
}
foreach ($File in @("install.ps1", $Wheel)) {
    if (-not $Expected.ContainsKey($File)) {
        throw "$File is missing from SHA256SUMS"
    }
    $Actual = (Get-FileHash ".\$File" -Algorithm SHA256).Hash.ToLowerInvariant()
    if ($Actual -ne $Expected[$File]) {
        throw "$File SHA-256 mismatch"
    }
}
$WheelSha256 = $Expected[$Wheel]
powershell.exe -NoProfile -ExecutionPolicy Bypass -File .\install.ps1 `
  -Wheel ".\$Wheel" -Sha256 $WheelSha256
```

`ExecutionPolicy Bypass` applies to that process only. The script does not change the system policy
and does not require administrative privileges.

The release also contains the source distribution, both installers, and `SHA256SUMS` for offline
verification and installation.

The installers always accept exactly one explicit source:

```text
install.sh  --wheel PATH --sha256 HEX
install.sh  --git-commit FULL_COMMIT

install.ps1 -Wheel PATH -Sha256 HEX
install.ps1 -GitCommit FULL_COMMIT
```

Use the wheel and manifest for a release installation. The full 40-character commit option is for
testing an exact repository revision and never follows a branch or tag implicitly.

## 3. Verifying the tool

For `0.5.1`:

```bash
bora --version
bora validate
bora doctor
```

`validate` checks the installed locks, schemas, and content. `doctor` reads the configuration,
hardware, engine, and records without modifying them.

## 4. Making the model available

The launcher does not distribute the weights, but it does acquire them. `bora pull` downloads the
artifacts pinned in `engine.lock`, and `bora engine install` does it in the same run:

```text
repository: unsloth/Qwen3.6-35B-A3B-MTP-GGUF
revision:   5bc3e238d916f48a861bac2f8a1990a0e9b7e98d
GGUF:       Qwen3.6-35B-A3B-UD-Q4_K_M.gguf
mmproj:     mmproj-BF16.gguf
```

The download uses HTTPS against that exact revision, shows transferred bytes, rate, and an
estimate, writes through a partial file that is never mistaken for a complete one, and accepts the
result only when the name, size, and SHA-256 all match the lock. The projector is only required by
`vstudio`.

The artifacts land in the managed store, `<data root>/models`. Resolution at launch looks there
first and then falls back, read-only, to the pinned Hugging Face snapshot, so files acquired by any
other tool are used as they are and never downloaded a second time. Nothing is ever written into
that cache: no refs, no snapshots, no blobs.

A different model requires a consistent `model` + `model_path` pair in the configuration. It
inherits none of the default model's gates, records, or compatibility; `pull` and `rm` do not
manage it, and `vstudio` cannot use it, because an alternative mmproj is not configurable.

## 5. Installing the engine and the model

```bash
bora engine install
bora engine status
```

The backend is chosen from the detected hardware. Ubuntu CPU and Windows CPU use verified prebuilts;
Windows CUDA combines the verified server and CUDA 13.3 runtime; Ubuntu CUDA builds `llama-server`
alone from the pinned source commit. If build prerequisites are missing, the command lists them
without running `sudo` or a package manager.

Download, checksum, extraction, verification, and activation must all complete before `current.json`
points to the new installation. On a terminal, the CLI shows a byte progress bar for download and
extraction with the current asset, speed, and computed ETA; the other operations keep the phase
visible without inventing a duration. It is normal for the Ubuntu CUDA build to take several
minutes. The final version and help probes stay bounded to 60 seconds each. See the
[architecture](architecture.md#engine-and-model) for the contract.

Once the engine is active the command downloads the pinned model, unless `--no-model` declines it,
so a first setup is one command rather than three. About 22 GB arrive at this step. `bora pull`
performs exactly the same acquisition on its own and is what to rerun after an interruption: a
verified artifact is recognized and not fetched again.

## 6. First use

The minimal path:

```bash
bora doctor
bora coding
```

Without a valid local record the launcher uses the verified `ctx=8192` baseline; on CUDA it also
uses `n_cpu_moe=48`. The CLI declares it as not optimized.

To measure the machine before ordinary launches:

```bash
bora calibrate --mode all
```

Calibration can run for a long time, creates local processes, and activates the resulting records by
default. Read [Calibration](calibration.md) before starting it.

The available modes are:

```bash
bora coding    # text API, no UI and no vision
bora studio    # text chat in a browser UI
bora vstudio   # the same UI, with image input
```

`studio` and `vstudio` open DeepSeek Harness, which `bora engine install` put in place, as a second
managed service. The browser opens once the engine and the interface have each reported ready. The
model appears in its picker as `Qwen 3.6`, which is simply the alias the engine reports; bora writes
nothing into the harness's own storage.

The harness is an agent, not a plain chat window: a session runs against a workspace you pick, under
a permission preset shown in the composer, and it can read and edit files there and run commands.
The default preset confines writes to the selected workspace and the temporary directories; reads,
network access, and process visibility are not confined. Choose the workspace deliberately.

If you installed with `--no-ui`, both modes open the integrated llama.cpp interface instead.
`bora ui install` adds the harness later, and `bora ui remove` takes it back out — asking about the
installation and about your own sessions as two separate questions.

The processes stay in the foreground. `Ctrl-C` performs the cleanup and exits with code 130. From
another terminal you can use:

```bash
bora status
bora stop
```

To drive the API from the [pi](https://pi.dev/) coding agent, start `bora coding`, run `bora pi`
once to connect its provider, then use `bora pi launch`; see [Commands](commands.md#bora-pi).

## 7. Updating

```bash
bora update --check
bora update
```

`update` compares the installed version with the newest GitHub Release and installs it only when it
is strictly newer. It downloads that release's `SHA256SUMS` and wheel over HTTPS, verifies the
wheel's SHA-256 against the manifest, and hands the verified file to
`uv tool install --force --python 3.12.13` — the same trust chain as the manual commands above.

The managed engine, the configuration, and the calibration records are not touched. Before
installing, the command reads `engine.lock` out of the downloaded wheel and says whether the new
version keeps the active engine release or requires `bora engine install` afterwards.

Stop every managed service first: `update` refuses to run while one is live, because the running
launcher still holds the environment uv must replace. For the same reason uv runs from a helper that
waits for the command to exit, so exit code 0 means the installation was scheduled; `bora --version`
in a new shell is the confirmation. An installation that `uv tool` does not own — a development
checkout, for instance — is reported and left alone; use the installer commands in section 2.

## 8. Removal

```bash
bora rm          # only the model, keeping the tool installed
bora stop
bora uninstall   # everything
```

`uninstall` shows the four managed roots and the Python installation, then asks for a single
confirmation. It refuses live services, roots that are symlinks, or an altered set of paths. With
the supported script installation it also removes the Python tool through uv as soon as the command
finishes; uv itself always stays excluded.

The model store lives inside the data root, so the weights it holds are deleted with it. Weights
that also exist in the Hugging Face cache survive that deletion and are offered afterwards as a
**separate question**, which defaults to no. That separation is deliberate: the managed roots
belong to this tool, while the cache is shared with everything else on the machine. Declining it,
or answering nothing at all, leaves the cache exactly as it was.

Cache deletion is confined to the pinned snapshot of the locked repository. It removes only the
artifacts named by `engine.lock`, follows a symlinked entry no further than that repository's own
`blobs/`, keeps a blob that another snapshot of the same repository still references, refuses a
symlinked cache directory instead of following it, and prunes only directories that are already
empty. Repositories belonging to other tools are never even looked at.

**Next:** [Commands](commands.md)
