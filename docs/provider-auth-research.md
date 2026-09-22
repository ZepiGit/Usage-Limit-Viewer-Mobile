# Provider auth research (Phase 0)

Findings from reading the current reference implementations, and the decisions
they led to. This is the document the rest of the provider work was built from.

**Sources read, at these exact commits:**

| Repository | Commit | Date |
|---|---|---|
| `router-for-me/CLIProxyAPI` | `7fac6b15bcfe5ea55c18c9eaec8e5b7e6457d974` | 2026-09-09 |
| `router-for-me/Cli-Proxy-API-Management-Center` | `ed5f1c48e11ba7335f1e8f676f228c280196af85` | 2026-09-08 |
| `AllenReder/CLIProxyAPI-Quota-Inspector` | `1895bc54d0cbdd3b73ac85b3e535b23b7481a1a0` | 2026-04-17 |

## Feasibility matrix

| Provider | Login method chosen | Mobile-suitable | Refresh | Usage | Known risks |
|---|---|---|---|---|---|
| **Codex** | OAuth 2.0 device authorization | **Yes — best fit** | `refresh_token` grant | `GET /backend-api/wham/usage` | PKCE pair is generated *server-side*; internal endpoint; polling uses 403/404 rather than the RFC's `authorization_pending` |
| **xAI / Grok** | RFC 8628 device flow via OIDC discovery | **Yes — best fit** | `refresh_token` grant | `GET /v1/billing` ×2 | Endpoints discovered at runtime (validated); billing semantics differ per plan |
| **Claude** | Authorization code + PKCE, loopback redirect | Workable, with a caveat | `refresh_token` grant | `GET /api/oauth/usage` | **Bot detection.** Reference client mimics TLS fingerprints; this app does not — see below |
| **Antigravity** | Authorization code + PKCE, loopback redirect | Workable | `refresh_token` grant | `POST v1internal:retrieveUserQuotaSummary` | Ships a Google installed-app client secret; fixed loopback port; three candidate hosts |
| **Devin** | Authorization code + PKCE, ephemeral loopback redirect | Yes | Session token (no refresh grant) | Connect `GetUserStatus` JSON/protobuf | Internal seat-management endpoint; session token is a bearer credential |
| **Meta Muse** | OAuth 2.0 device authorization | Yes | DCA token (no refresh grant) | `POST /muse-code/key` with DCA bearer | Internal Muse endpoint; API key and DCA token must be stored separately |

None of these flows has been executed against a live account in the environment
where this was built. They are implemented from the reference implementations and
are **unverified end-to-end**. Treat the matrix as "designed and implemented",
not "tested against production".

## The central question: which flow on Android?

The brief asked for both options to be investigated for Codex, and for the best
secure Android flow elsewhere. The answer differs per provider, and the reason is
always the redirect.

### Why device flow wins where it is available

A loopback redirect (`http://localhost:PORT/...`) requires the app to bind a fixed
port and still be alive when the browser comes back. On Android that is three
distinct liabilities:

1. The port can already be taken by another app, and the provider's client
   registration pins the exact number, so there is no fallback port.
2. The app is backgrounded the moment the browser opens, and may be killed under
   memory pressure before the redirect arrives.
3. Some OEM battery managers are aggressive about backgrounded processes holding
   sockets.

A device flow has none of these. The app holds no listener, keeps no port, and
polls an HTTPS endpoint it initiates. If the app is killed, the login simply fails
cleanly rather than hanging on a socket that will never be written to.

**Decision, as first made: Codex and xAI use the device flow.** For Codex this
was a deliberate divergence from the reference implementation's default, which uses
`http://localhost:1455/auth/callback`.

**Revised for Codex.** The three liabilities above are real, but they are the same
three that Claude and Antigravity have always lived with, and `LoopbackServer` has
answered each of them in practice: the port is bound before the browser opens so a
conflict is known up front, the listener polls with a short timeout so an abandoned
sign-in never strands the port, and the process has survived the browser round-trip
on every device it has been tried on. What the device flow cost, meanwhile, was the
one thing a user notices on every sign-in: a code to read off this app and type
into the browser. So Codex now runs the reference client's browser flow by default,
on the CLI's own registered redirect, and falls back to the device flow only when
port 1455 is taken. xAI stays on the device flow: its client registers no loopback
redirect, and the device flow is its native one.

### Where a redirect is unavoidable

Claude and Antigravity publish no device endpoint. Their client registrations pin
loopback redirects (`:54545/callback` and `:51121/oauth-callback`), so a custom
Android scheme cannot be substituted — the authorization server would reject it.

Both therefore use `LoopbackServer`, which binds `127.0.0.1` only, serves exactly
one request, and closes in a `finally` block. Both validate `state` with a
constant-time comparison before the code is exchanged, and both use PKCE. Codex's
browser flow is the same code path on `:1455/auth/callback`.

Neither uses a WebView. The user authenticates in the real browser via Custom
Tabs, where the address bar is visible and this app is never in a position to
observe a password.

## Per-provider notes

### Codex — device flow, with an honest caveat

```
POST auth.openai.com/api/accounts/deviceauth/usercode   {client_id}
  → device_auth_id, user_code (also spelled "usercode"), interval
user visits auth.openai.com/codex/device, enters the code
POST auth.openai.com/api/accounts/deviceauth/token      {device_auth_id, user_code}
  → 403/404 while pending; 2xx → authorization_code, code_verifier, code_challenge
POST auth.openai.com/oauth/token
     redirect_uri = auth.openai.com/deviceauth/callback
```

