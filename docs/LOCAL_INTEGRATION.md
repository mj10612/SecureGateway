# Local Claude Code & Codex integration / 로컬 에이전트 연동

For automatic prompt/code protection and result restoration with existing subscription
logins, use the [0.5 subscription gateway](GATEWAY.md). It registers no agent hooks.
This page documents the optional legacy hook integration.

SecureGateway 0.4 supports opt-in Claude Code and Codex command hooks without an API gateway, HTTP service,
or provider endpoint changes. This is an experimental **tool-text integration**, not
a guarantee that all confidential data stays off the network. The project name remains SecureGateway.

## Install and remove

The Claude Code instructions follow. For Codex, see [Codex](#codex).

Install the package in an environment that will remain available to Claude Code:

```powershell
uv tool install .
secure-gateway init --agent claude
secure-gateway doctor
```

The default scope is the current project: `.claude/settings.local.json`. Use `--global`
on both `init` and `doctor` for `~/.claude/settings.json`. `--state-dir PATH` selects a
different local state directory; pass the same path to installation, diagnostics and
manual commands. Restart Claude Code after installation or removal.

```powershell
secure-gateway init --agent claude --global
secure-gateway doctor --agent claude --global
secure-gateway uninstall --agent claude --global
```

Installation merges our four command hooks into the existing registry. Other hooks,
permissions and settings are retained. Existing settings receive an exact byte backup
named `settings.json.secure-gateway-<timestamp>.bak` (or the project equivalent).
Repeated installation replaces our entries rather than duplicating them. Invalid JSON
or invalid hook registries are refused. Removal deletes only our registrations, retaining
encrypted state and backups. It never restores an old entire settings file over newer changes.

The registered command uses the absolute installing Python executable, so moving/removing
that environment requires reinstalling the hooks. `doctor` checks registrations and key
presence; it does **not** certify host-version compatibility or inspect actual provider traffic.
Claude Code must support `updatedToolOutput` and `MessageDisplay`. Check the
[current official hook reference](https://code.claude.com/docs/en/hooks), then test the
installed host with a disposable, nonsensitive fixture before relying on the integration.

## Codex

```powershell
secure-gateway init --agent codex
secure-gateway doctor --agent codex
secure-gateway uninstall --agent codex
```

The default project file is `.codex/hooks.json`. Use `--global` on each command to select
`$CODEX_HOME/hooks.json`, or `~/.codex/hooks.json` when `CODEX_HOME` is unset. SecureGateway
does not edit `config.toml`, enable disabled features, change approval/sandbox settings, or
mark hooks trusted. Restart Codex, trust the project if using project hooks, and review/trust
the exact hook definitions through `/hooks`. Changed definitions can require renewed trust.
`doctor` reports installation/key readiness, not effective hook trust or enabled feature flags.

Codex has three registered hooks:

| Event | SecureGateway behavior |
| :--- | :--- |
| `PostToolUse` | Mask supported tool text and return feedback replacing the original tool result |
| `PreToolUse` | Restore string argument values for `Bash` and `apply_patch`; refuse unknown surrogates |
| `SessionEnd` | Delete the encrypted conversation snapshot |

Codex uses a different output protocol from Claude Code. The adapter returns `continue: false`
with masked `stopReason` text for post-tool feedback rather than `updatedToolOutput`. Structured
results become JSON text in that feedback. Codex requires `permissionDecision: "allow"` alongside
restored `updatedInput`; this is a pre-tool rewrite, not a `PermissionRequest` approval. No
PermissionRequest handler is installed. Bash and patch rewrites retain a string `command` field.
Other tools do not receive restored originals. Feedback replacement also works for code-mode
tool calls without intentionally rejecting their nested promises.

There is no Codex display-only restoration hook in the currently documented interface. Responses
remain surrogate text. For local display before the session ends, feed UTF-8 text into:

```powershell
secure-gateway restore --agent codex --session-id <codex-session-id>
secure-gateway stats --agent codex --session-id <codex-session-id>
secure-gateway exec --agent codex --session-id <codex-session-id> -- git status
```

`restore` reads text from stdin until EOF and writes restored text to stdout. Never invoke it as
a model-visible shell tool: restored stdout would reintroduce originals into model context.
The manual `exec` wrapper still buffers output and is not installed as a command rewrite.
Codex state is stored in `<state-dir>/codex`, isolating it from existing Claude snapshots even
when conversation IDs match. Custom `--state-dir` takes the base directory, not this subdirectory.

Codex CLI **0.160.0** was exercised against a deterministic local fixture provider: a shell read
produced masked model-visible feedback, a following shell write restored the value locally,
and captured provider requests contained no original fixture email. No external model or paid
API was used. Reproduce this optional host test with a native binary:

```powershell
$env:SECURE_GATEWAY_CODEX_BINARY = "C:\path\to\codex.exe"
python -m pytest tests/test_codex_host.py -q
```

Without that environment variable, ordinary CI skips the real-host test and runs the adapter
regressions. The fixture test bypasses hook trust only for its newly generated, locally vetted
definitions in an isolated temporary Codex home; normal installation never bypasses trust.

Codex hook errors we can catch suppress a post-tool result with sanitized feedback; unknown or
missing mappings deny a pre-tool restoration. Host timeouts, skipped/untrusted/disabled hooks,
specialized tool paths, other concurrent hooks, hosted web search, direct prompts, attachments,
and telemetry remain outside the boundary. Nonzero-exit Bash results can reach Codex PostToolUse;
that differs from the successful-result Claude path below. Consult the
[official OpenAI hook reference](https://learn.chatgpt.com/docs/hooks) for host behavior and coverage.

## Data flow and scope

1. `PostToolUse` masks recognized text fields in successful tool results with the existing
   `entities_only` engine, using Unicode placeholders such as `⟦ENT_1⟧`.
2. `PreToolUse` restores string argument values for local `Bash`, `PowerShell`, `Read`,
   `Grep`, `Glob`, `Edit`, `Write` and `MultiEdit` tools before execution. It never returns
   an approval decision on success. Normal host permissions remain necessary.
3. `MessageDisplay` restores assistant text for display only. The replacement does not
   change the model's response history. Whole-line deltas supplied by the host are used;
   this is not a generic arbitrary-chunk streaming adapter.
4. `SessionEnd` deletes that conversation's encrypted snapshot. No mappings are exposed
   through MCP restoration tools.

JSON keys, numeric/boolean scalars and protocol fields are preserved. Recognized text fields
are `stdout`, `stderr`, `text`, `content`, `output`, `filePath`, `file_path`, `filename`,
`filenames`, `matches`, `line`, `lines` and `message`. Top-level strings/lists are also handled.
Binary data, signatures, IDs, type and MIME discriminators are preserved. Unknown fields,
images, PDFs, numeric JSON values and other opaque data are **not protected**. This schema-aware
selection avoids corrupting tool protocols; new tool schemas require an adapter and validation.
This policy is heuristic, conservative for Korean, and can reduce reasoning quality. It does
not preserve all source-code semantics or provide universal secret detection.

Restoration is restricted to the listed local tools. A surrogate-bearing remote MCP/network
tool call is refused rather than receiving restored originals. Local commands can themselves
use a network, so hooks are not a network sandbox. Keep host permissions and network controls.

### Important uncovered paths and failure behavior

- Direct user prompts, rules/system instructions, `@file` attachments, automatic context,
  tool schemas, failed-tool responses and history loaded before installation are not intercepted.
  `UserPromptSubmit` cannot replace the submitted prompt. Do not paste secrets expecting this
  integration to rewrite them.
- Host telemetry can record original tool output **before** `PostToolUse`. Local transcripts,
  restored execution arguments, the tool execution itself, and other host context-building
  paths are outside this protection boundary. There is no all-traffic privacy claim.
- A malformed replacement schema can be ignored by the host. Hook errors/timeouts can also
  cause original output to be used. A post-execution hook cannot fail closed against all leaks.
  This integration must not be used as the sole enforcement layer for confidential workloads.
- Missing/expired/corrupt mappings, unknown placeholders or concurrent state writes refuse
  restoration. `PreToolUse` returns a deny decision with a sanitized error. Display failures
  leave surrogate text visible. No raw input or error candidates are echoed by the CLI.
- Other output-rewriting hooks may replace our result. Test the final model-visible payload
  when combining RTK or other integrations; registration alone does not prove protection.

## Local command wrapper

For commands whose output must be masked **before the host receives it**, invoke the local
wrapper explicitly (or through your own validated command-rewrite integration):

```powershell
secure-gateway exec --session-id example -- git status
secure-gateway stats --session-id example
```

The wrapper accepts an executable and argument list, with no implicit shell. For pipelines,
invoke a shell explicitly. It restores known placeholders in the arguments, captures UTF-8
stdout/stderr locally, masks them before returning either stream, and preserves the exit code.
Masking or UTF-8 decoding failure returns no raw captured output. Execution is buffered, not
interactive streaming. Defaults are 180 seconds and 16 MiB combined stdout/stderr; configure
`--timeout` and `--max-output-bytes`. Exceeding either limit fails without partial output.
The direct child is reaped. POSIX cancellation kills its process group; Windows uses hidden
processes and best-effort tree termination while the direct child exists. Already detached
descendants are outside this ownership guarantee. Match the host's `session_id` if using the same mappings
for hooks. `init` does not automatically rewrite shell commands: doing so changes permission
matching and shell behavior and needs a separate host-specific validation.

## State and lifecycle

Hook subprocesses share authenticated, encrypted session snapshots under
`~/.secure-gateway/hooks` by default. A random local password is stored in `key` beside them;
it is never included in hook settings. The existing encrypted-session transaction lock prevents
concurrent updates; a conflicting writer fails without overwriting mappings. Session filenames
are hashes of host conversation IDs, preventing path traversal.

Mappings expire after one hour idle. An expired session is refused, not silently reallocated:
old placeholders must not acquire new meanings. Start a new conversation to get a new host ID.
Disk expiry is validated on access rather than by a background daemon. Native OS locks release
on process exit, while marked `.lock` files remain and must be retained. Legacy empty locks
require migration after confirming no old writer is active. Removal retains state so a conversation can still be
restored manually. Delete the state directory after all conversations are finished if desired.

Use `secure-gateway state status [--agent codex]` to inspect aggregate snapshot states without
original IDs, mappings, passwords, or paths. `state gc` previews expired ciphertext retirement;
`state gc --apply` revalidates expiry under the transaction lock. It preserves valid, corrupt,
unknown, active, and legacy-locked files, and never deletes persistent locks. A durable retired
marker prevents old host IDs from allocating new meanings for old aliases. Start a new host
conversation after retirement; no automatic alias reuse occurs. Custom directories use
`--state-dir`; Codex remains scoped to its own subdirectory.

The key and snapshots are protected by the local OS account. POSIX creation requests private
permissions; Windows uses inherited ACLs, which must be suitable for private user files.
Encryption with a colocated key does not defend against another process running as the same user,
a malicious agent permitted to read these files, or a compromised machine. Backups inherit the
same local trust requirement. No physical memory-zeroization guarantee is made.

## 한국어 사용 안내

Codex는 `secure-gateway init --agent codex`로 등록하고, `secure-gateway doctor --agent codex`로
확인합니다. 프로젝트의 `.codex/hooks.json`에 설치하며 `--global`은 `CODEX_HOME` 또는
`~/.codex`를 사용합니다. Codex를 재시작한 뒤 `/hooks`에서 정확한 Hook 정의를 검토하고
신뢰해야 합니다. 자동으로 신뢰하거나 보안 설정을 바꾸지는 않습니다.

Codex는 도구 결과를 마스킹한 피드백으로 교체하고 `Bash`·`apply_patch` 실행 인자를 복원합니다.
화면 자동 복원은 제공하지 않습니다. 대화가 끝나기 전에 `secure-gateway restore --agent codex
--session-id <ID>`에 마스킹된 텍스트를 UTF-8 표준입력으로 전달하면 로컬에서 복원할 수 있습니다.
이 복원 명령을 모델이 보는 도구로 실행하면 안 됩니다. Codex 상태는 별도 `codex` 하위 폴더에
저장합니다. CLI 0.160.0에서 로컬 가상 제공자를 사용하여 실제 실행과 재전송 데이터까지 검증했습니다.

이름은 SecureGateway로 유지합니다. 로컬에 설치한 뒤 `secure-gateway init --agent claude`를
실행하면 프로젝트의 Claude Code Hook을 등록합니다. API 주소 변경이나 게이트웨이 서버는
필요하지 않습니다. 전체 프로젝트에 적용하려면 `--global`을 사용하세요. `doctor`는 설정과
키 존재 여부를 검사하며, 실제 호스트의 동작을 보증하지는 않습니다.

성공한 도구 실행 결과의 지원 텍스트 필드를 마스킹하고, 다음 로컬 도구 실행 전에 치환값을
복원합니다. 화면에 표시하는 답변은 원문으로 복원하되 모델 응답 기록은 치환된 상태로 둡니다.
영어·한국어·혼합 문장을 지원하지만 한국어의 보수적인 마스킹은 일반 명사까지 가릴 수 있습니다.
기존 권한 설정과 다른 Hook을 유지하며, 설치 전 설정은 백업하고 해제 시에는 우리 Hook만 제거합니다.

**직접 입력, 자동 첨부, 시스템 지시문, 미지원 필드, 이미지, 실패한 도구 결과, 텔레메트리는
보호 범위에 포함되지 않습니다.** Hook 오류나 호스트 출력 형식 변경으로 원문이 전달될 수
있으므로 전체 개인정보 유출 방지 수단으로 사용하면 안 됩니다. 실행 결과를 호스트에 전달하기
전에 가리려면 `secure-gateway exec --session-id <ID> -- <실행파일> <인자>`를 사용하세요.
이 명령은 현재 자동 등록되는 명령 재작성 기능이 아닙니다.

치환표는 대화 ID별로 암호화하여 저장하고 별도 Hook 프로세스가 공유합니다. 로컬 키가 같은
폴더에 있으므로 같은 사용자 권한의 프로세스까지 차단하지는 않습니다. 대화 종료 시 치환표를
삭제하며, 비정상 종료 후 남은 파일과 백업은 사용자가 정리해야 합니다. 알 수 없는 치환값,
만료·손상된 상태 또는 동시 쓰기가 발생하면 실행 인자 복원을 거부합니다. 원격 도구에는 원문을
복원해 전달하지 않습니다. 실제 Claude Code 버전에서 민감하지 않은 테스트 자료로 동작을 먼저 확인하세요.