Two things here differ from the textbook and are worth stating plainly:

- **Pending is signalled by status, not body.** OpenAI returns 403 or 404 while
  the code is unclaimed, not the RFC 8628 `authorization_pending` error body. The
  polling loop treats exactly those two statuses as "keep waiting" and everything
  else as terminal.
- **The PKCE pair is generated by the provider.** The token response hands back
  both the verifier and the challenge. PKCE normally proves that the client
  redeeming the code is the one that started the flow; when the server generates
  the pair, it does not prove that. The verifier still never crosses an untrusted
  channel, so this is not a live vulnerability, but it is not the guarantee PKCE
  usually provides, and the code says so.

### Claude — the one real feasibility risk

The reference implementation does substantially more than send an HTTPS request:
it uses uTLS to imitate a specific TLS ClientHello fingerprint, pins header
ordering to match an Axios client, and preserves JSON key order on the wire
because `encoding/json` would otherwise re-sort it. That is bot-detection evasion,
and it exists because Anthropic's edge fingerprints clients.

**This app does not do any of that**, and will not. The brief was explicit about
not circumventing provider security mechanisms, and TLS fingerprint imitation is
exactly that. What is implemented is a plain, honest HTTPS request carrying the
headers the protocol needs.

The consequence is a real risk: **if Anthropic's edge rejects an ordinary
OkHttp/Android client, Claude login and usage will fail on-device.** The app's
correct behaviour then is a clear "sign-in unavailable" surfaced to the user, not
an escalation. If that happens, the legitimate paths are to ask Anthropic for a
supported integration route, or to drop Claude support — not to imitate a browser.

Two smaller findings that are easy to get wrong:

- The token endpoint is `platform.claude.com/v1/oauth/token`, **not**
  `api.anthropic.com`, and it takes a **JSON** body while Codex and xAI take form
  encoding.
- The authorization URL requires a `code=true` parameter that appears in no
  standard flow. Omitting it fails the login.

### Antigravity — the client-secret trade-off

The reference implementation ships a Google client secret in source. The brief
says no client secrets in the APK. These conflict, so the conflict is documented
rather than quietly resolved.

- Google classifies this as an **installed-application** client. RFC 8252 §8.5 and
  Google's own documentation treat such secrets as **not confidential** — they
  cannot be kept secret in a distributed binary, and the security model does not
  assume they are.
- PKCE is what actually protects this flow. Possession of the string alone does
  not let an attacker complete an exchange.
- The alternative — registering a proper Android OAuth client with no secret — was
  rejected because the Antigravity quota scopes (`cclog`,
  `experimentsandconfigs`, and the `cloudcode-pa` surface) are bound to this
  specific client ID. A self-registered client is not granted them, so the feature
  would simply not work.

The value is isolated in `ProviderEndpoints.Antigravity` with a comment stating
all of this. It is a documented, deliberate exception, not an oversight.

**The best finding of the whole phase** also lives here. The brief worried about
rendering hundreds of individual models. Using `retrieveUserQuotaSummary` (rather
than `fetchAvailableModels`) makes that a non-problem: the server already returns
`groups[] → buckets[]`, pre-grouped by shared quota bucket, with a
`remainingFraction` per bucket. Models sharing a bucket are already collapsed
upstream, so the app renders one row per bucket without doing any grouping of its
own.

### xAI — the cleanest of the original four

Textbook RFC 8628, discovered via OIDC rather than hardcoded. The one security-relevant
detail is that a discovery document is attacker-controllable if the host is ever
compromised, so both returned endpoints are validated before use: HTTPS only, and
the host must be exactly `x.ai` or a dot-anchored `.x.ai` subdomain. The anchor is
what stops `notx.ai` and `x.ai.example.com` from passing.

Billing needs two calls with different shapes — a credit/weekly view and a
monthly view in **integer cents** — merged into one window list.

## Corrections to the original specification

Reading the current code rather than trusting the brief changed three things:

| Brief said | Actually true | Consequence |
|---|---|---|
| Claude's Fable window key is `seven_day_fable` | It is `iguana_necktie` — a codename | Parsing on the old key would silently drop the window |
| Codex needs `OpenAI-Beta: codex-1` and `Originator: Codex Desktop` | Only on the **reset-credit** endpoints; `/wham/usage` does not take them | Harmless if over-sent, but the docs were wrong about where they belong |
| Windows can be read as primary/secondary | Upstream puts a **monthly** window in the secondary slot on team plans | Trusting position labels a month as a week — a materially wrong number |

The third is the one that would have produced a plausible, quietly incorrect UI.
Windows are classified by `limit_window_seconds` throughout, with payload order
used only as a legacy fallback when the field is absent.

## Stability

Of the endpoints above, only the OAuth ones are standards-based. Every **usage**
endpoint is an internal endpoint of a first-party CLI or desktop client:

- `chatgpt.com/backend-api/wham/*`
- `api.anthropic.com/api/oauth/usage`
- `cloudcode-pa.googleapis.com/v1internal:*`
- `cli-chat-proxy.grok.com/v1/billing`

None is a documented third-party API, and none carries a stability guarantee. That
is why every URL, header and client version lives in a single
`ProviderEndpoints` file, why every parser tolerates missing and unknown fields,
and why the parsers carry the bulk of the test suite. An upstream change should
cost one row on one card and one edit in one file.
