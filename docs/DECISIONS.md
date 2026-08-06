# Architecture Decision Records

Format: one entry per decision, in the order made. Rejected alternatives are recorded, not deleted,
per CLAUDE.md's working-style rules. See also `CLAUDE.md`'s "Project decisions (resolved at
kickoff)" section for the kickoff-time answers this log expands on.

---

## ADR-0001: Greenfield build, no fork of Open5GS or free5GC

**Date:** 2026-08-04
**Status:** Accepted

**Context:** PROMPT.md Section 2 flags build-vs-fork as the decision most likely to dominate this
project's economics, and asks for a build-vs-fork analysis as a first deliverable.

**Decision:** Build greenfield. Open5GS (C) and free5GC (Go) remain reference reading only.

**Rejected alternative:** Fork or structurally borrow from Open5GS/free5GC. Rejected per explicit
user instruction ("Greenfield from scratch"), given without requesting the comparative analysis
first.

**Consequence:** No shortcut on control-plane procedure implementations later; everything is
generated from the R19 YAML or hand-written against the spec text, per the source-of-truth rule.

---

## ADR-0002: Public repository, Apache-2.0 license

**Date:** 2026-08-04
**Status:** Accepted

**Context:** Brief mandates open source; hosting/license choice was left open.

**Decision:** Public GitHub repository, Apache-2.0.

**Rejected alternatives:**
- MIT: simpler but no explicit patent grant, which matters more here given likely corporate
  forks/contributors in a standards-adjacent project.
- AGPL-3.0: copyleft network-use clause is a poor fit for a reference implementation meant to be
  forked and embedded freely.

---

## ADR-0003: GoogleTest + gMock as the primary test framework

**Date:** 2026-08-04
**Status:** Accepted

**Context:** Mandated stack lists both GoogleTest and Catch2 without specifying which is primary.

**Decision:** GoogleTest + gMock for unit and integration tests (natural pairing; gMock only works
with GoogleTest).

**Rejected alternative:** Catch2 as primary. No strong reason against it, but GoogleTest + gMock's
mocking integration is more valuable given how much of this codebase is SBI clients/servers that
will want mocked peers in unit tests. Catch2 was initially left in the vcpkg manifest for later
BDD-style use, then dropped during Task 8 (build validation) because its vcpkg port needs
`pkg-config`, which isn't installed and nothing yet uses Catch2 -- re-add when a real test wants
it rather than carrying an unused dependency.

---

## ADR-0004: Hand-rolled HTTP/2 server on raw nghttp2 + Boost.Asio

**Date:** 2026-08-04
**Status:** Accepted

**Context:** The mandated stack lists "nghttp2 (core), Boost.Beast or Pistache for the service
layer." In practice: vcpkg's `nghttp2` port builds only the core C library, not upstream's bundled
`asio_http2` ("nghttp2-asio") convenience wrapper -- it isn't packaged at all. Neither Boost.Beast
(HTTP/1.1 + WebSocket only) nor Pistache (HTTP/1.1 only) implement HTTP/2. Since the non-negotiable
rules require "100% of SBI traffic is HTTP/2," something has to actually speak the protocol.

**Decision:** `libs/sbi-core`'s `http2::Server` drives nghttp2's raw C session API
(`nghttp2_session_server_new`, `nghttp2_session_mem_recv`/`mem_send`, header/frame/data callbacks)
directly, with Boost.Asio supplying the TCP accept/read/write loop. See
`libs/sbi-core/src/http2_server.cpp`.

**Rejected alternative:** Add Drogon (MIT, in vcpkg, has built-in HTTP/2 support) as the server
framework. Would have cut implementation effort significantly, but deviates from the brief's
mandated stack without being asked for; user chose the raw-nghttp2 path specifically to avoid an
undisclosed dependency substitution.

**Consequence:** More code to review and maintain than a framework would need, and it's the
highest-risk hand-written piece in Phase 0 -- stream lifecycle and flow-control bugs here would be
subtle. Flagged explicitly for extra scrutiny during build/test (see PHASE0-NOTES below).

---

## ADR-0005: h2c (cleartext) only for Phase 0, no TLS/mTLS yet

**Date:** 2026-08-04
**Status:** Superseded by ADR-0011 (2026-08-04) -- real TLS 1.3 + mTLS is now in place.

**Context:** The non-negotiable rules mandate OpenSSL 3.x with TLS 1.3 and mTLS for real SBI
traffic. Standing up a lab PKI (CA, per-NF certs, mTLS validation) is real scope on its own and
wasn't needed to prove Phase 0's actual goal: that the hand-rolled HTTP/2 transport and OAuth2 flow
work end-to-end.

**Decision:** `http2::Server` and `http2::Client` speak h2c (HTTP/2 cleartext, "prior knowledge")
only. hello-nf <-> stub-nrf runs entirely over plaintext TCP.

**Consequence -- explicitly non-conformant:** This is a real gap against TS 33.501 and the
non-negotiable rules, not a hidden one. It must be closed with real TLS 1.3 + mTLS (ALPN
negotiating "h2") before any NF-to-NF traffic beyond the Phase 0 stub is considered done. Tracked
as follow-up work for Phase 2.

---

## ADR-0006: Synchronous libcurl calls for the HTTP/2 client (Phase 0)

**Date:** 2026-08-04
**Status:** Accepted (temporary)

**Context:** libcurl's easy interface is blocking by default; integrating it with Boost.Asio's
event loop properly means driving `curl_multi_socket_action` from Asio's reactor.

**Decision:** `http2::Client::send()` blocks the calling thread via `curl_easy_perform`. Fine for
hello-nf, which has nothing else to do while waiting.

**Consequence:** Not viable for a real NF handling concurrent inbound SBI requests while also
making outbound calls -- that would stall the server's io_context if called from the same thread.
Revisit (curl_multi + Asio integration, or a dedicated client thread pool) before any Phase 2 NF
needs to make outbound calls while serving inbound ones.

---

## ADR-0007: ProblemDetails/InvalidParam hand-written in sbi-core, not generated

**Date:** 2026-08-04
**Status:** Accepted (disclosed, deliberate exception to "never hand-write a DTO")

**Context:** `sbi-core` (Phase 0) is itself a dependency of `tools/sbi-codegen` (Phase 1) -- there
is no codegen pipeline yet to generate anything from. But `ProblemDetails` (TS 29.500 clause 5.2.7
generic error handling) is needed by sbi-core's own server/client error paths.

**Decision:** `sbi_core::ProblemDetails` and `sbi_core::InvalidParam` are hand-written in
`libs/sbi-core/include/sbi_core/problem_details.hpp`, with every field name transcribed verbatim
from `specs/5G_APIs-REL-19/TS29571_CommonData.yaml` (commit `bca84b6`, lines 518-559 and 615-630).
Three fields that reference other files' schemas (`accessTokenError`, `accessTokenRequest`,
`noProfileMatchInfo`) are carried as opaque `nlohmann::json` rather than fully modeled, since fully
modeling them would mean also generating the NRF access-token/discovery schemas early.

**Consequence:** Once Phase 1's codegen exists, generated NF code should depend on and reuse
`sbi_core::ProblemDetails` rather than regenerating a second copy from `CommonData.yaml` --
otherwise there would be two competing definitions of the same wire type.

---

## ADR-0008: CI split into build / sanitize / lint jobs on free GitHub-hosted runners

**Date:** 2026-08-04
**Status:** Accepted

**Context:** User chose free-tier CI compute (no self-hosted runners) and small-increment cadence.

**Decision:** Three jobs: `build` (plain Debug build + ctest), `sanitize` (matrix: ASan+UBSan vs.
TSan, kept as two separate configs since they're mutually exclusive at compile time), `lint`
(clang-format --dry-run, clang-tidy). vcpkg binary caching via `actions/cache` to keep runtimes
reasonable on the free tier.

**Rejected alternative:** A libFuzzer job. Deferred -- there's no codec worth fuzzing yet; the
first real target is the PFCP codec in Phase 3.

---

## ADR-0009: Target raised from lab-grade to production-grade

**Date:** 2026-08-04
**Status:** Accepted

**Context:** PROMPT.md Section 2 and CLAUDE.md's original goal statement both scoped this project
as "lab-grade... not a carrier-grade core," and CLAUDE.md's own Reality Check section still says
so. The user edited CLAUDE.md's goal line to "production-grade" and, when the resulting
inconsistency (production-grade goal vs. still-lab-grade Reality Check, vs. PROMPT.md's original
framing) was flagged per CLAUDE.md's own "if this file and PROMPT.md disagree, treat that as a
bug" rule, confirmed the change is deliberate: the real target is production-grade, not lab-grade.

**Decision:** The project's quality bar is raised to production-grade. CLAUDE.md's Reality Check
section is updated to match (see that section's amended text) rather than left contradicting the
goal statement.

**Immediate consequence -- work already built must be revisited:**
- **ADR-0005 (h2c only, no TLS/mTLS)** was justified as "an acceptable Phase 0 lab
  simplification." Under a production-grade bar it is not acceptable as a final state -- real
  TLS 1.3 + mTLS (per TS 33.501 and the non-negotiable engineering rules) must be added before
  Phase 2 NFs talk to anything beyond the throwaway stub-nrf. Not fixed in this ADR; tracked as
  required follow-up, first candidate being before/during Phase 2's NRF work since NRF is the
  trust anchor every other NF's OAuth2 flow depends on.
- **stub-nrf's unsigned, fake OAuth2 token** similarly stops being acceptable once real NFs need
  to validate tokens against it -- the real NRF (Phase 2) must issue and NFs must validate
  properly signed JWTs.
- **ADR-0006 (synchronous libcurl client)** and the ~40 outstanding `clang-tidy` style warnings
  noted in PHASE0-NOTES below become real technical debt against a production bar, not
  acceptable-forever lab shortcuts. Not urgent individually, but should not accumulate further
  without a plan to close them.
- Every future phase's Definition of Done should be read as production-grade from here forward:
  full TS 23.502 procedure coverage (not "mandatory only" read loosely), real conformance testing,
  and no silent gaps -- consistent with CLAUDE.md's existing "flag stubs/simplifications honestly"
  rule, which does not change, only the bar for what's an acceptable *permanent* state does.

**Rejected alternative:** Revert CLAUDE.md's goal line back to "lab-grade" to match PROMPT.md and
avoid the rework above. Rejected -- user explicitly confirmed production-grade is the intended
target after the conflict was surfaced.

**Note:** PROMPT.md itself is left unedited as the historical record of the original brief;
CLAUDE.md is the living document and is what future sessions should treat as authoritative on this
point going forward.

---

## ADR-0010: Custom Jinja2 generator for `tools/sbi-codegen`, not openapi-generator

**Date:** 2026-08-04
**Status:** Accepted

**Context:** Phase 1 requires evaluating openapi-generator's C++ targets against a custom Jinja
generator on three pilot files (`TS29510_Nnrf_NFManagement.yaml`, `TS29518_Namf_Communication.yaml`,
`TS29571_CommonData.yaml`) and recommending one with evidence. Correction to PROMPT.md's own text:
current openapi-generator has no `cpp-restsdk` *server* target -- `cpp-restsdk` is client-only.
Available C++ server targets: `cpp-httplib-server`, `cpp-oatpp-server`, `cpp-pistache-server`,
`cpp-qt-qhttpengine-server`, `cpp-restbed-server`(-deprecated). `cpp-pistache-server` was used as
openapi-generator's representative since PROMPT.md named Pistache explicitly.

**Framework HTTP/2 support (checked, not assumed):** none of Pistache, cpp-httplib, restbed, or
oatpp advertise HTTP/2 in their vcpkg port descriptions, and this matches their known designs
(Pistache, cpp-httplib, restbed are HTTP/1.1-only by construction). This reinforces ADR-0004: no
openapi-generator C++ server target can replace `libs/sbi-core`'s hand-rolled HTTP/2 server, so
codegen server/route scaffolding is out of scope regardless of which model-generation approach
wins -- only the DTO/serializer layer is a real candidate for adoption.

**openapi-generator model output -- concrete defects found by actually compiling it:**
1. **anyOf-open-enum (3GPP's pervasive `anyOf: [{enum:[...]}, {type: string}]` pattern, e.g.
   `NFType`, `NFStatus`) generates a completely empty class.** `NFType.h`/`.cpp` from
   `cpp-pistache-server` has no data member; `to_json` emits `{}`; and `operator==`'s body is a bare
   `return;` in a `bool`-returning function -- **confirmed with `g++ -std=c++20 -fsyntax-only`: this
   does not compile** (`error: return-statement with no value, in function returning 'bool'`). This
   pattern covers dozens of types across the R19 API surface, not an edge case.
2. **Pattern/format constraints are silently dropped.** `Fqdn`'s regex pattern
   (`TS29571_CommonData.yaml`) and `Ipv6Addr`'s `allOf`-combined patterns have zero enforcement in
   generated code -- `grep -rl "std::regex" model/` finds regex usage only in the generator's own
   hardcoded RFC 3339 date/date-time helper, nowhere else.
3. **Cross-file `$ref` duplication.** Generating `TS29510_Nnrf_NFManagement.yaml` and
   `TS29518_Namf_Communication.yaml` independently (as real per-NF codegen invocations would)
   produces 84 duplicate files (42 types x .h+.cpp) for shared `TS29571_CommonData.yaml`-derived
   types (`PlmnId`, `Guami`, `InvalidParam`, `AccessTokenReq`, ...) -- an ODR risk if ever linked
   together, and definite drift risk if maintained per-NF.
4. No `discriminator:` usage exists in the three pilot files (checked, not assumed absent) --
   openapi-generator's polymorphism handling was not evaluated since there is nothing to evaluate
   it against here.
5. `nullable` fields use an `...IsSet` boolean-flag pattern rather than `std::optional`, which is
   functional (not a defect), just a different convention than this project's `std::optional`-based
   `sbi_core::put_optional`/`get_optional` helpers already in use in `libs/sbi-core`.

**Decision:** Build `tools/sbi-codegen` as a custom Python + Jinja2 generator
(`tools/sbi-codegen/`), not a wrapper around openapi-generator. It:
- Resolves `$ref` (internal and cross-file) into a single schema registry so a shared type (e.g.
  `Guami`) is generated exactly once regardless of how many pilot/NF files reference it, eliminating
  defect #3 above.
- Represents the anyOf-open-enum pattern as a plain-`std::string`-backed struct with named
  `static inline const std::string` constants for known values -- any value (known or not)
  round-trips correctly, fixing defect #1. Proven in `tests/conformance/test_round_trip.cpp`
  (`NFTypeUnknownValueRoundTrips`) with a value that is not in the known-enum list.
  See `libs/sbi-core/include/sbi_core/sbi_headers.hpp`.
- Enforces `pattern` (direct or `allOf`-combined) via a generated `validate_<Type>(const
  std::string&)` using `std::regex`, fixing defect #2. Proven in `tests/conformance/test_round_trip.cpp`
  (`AmfIdPatternValidation`) with both an accepted and a rejected value.
- Uses `std::optional<T>` for `nullable`/non-required fields via the existing
  `sbi_core::put_optional`/`get_optional` helpers (`json_serde.hpp`), collapsing the
  absent-vs-explicit-null distinction into one state -- a disclosed simplification (most real-world
  OpenAPI-to-C++ generators do the same; a true tri-state would need
  `std::optional<std::optional<T>>` or an explicit sentinel, not worth the complexity for a Phase 1
  prototype).
- Falls back to `using Name = nlohmann::json;` (opaque passthrough) for schema shapes not
  confidently modeled (inline-composed properties, non-string enums, unrecognized `allOf` member
  shapes) rather than guessing. Across the full transitive closure of the three pilot files (1076
  types, 22 source YAML files pulled in transitively -- 3GPP's own schemas are far more
  interconnected than "three pilot files" suggests), **114 types (10.6%) are opaque fallbacks**;
  the rest (583 objects, 193 aliases, 186 open-enums) are fully typed. This ratio is reported
  honestly, not hidden.

**A genuine structural finding, not a codegen bug:** the three pilot files' transitive `$ref`
closure forms one large strongly-connected component spanning 22 of the 33 initially-encountered
source files (`TS29571_CommonData.yaml` <-> `TS29510_Nnrf_AccessToken.yaml` <->
`TS29520_Nnwdaf_EventsSubscription.yaml` <-> ... ). A first, naive one-header-per-source-file version
of this generator hit real "not declared in this scope" compile errors from `#pragma once` silently
no-op'ing a re-entrant `#include` before the needed type was defined -- a genuine circular
C++-header dependency caused by a genuine circular schema dependency in 3GPP's own YAML, not
something either generator invented. Fixed by computing strongly-connected components (Tarjan's
algorithm, `render.py`) over the file dependency graph and emitting **one merged header per SCC**,
with types topologically sorted *within* the merged group by field-level dependency. Result: 11
output file-groups instead of 33, one of which (`TS29122_CommonData_grp.hpp`) is a 546KB file
covering all 22 mutually-dependent source files with a citation block listing all of them.
**Trade-off, disclosed:** this means a change to any one of those 22 files' schemas forces
recompilation of everything in the merged group -- acceptable for a Phase 1 prototype proving
feasibility, but worth revisiting (e.g. finer-grained per-type headers with forward declarations
where the field is used via reference/pointer) if build-time incrementality becomes a real pain
point once more NFs are generated in Phase 2+.

**Four more real bugs found only by actually compiling the generated output** (not by inspection --
each was caught by `g++ -fsyntax-only` on the real generated files, then fixed and re-verified):
- Multi-line 3GPP YAML descriptions (common -- long prose paragraphs with embedded quotes and
  clause references like "3GPP TS 23.003") only had their first line `//`-commented; subsequent
  lines leaked as raw uncommented text into the file. Fixed with a `cppcomment` Jinja filter that
  prefixes every line.
- JSON field names that legitimately start with a digit (`5qi`, `5gMmCapability` -- real 5G QoS
  Identifier field names) are invalid C++ identifiers. Fixed with an `n`-prefix shim
  (`_cpp_field_name`) that only affects the emitted C++ member name, not the JSON wire name.
- The same issue for *type* names (`5GDdnmfInfo`, `2G3GLocationArea` are real schema names), plus
  `and`/`or`/`not`/etc. (C++'s alternative-operator keywords, easy to forget) colliding with real
  field names. Fixed with a shared `cpp_type_name`/reserved-word sanitizer applied consistently at
  both a type's declaration and every reference to it.
- A field whose name is identical to its own type's name (e.g. field `Snssai` of type `Snssai`,
  observed in `SmallDataRateStatusInfo`) compiles but triggers `-Wchanges-meaning` and genuinely
  breaks subsequent name lookup within the same struct once GCC's strict mode is considered. Fixed
  by appending `_` to a field name when it collides with its own bare type name.

**Rejected alternative:** Use openapi-generator for the model/DTO layer specifically (since server
scaffolding was already ruled out by the HTTP/2 finding above), patching its Mustache templates to
fix the anyOf-open-enum bug. Rejected: openapi-generator is a Java tool with its own template
release cadence; maintaining a fork of its templates long-term is a comparable or larger maintenance
burden than owning a ~600-line Python generator we already have full visibility and control over,
and the duplication problem (defect #3) is architectural to openapi-generator's per-invocation model
generation, not fixable via template patches alone.

**Consequence:** `tools/sbi-codegen/generate.py` is wired into the CMake build
(`libs/sbi-generated/CMakeLists.txt`) as a configure-time + rebuild-time step (re-runs when the
generator, its templates, or the pilot YAML change; adding/removing a pilot file needs a
re-configure for `file(GLOB)` to notice new output files -- a known, disclosed CMake limitation of
globbing dynamically generated sources). Requires `python3` with `jinja2`/`pyyaml` on `PATH` --
**not** vcpkg-managed, since there is no vcpkg C++ substitute for a Python code generator; CI
installs these explicitly. This generator's ~10.6% opaque-fallback rate and disclosed
nullable-collapsing simplification are expected to shrink incrementally as Phase 2+ NF work
surfaces schema shapes not yet handled -- it is deliberately not attempting to be a complete,
general-purpose OpenAPI-to-C++ compiler on day one.

---

## ADR-0011: Real TLS 1.3 + mTLS, closing ADR-0005's gap

**Date:** 2026-08-04
**Status:** Accepted

**Context:** ADR-0009 raised the project's target to production-grade, which made ADR-0005's h2c-
only transport explicitly unacceptable as a permanent state, and the user confirmed TLS/mTLS must
land before Phase 2's NRF work starts (not retrofitted after).

**Decision:**
- **Lab PKI**: `scripts/gen-lab-pki.sh` generates a self-signed root CA and one leaf cert per NF
  (EC P-256/prime256v1, SHA-256, 365-day validity), each with **both** `serverAuth` and
  `clientAuth` EKU since every NF is simultaneously an SBI server and client. SAN covers
  `127.0.0.1`/`localhost`/the NF's own name. Output to `certs/` at repo root (gitignored --
  regenerable dev material, not secrets worth version-controlling); the script itself is
  committed.
- **`http2::Server`**: the accepted TCP socket is wrapped in `boost::asio::ssl::stream`, using an
  `ssl::context::tlsv13_server` context (method-table-level restriction to TLS 1.3, not just an
  option flag). Loads the NF's cert+key, sets `verify_peer | verify_fail_if_no_peer_cert` against
  the configured CA (real mTLS enforcement), and installs an ALPN select callback
  (`SSL_CTX_set_alpn_select_cb` + `SSL_select_next_proto`) that accepts only `h2` --
  `SSL_TLSEXT_ERR_ALERT_FATAL` on anything else, no HTTP/1.1 or no-protocol fallback.
  `TlsConfig{cert_path, key_path, ca_path}` (shared with the client, `tls_config.hpp`) is a
  required constructor argument, not optional/defaulted -- a caller cannot construct an
  unauthenticated or unencrypted `Server` by omission; the constructor throws if any path is
  missing or the material fails to load.
- **`http2::Client`**: almost entirely libcurl configuration -- `CURLOPT_SSLVERSION` pinned to
  `CURL_SSLVERSION_TLSv1_3`, `CURLOPT_SSLCERT`/`SSLKEY` (client cert for mTLS),
  `CURLOPT_CAINFO` (verify server), `CURLOPT_SSL_VERIFYPEER`/`VERIFYHOST` left on. HTTP version
  switched from `CURL_HTTP_VERSION_2_PRIOR_KNOWLEDGE` (h2c) to `CURL_HTTP_VERSION_2TLS` (ALPN-
  negotiated over TLS).
- **stub-nrf/hello-nf**: both load their own cert/key + the shared CA (paths baked in at compile
  time via `CERTS_DIR` -- see below), URLs switched to `https://`.

**Proof, not assertion:**
- `openssl s_client -connect 127.0.0.1:7777 -alpn h2 -tls1_3 -CAfile certs/ca/ca.crt` **without**
  a client cert: server sends `tlsv13 alert certificate required` -- mTLS is actually enforced,
  not just configured and silently unchecked.
- Same command **with** `-cert certs/hello-nf/cert.pem -key certs/hello-nf/key.pem`: succeeds,
  `New, TLSv1.3, Cipher is TLS_AES_256_GCM_SHA384`, `ALPN protocol: h2`, `Verify return code: 0
  (ok)`.
- `tests/integration/test_hello_nf_registration.cpp` (real subprocess-to-subprocess, not mocked)
  passes: hello-nf obtains an OAuth2 token, registers (201), heartbeats (200), deregisters (204),
  all over the real TLS 1.3 + mTLS handshake above.

**Disclosed simplifications / known gaps, not hidden:**
- **No graceful TLS shutdown**: `Connection::close()` closes the underlying TCP socket directly
  rather than performing `async_shutdown` (TLS `close_notify`). A fully correct version needs its
  own timeout handling to avoid an unresponsive peer leaking the connection indefinitely; that
  timeout machinery wasn't built. Every current `close()` call site is a teardown/error path, not
  a graceful reuse handoff, so the practical impact today is limited -- but this is real,
  disclosed debt, not fixed.
- **Cert paths are compile-time absolute paths** (`CERTS_DIR` baked in via
  `target_compile_definitions` from `CMAKE_SOURCE_DIR`), not a runtime config system. Acceptable
  for dev/lab binaries run in-place; will need real config (env vars, a config file, whatever
  Phase 2's NF config story ends up being) once these aren't just Phase 0 throwaways.
- **No cert rotation/revocation** (no CRL/OCSP checking, no rotation tooling) -- single static lab
  CA and leaf certs, regenerate-and-restart is the only "rotation" story right now.
- **stub-nrf's OAuth2 token is still unsigned** (ADR-0009 already flagged this separately) --
  TLS/mTLS secures the transport; it doesn't address token signature validation, which is
  unrelated and still Phase 2 NRF work.

**Rejected alternative:** Defer TLS/mTLS until Phase 2, retrofitting it once NRF exists. Rejected
per explicit user decision when the sequencing question was asked directly -- TLS/mTLS first so
Phase 2 starts on solid transport rather than needing a retrofit across whatever NF code lands in
the meantime.

**Note:** the "over actual h2c HTTP/2" phrasing in ADR-0008's PHASE0-NOTES appendix below describes
the Phase 0 build-validation run at the time it was written and is left as a historical record, not
updated to match current behavior -- the transport it describes has since changed per this ADR.

---

## ADR-0012: jwt-cpp + ES256 for NRF's OAuth2 token issuance/verification

**Date:** 2026-08-05
**Status:** Accepted

**Context:** `TS29510_Nnrf_AccessToken.yaml`'s `AccessTokenClaims` schema (lines 361-406) requires
`iss`, `sub`, `aud`, `scope`, `exp` -- real signed JWTs, not stub-nrf's Phase 0 unsigned placeholder
(ADR-0009 already flagged that as needing to close). Needed: a JWS/JWT library.

**Decision:** `jwt-cpp` (header-only, MIT, vcpkg-available, uses OpenSSL under the hood -- no new
crypto backend). Algorithm: ES256 (ECDSA P-256), not RS256. The lab PKI
(`scripts/gen-lab-pki.sh`) already generates P-256 keys for every NF's mTLS cert, so ES256 keeps
the codebase to one curve/algorithm family instead of two; EC keys are also smaller and faster to
verify than RSA at an equivalent security level. NRF's JWT signing keypair
(`certs/nrf-jwt/{private,public}.pem`) is generated separately from any NF's mTLS transport
cert -- reusing a transport key for JOSE signing mixes usages that real PKI practice (and
TS 33.501) keeps apart.

**Verification (not just chosen, checked to work):** a standalone round-trip test
(issue -> verify valid, issue -> tamper one byte -> verify rejects with "invalid signature", issue
-> verify against a Verifier expecting a different issuer -> rejects with "claim value does not
match expected value") passed before this was wired into NRF's request handlers. Re-verified live
against the running NRF over the real TLS+mTLS transport: a request with `Authorization: Bearer
<token>tampered` gets a real 401 with `ProblemDetails{"detail":"invalid signature", ...}`, not a
silent accept.

**Rejected alternative:** RS256. No functional reason against it, but see above -- would have
added a second key type/algorithm family to the codebase for no benefit over ES256 in a lab
context with no interop requirement forcing RSA specifically.

**Consequence:** `sbi_core::jwt::Verifier` lives in `libs/sbi-core` (not `nfs/nrf`), specifically
because every future NF needs to verify incoming bearer tokens NRF issued, not just NRF itself --
NRF only needs the `Issuer` side.

---

## ADR-0013: Prometheus metrics via opentelemetry-cpp's own exporter, not a separate prometheus-cpp dependency

**Date:** 2026-08-05
**Status:** Accepted

**Context:** CLAUDE.md's Definition of Done requires "OpenTelemetry spans + Prometheus metrics
emitted" per NF. Tracing (spans) already exists via opentelemetry-cpp (`otel.hpp`, Phase 0).
Metrics export does not exist yet anywhere in the project.

**Decision:** Enable opentelemetry-cpp's `prometheus` vcpkg feature
(`opentelemetry-cpp[prometheus]`) rather than adding `prometheus-cpp` as an independent top-level
dependency. `libs/sbi-core/include/sbi_core/metrics.hpp` mirrors `otel.hpp`'s shape
(`init_metrics(bind_address)` / `get_meter(name)`). Pull model: `PrometheusExporterFactory`
starts a small HTTP listener (civetweb, bundled transitively) that Prometheus scrapes directly at
`/metrics` -- no push/collector step, unlike the OTLP tracing path.

**Rejected alternative:** `prometheus-cpp` directly. It's what opentelemetry-cpp's Prometheus
feature uses internally anyway (visible in the vcpkg dependency resolution:
`prometheus-cpp[compression,core,pull]` gets pulled in transitively) -- depending on it directly
would mean two ways to create/register metrics in the same codebase (raw prometheus-cpp registry
API vs. the OTel Meter API already used for consistency with tracing) for no benefit.

**Verification:** NRF exposes `nrf_registrations_total`, `nrf_deregistrations_total`,
`nrf_heartbeats_total`, `nrf_tokens_issued_total` (counters) and `nrf_registered_nf_count` (an
`ObservableGauge` reading the live registry size via callback). Confirmed live:
`curl http://127.0.0.1:9464/metrics` returns real Prometheus text-format output with
`nrf_registered_nf_count{otel_scope_name="nrf"} 0` visible before any registration.

**API note for future NFs using this:** `opentelemetry::metrics::Counter<T>`/`ObservableInstrument`
are only forward-declared in `meter.h` (used for the `Meter` interface's return types); a caller
needs `#include <opentelemetry/metrics/sync_instruments.h>`,
`<opentelemetry/metrics/async_instruments.h>`, and `<opentelemetry/metrics/observer_result.h>`
directly to get complete types before calling `->Add(...)` or `->AddCallback(...)` -- otherwise it
fails to compile with "invalid use of incomplete type". `metrics.hpp` already pulls these in so
callers of `sbi_core::get_meter()` don't hit this themselves.

---

## ADR-0014: NRF Docker image -- Ubuntu 24.04 multi-stage, PKI generated at container start

**Date:** 2026-08-05
**Status:** Accepted

**Context:** No NF has been containerized before this (Phase 0's binaries were throwaways, never
built a Dockerfile). `nfs/nrf/CMakeLists.txt` bakes `CERTS_DIR` in as a compile-time absolute path
(`${CMAKE_SOURCE_DIR}/certs`, an already-disclosed Phase 0/ADR-0011 simplification) -- this has a
direct, concrete consequence for how the image has to be built.

**Decision:** `deploy/docker/nrf.Dockerfile`, multi-stage: `builder` (Ubuntu 24.04, full build
toolchain + vcpkg + codegen Python deps, builds the `nrf` target only -- `-D5GC_BUILD_TESTS=OFF`),
`runtime` (Ubuntu 24.04 + `openssl`/`ca-certificates` only, copies the built binary). Both stages
use `/build` as `WORKDIR` specifically so the compile-time `CERTS_DIR` path resolves at runtime
too. The entrypoint runs `scripts/gen-lab-pki.sh nrf` fresh on every container start (ephemeral
CA/certs per container instance by default -- consistent with this being a lab image, not a
provisioned deployment).

**Real build issues hit and fixed, not just anticipated:**
- Docker build context initially copied the host's `build/` directory (stale `CMakeCache.txt`
  pointing at the host's absolute path) -- CMake correctly refused to reuse it inside the
  container. Fixed with `.dockerignore` excluding `build/`, `build-*/`, `certs/`, `.git/`, etc.
- `git clone --depth 1` for vcpkg inside the Dockerfile failed vcpkg's own baseline resolution:
  `vcpkg.json`'s `builtin-baseline` pins a specific historical commit, but a shallow clone only
  fetches the current tip of the default branch, which does not contain that commit object. Fixed
  with a full clone + explicit `git checkout <pinned-commit>`.

**Verification:** actually built (`docker build -f deploy/docker/nrf.Dockerfile -t 5gc-nrf:test .`)
and ran in this environment, not just written-but-unverified Dockerfile text -- see
`docs/TRACEABILITY.md` for the concrete command/output this ADR's claims are backed by.

**Rejected alternative:** a distroless or Alpine runtime base for a smaller image. Rejected for
now on time/complexity grounds (musl vs. glibc ABI concerns with the vcpkg-built static libs
weren't worth resolving for a first Docker pass); worth revisiting once image size actually
matters for the lab.

**Disclosed gap:** no non-root `USER` directive yet -- the container currently runs as root. Real
gap against container-security best practice, not fixed in this pass; flagged rather than silently
shipped as if it were fine.

---

## ADR-0015: NRF-specific simplifications (in-memory storage, partial discovery/subscription semantics)

**Date:** 2026-08-05
**Status:** Accepted (disclosed, tracked)

Consolidates the Phase 2 NRF-specific gaps that don't warrant their own ADR individually but need
to be findable in one place rather than scattered only as code comments:

- **In-memory storage only** (`nfs/nrf/src/registry.hpp`'s `NfRegistry`/`SubscriptionRegistry`),
  no persistence across restarts. A restart loses every registered NF and subscription; every NF
  would need to re-register (which real NFs do periodically via heartbeat anyway, so this is a
  softer gap than it sounds for NFs already running, but a hard one for anything mid-flight during
  a restart).
- **`SearchNFInstances` filters on `target-nf-type` only.** `TS29510_Nnrf_NFDiscovery.yaml`'s real
  query parameter set is much larger (service-names, snssais, dnn, requester-nf-instance-fqdn,
  ...); only the one mandatory discriminating parameter needed for a single-NRF lab to be useful
  is implemented. Real per CLAUDE.md's source-of-truth rule -- not a fabricated subset, a
  disclosed incomplete one.
- **Subscription notification fan-out ignores `subscrCond`.** `SubscriptionData.subscrCond` is a
  real, conditionally-typed filter (which NF types/events a subscriber cares about); this
  implementation delivers every `NF_REGISTERED`/`NF_PROFILE_CHANGED`/`NF_DEREGISTERED` event to
  every active subscriber regardless of what they actually asked for.
- **Notification delivery is synchronous best-effort** (log a warning on failure, no retry) --
  consistent with ADR-0006's synchronous HTTP/2 client; a slow or unreachable subscriber blocks
  the NRF request that triggered the notification for the duration of that one delivery attempt.
- **`GetNFInstances` (list-all) has no pagination** -- `TS29510_Nnrf_NFManagement.yaml` doesn't
  mandate it for this operation, but a very large registry would return an unbounded response
  body; not a problem at lab scale, flagged for whenever it might become one.
- **`/shared-data*` (multi-NRF federation) and `/scp-domain-routing-info*` (SCP-specific) are not
  implemented at all** -- explicitly out of scope for this pass per the agreed procedure list, not
  silently dropped from consideration. No second NRF instance exists in this lab and SCP isn't
  built yet, so neither is exercisable regardless.

---

## PHASE0-NOTES: build validation outcome

Resolved during the "build and run locally" pass (2026-08-04), g++ 13.3 / vcpkg baseline
`f1d4bbc7`, against the actual installed package versions:

- **nghttp2 C API** (nghttp2 1.69.0): the classic API written against
  (`nghttp2_session_mem_recv`/`mem_send`, `nghttp2_data_provider`, `nghttp2_submit_response`)
  compiled and ran correctly as-is -- no `*2`/`nghttp2_ssize` migration needed.
- **nghttp2 CMake integration**: wrong on the first attempt. vcpkg's `nghttp2` port ships only a
  pkg-config file (`libnghttp2.pc`), not a CMake config -- `find_package(nghttp2 CONFIG REQUIRED)`
  / `nghttp2::nghttp2` do not exist. Fixed to `pkg_check_modules(nghttp2 REQUIRED IMPORTED_TARGET
  libnghttp2)` / `PkgConfig::nghttp2` in `libs/sbi-core/CMakeLists.txt`. See ADR-0004.
- **OpenTelemetry C++ SDK** (opentelemetry-cpp 1.28.0): header paths and factory API
  (`TracerProviderFactory`, `OtlpHttpExporterFactory`, `OStreamSpanExporterFactory`,
  `SimpleSpanProcessorFactory`/`BatchSpanProcessorFactory`) were correct as written. One real bug:
  constructing `opentelemetry::nostd::shared_ptr<TracerProvider>` directly from the
  `std::unique_ptr` returned by `TracerProviderFactory::Create` is ambiguous (two applicable
  constructor overloads). Fixed in `otel.cpp` by routing through an intermediate
  `std::shared_ptr<TracerProvider>` first.
- **Other vcpkg CMake target names** used in `libs/sbi-core/CMakeLists.txt` --
  `opentelemetry-cpp::trace`, `opentelemetry-cpp::ostream_span_exporter`,
  `opentelemetry-cpp::otlp_http_exporter`, `tl::expected`, `nlohmann_json::nlohmann_json`,
  `spdlog::spdlog`, `CURL::libcurl`, `Boost::system` -- all resolved correctly, no changes needed.
- **vcpkg manifest**: `catch2` and (transitively) `openssl` need `pkg-config` on the build host to
  compile from source; wasn't installed initially. `catch2` was dropped from the manifest instead
  (unused -- see amended ADR-0003); `pkg-config` was installed for `openssl`, which is a real
  dependency and couldn't be dropped.
- **Result**: full build green (`sbi_core`, `stub-nrf`, `hello-nf`, `integration_tests`), the
  `tests/integration` GoogleTest suite passes, and a manual run confirms the real behaviour: hello-nf
  obtains an OAuth2 token, registers (HTTP 201), heartbeats (HTTP 200), deregisters (HTTP 204), all
  over actual h2c HTTP/2 through the hand-rolled nghttp2 server, with OTel spans emitted for the
  register/heartbeat steps.
- **Not yet clean**: `clang-tidy` (now runnable locally, clang-18 installed) reports ~40 style-only
  warnings across the hand-written files -- `readability-identifier-length` (short names like `ms`,
  `it`, `pd`), `misc-include-cleaner` (missing direct includes for transitively-available symbols),
  `misc-const-correctness`, one `google-build-using-namespace`, one `bugprone-exception-escape` on
  each `main()` (no top-level try/catch around the NF lifecycle). None are errors --
  `WarningsAsErrors` is empty and CI's lint job won't fail on them -- but they're real, undone
  cleanup, not silently ignored. Left for an incremental pass rather than gold-plating Phase 0
  further before Phase 1 starts.

---

## ADR-0016: UERANSIM as an arms-length RAN/UE simulator, fetched not vendored

**Date:** 2026-08-05
**Status:** Accepted

**Context:** AMF's real northbound surface is `Namf_Communication` (SBI/REST, generated from
`TS29518_Namf_Communication.yaml`), but the actual UE Registration procedure (TS 23.502 clause
4.2.2.2.2) starts over N2 (gNB -> AMF, NGAP/TS 38.413, ASN.1 over SCTP) and N1 (NAS), neither of
which is SBI/REST or expressible in the OpenAPI YAML -- there is nothing to codegen here, and
implementing an NGAP stack is a substantial protocol effort in its own right (comparable to Phase
3's PFCP work), deliberately deferred to a later, dedicated turn (`docs/TRACEABILITY.md` will carry
that gap until it's closed). To eventually test AMF's N2/N1 handling against a real, spec-following
peer rather than a hand-rolled test harness that might silently diverge from the actual NGAP/NAS
wire format, the user asked for a RAN/UE simulator.

**Decision:** UERANSIM (`github.com/aligungr/UERANSIM`, tag `v3.3.0`, commit
`6bf5a1a96aaef6ae8778b9d8b477ac6e2bbf8156`) -- an open-source, 3GPP-Release-15-conformant 5G-SA UE
and gNodeB simulator (NGAP/N2 and NAS/N1 control plane, GTP-U/N3 user plane; the NR radio interface
itself is simulated over UDP, not real RF, which is fine since we have no RF hardware target
either).

**License, checked not assumed (correction to what the user was initially told):** UERANSIM is
**AGPL-3.0** (dual-licensed with a commercial option), *not* GPL-3.0 as first stated in this
session before verifying against the actual GitHub repository metadata and `LICENSE` file --
flagged and corrected before this ADR was written, not silently left wrong. AGPL-3.0 is OSI-approved
(satisfies CLAUDE.md's "OSI-approved open source" bar) but is copyleft with a network-use clause
that would require offering source to users of a modified version served over a network. That
clause is not triggered here: UERANSIM runs **unmodified**, as its own separate OS process
(`nr-gnb`/`nr-ue` binaries), communicating with our NFs only over the wire (NGAP/SCTP, NAS, GTP-U)
-- never linked into, statically or dynamically, any `libs/` or `nfs/` binary. No derivative work is
created on our side; our Apache-2.0 code and UERANSIM's AGPL-3.0 code remain two separate programs
talking a standard protocol, the same relationship our NFs will have with any other black-box UE/RAN
implementation.

**Not vendored into the repository.** UERANSIM's source is not committed into this git history --
consistent with keeping AGPL-licensed source code out of an Apache-2.0 project's own tree (avoids
any ambiguity about what license governs what part of the repository) and with the existing pattern
of not vendoring vcpkg dependencies either. `simulators/ransim/fetch-and-build.sh` clones the pinned
commit into `simulators/ransim/vendor/UERANSIM/` (gitignored) and builds it there on demand.

**Directory:** `simulators/ransim/` at repo root, sibling to `nfs/`, `libs/`, `tests/` -- not nested
under `tests/`, since it is a standalone external tool (its own build, its own binaries) rather than
test code we author, even though its primary purpose here is testing our NFs.

**Scope of this session, explicitly:** simulator scaffold only -- fetch script, pinned commit,
build verified to actually produce `nr-gnb`/`nr-ue`/`nr-cli` binaries in this environment (see
`docs/TRACEABILITY.md`), and placeholder `gnb.yaml`/`ue.yaml` configs pointed at AMF's future N2
listener address (`127.0.0.5:38412`, not yet bound by anything -- AMF has no NGAP server yet). **Not
wired to AMF this session** -- there is nothing on the other end yet. Running `nr-gnb` against this
config today will fail to connect (SCTP `ECONNREFUSED`), which is the expected, disclosed state
until AMF's NGAP termination is built in a later turn.

**Test PLMN:** `mcc: '999'`, `mnc: '70'` -- not a 3GPP-assigned real-network PLMN; this is the
de facto "not a real network" test PLMN convention used across the open5gs/free5GC/UERANSIM lab
ecosystem (UERANSIM's own `config/open5gs-gnb.yaml` in the same repo uses the identical pair). A
config-value convention, not a fabricated spec fact -- disclosed as a choice we made, not something
transcribed from a 3GPP TS.

**Rejected alternative:** hand-roll a minimal NGAP/NAS test client that only emits the exact
messages our own AMF implementation expects. Rejected -- that risks tautological tests (our fake
peer and our AMF agreeing with each other while both diverge from the real TS 38.413/24.501 wire
format), which a real, independently-implemented, spec-conformant simulator avoids.

**Consequence / follow-up required:** AMF's own turn(s) still need to (a) implement Namf_Communication
per the procedure list already agreed with the user, and (b) implement NGAP/N2 termination (SCTP
transport, ASN.1 PER encode/decode per TS 38.413) before UERANSIM's `nr-gnb` can successfully reach
it. Both tracked as not-yet-done, not silently assumed complete because the simulator now exists.

---

## ADR-0017: Fix tools/sbi-codegen's cross-file schema name collision bug

**Date:** 2026-08-05
**Status:** Accepted

**Context:** While building AMF's `Namf_Communication` surface, cross-referencing the already-agreed
`AMFStatusChangeSubscribe` procedure's request schema against the generated C++ output surfaced a
real generator defect, not a spec ambiguity: `TS29518_Namf_Communication.yaml` defines its own local
`SubscriptionData` schema (`{amfStatusUri (required), guamiList}`), but only ONE `SubscriptionData`
struct existed anywhere in generated output, and it had NRF's shape
(`{nfStatusNotificationUri (required), subscrCond, ...}` from `TS29510_Nnrf_NFManagement.yaml`) --
AMF's real schema had been silently dropped.

**Root cause, verified by reading `tools/sbi-codegen/sbi_codegen/loader.py`:**
`SchemaRegistry.schemas` was keyed by bare schema name only (`dict[str, tuple[schema, source_file]]`),
and `load_file()` only inserted a schema `if name not in self.schemas` -- first file loaded wins
silently, every later file's same-named schema is discarded with no warning. The loader's own
docstring asserted this was safe ("3GPP's OpenAPI files consistently reuse the same schema name for
the same concept across files"). Checked, not assumed: a script comparing every locally-defined
schema name shared by two or more of the 5 current pilot files
(`TS29510_Nnrf_NFManagement/NFDiscovery/AccessToken.yaml`, `TS29518_Namf_Communication.yaml`,
`TS29571_CommonData.yaml`) found 7 collisions -- `SubscriptionData`, `NFProfile`, `NFService`
(NFManagement vs. NFDiscovery), `Ipv4AddressRange`, `Ipv6PrefixRange`, `TransportProtocol`,
`MbsSession` (NFManagement vs. CommonData) -- and **every one of the 7 has genuinely different
content** (structural dict comparison, descriptions excluded), not an identical redefinition. The
docstring's premise was false for locally-declared-but-coincidentally-named schemas; it only holds
for the deliberate pattern of one file externally `$ref`-ing another's canonical type (e.g.
`NfInstanceId` from `TS29571_CommonData.yaml`), which never hits this collision path since those
files don't also redeclare it locally.

**Blast radius, checked:** `grep` across `nfs/`, `libs/sbi-core/`, `tests/` for every one of the 7
colliding type names found zero hand-written C++ references to any of them -- NRF works with raw
`nlohmann::json` for `SubscriptionData`, not the generated struct (`nfs/nrf/src/registry.hpp`).
Renaming the generated C++ types was therefore safe with no call-site fallout.

**Decision:**
- `SchemaRegistry.schemas` re-keyed to `dict[(source_file, name), schema]`. `load_file()` now
  registers unconditionally (idempotent per-file, not per-name) -- no more silent drops.
  `resolve_ref()` for an internal (`#/...`) ref now always resolves within the *calling* file's own
  namespace, never an arbitrary other file's same-named schema.
- `schema_to_ir.py`'s `Converter` now runs a two-pass build: types are collected keyed by
  `(source_file, yaml_name)` (`TypeRef` gained a `ref_key` field to carry this through), then a final
  `_disambiguate()` pass assigns every key a guaranteed-unique C++ name -- the plain
  `cpp_type_name(name)` when only one file defines that name (the overwhelming majority: 1092 of the
  previous 1104-type output), or `{name}_{file_tag}` (e.g. `SubscriptionData_Nnrf_NFManagement` /
  `SubscriptionData_Namf_Communication`) when multiple files collide on it -- then patches every
  `IRType.name` and every `TypeRef.cpp_name` to match before handing off to `render.py` (which itself
  assumes name-uniqueness via `name_to_type`/`name_to_file` dicts and would have silently re-collided
  the two variants back into one if the renaming weren't resolved before reaching it).
- `tests/conformance/validate_structural_conformance.py` updated for the new `(file, name)`-keyed
  registry API (it looked up `registry.schemas["Guami"]`/`["NFType"]` directly).

**Verification:** regenerated from scratch -- type count went from 1092 to 1104 (12 additional
distinct types now correctly emitted instead of silently merged/dropped, more than the 7 found in the
5-pilot-file check above since the fix applies to the full transitive closure, not just the pilots).
`SubscriptionData_Nnrf_NFManagement` and `SubscriptionData_Namf_Communication` both now exist as
distinct structs with their real, correct fields (confirmed by direct inspection of the generated
header). Full project rebuild green; all 6 existing tests (integration + conformance round-trip +
structural) pass unchanged -- NRF's behavior is provably unaffected by this fix.

**Rejected alternative:** hand-write AMF's `SubscriptionData` DTO instead of fixing the generator.
Rejected as a direct violation of CLAUDE.md's "never hand-write a DTO the YAML can generate" rule --
the correct fix belongs in the shared generator, especially since the same collision pattern will
keep recurring as more NF YAML files are added as codegen roots in later phases.

**Consequence:** the disambiguation-suffix naming scheme (`{Name}_{Nnrf_NFManagement|Namf_Communication|...}`)
is now a permanent, load-bearing part of the generated API surface for every currently-colliding type
and any future collision the same mechanism catches. Future NF work referencing a schema name known to
collide must use the qualified name; this is discoverable by grepping the generated header for the
plain name if a compile error suggests it's missing.

---

## ADR-0018: NRF's own nfInstanceId is a fixed constant, not randomly generated per run

**Date:** 2026-08-05
**Status:** Accepted

**Context:** Discovered while wiring AMF's `sbi_core::jwt::Verifier` for incoming bearer tokens.
`sbi_core::jwt::Verifier`'s constructor requires the exact expected issuer id up front (checked
against every token's `iss` claim). NRF's own `main.cpp` previously called
`sbi_core::generate_uuid_v4()` for its own `nfInstanceId` at every process start -- fine for NRF
itself (it passed its own freshly-generated id to both its `Issuer` and its own `Verifier` in the
same process, so it always agreed with itself), but a real bootstrapping gap for every other NF:
AMF has no way to know what random id NRF picked this run before constructing its own `Verifier`.
Previously latent because NRF was the only NF that both issued and verified tokens; AMF is the
first NF to need to verify tokens NRF issued from outside NRF's own process.

**Decision:** `nfs/nrf/src/main.cpp`'s `kNrfInstanceId` is now a fixed compile-time constant
(`"5ba9a927-1d31-4c8e-8a10-000000000001"`, an arbitrary but validly-shaped UUID) instead of
`generate_uuid_v4()`. Every other NF that verifies NRF-issued tokens (starting with AMF) hardcodes
the identical constant. This is arguably the more correct design independent of the bug it fixes:
NRF is the trust anchor every other NF's OAuth2 flow depends on, and a real deployment's root of
trust having a stable, well-known identity (not one that changes every restart) is the normal
expectation, not a lab shortcut.

**Verification:** rebuilt `nrf`, reran the full test suite (all existing tests, unaffected) --
confirmed nothing depended on the identity being random. `grep` for `nrf_instance_id`/the removed
`generate_uuid_v4()` call site across the repo found only NRF's own file referencing it.

**Disclosed gap, not fixed here:** the constant is duplicated by hand in every NF that needs it
(`nfs/nrf/src/main.cpp` and `nfs/amf/src/main.cpp` so far) rather than coming from one shared
source of truth (e.g. a config file, environment variable, or `libs/sbi-core` constant). Acceptable
for two NFs; worth revisiting (shared config) once several more NFs need the same value -- tracked
as follow-up, not silently left as an accepted-forever hand-copy pattern.

**Rejected alternative:** have `Verifier` accept any issuer and expose the actual `iss` claim in
`VerifyResult` for the caller to check itself against a dynamically-discovered value. Rejected --
weakens the security-by-default property `Verifier` currently has (ADR-0012's tamper-rejection
test relies on issuer mismatch being rejected unconditionally), and there is no discovery mechanism
for "NRF's own identity" today anyway (NRF does not register itself in its own `NfRegistry`), so
this would have traded a real security check for solving a problem the fixed-constant approach
solves more simply.

---

## ADR-0019: AMF (Phase 2's second NF) and the docker-compose shared-PKI fix it required

**Date:** 2026-08-05
**Status:** Accepted

**Context:** AMF implements `Namf_Communication` (`specs/5G_APIs-REL-19/TS29518_Namf_Communication.yaml`)
-- the procedure list agreed with the user before implementation: `ReleaseUEContext`,
`EBIAssignment`, `UEContextTransfer`, `RegistrationStatusUpdate`, `N1N2MessageTransfer`,
`N1N2MessageSubscribe`, `N1N2MessageUnSubscribe`, `NonUeN2MessageTransfer`, `NonUeN2InfoSubscribe`,
`NonUeN2InfoUnSubscribe`, `AMFStatusChangeSubscribe`, `AMFStatusChangeUnSubscribe`,
`AMFStatusChangeSubscribeModfy` -- every operationId with a real `application/json` request-body
alternative in the YAML.

**Deferred, not dropped:** `CreateUEContext`, `RelocateUEContext`, `CancelRelocateUEContext` are
`multipart/related`-ONLY per spec (checked: no `application/json` alternative exists for any of the
three), and `libs/sbi-core` has no multipart/related support. Building that is a substantial
protocol effort in its own right (RFC 2046-style parsing/encoding layered onto the hand-rolled
nghttp2 server), useful to more than just AMF, and was explicitly deferred to a later, dedicated
turn per the user's decision when this was raised. Consequence: nothing in this build can ever
populate `nfs/amf/src/ue_context_store.hpp`'s store, so the four per-`ueContextId` operations
(`ReleaseUEContext`/`EBIAssignment`/`UEContextTransfer`/`RegistrationStatusUpdate`) can only be
exercised on their "no such UE context" (404) branch until `CreateUEContext` lands -- their "found"
branches are implemented for real (correct per spec) but currently unreachable/unverified. Disclosed
in `nfs/amf/src/main.cpp`'s file header, not hidden.

**Also disclosed:** subscriptions (`N1N2Message*`, `NonUeN2Info*`, `AMFStatusChange*`) are created
and removed for real, but notification *delivery* is not implemented -- there is no trigger path
yet (no NGAP/N2, no real UE, no multi-AMF deployment) that would ever fire one.

**NRF client lifecycle runs on a dedicated thread, not the server's `io_context`:** `libs/sbi-core`'s
`http2::Client` is synchronous (ADR-0006, disclosed debt). AMF is the first NF that is
simultaneously a real inbound SBI server (serving `Namf_Communication`) and needs to make ongoing
outbound calls (NRF registration + periodic heartbeat) -- exactly the scenario ADR-0006 flagged as
not viable on the same thread. Resolved minimally: `run_nrf_lifecycle` owns its own `http2::Client`
instance and runs on a dedicated `std::thread`, leaving the server's `io_context` free to serve
inbound requests without stalling during a heartbeat call. This is not the full `curl_multi`+Asio
integration ADR-0006 names as the eventual real fix -- that remains future work once more NFs need
outbound calls from their own request handlers (not just a background lifecycle loop).

**Docker Compose PKI bug found and fixed:** `deploy/docker/docker-compose.yml` previously had each
NF's container generate its own lab PKI independently at startup (`nrf.Dockerfile`'s entrypoint
runs `scripts/gen-lab-pki.sh nrf` fresh every start) -- harmless with only one NF/container in the
compose file (all that existed before AMF), but broken the moment a second container needs to
mutually trust the first over mTLS: two independently-generated root CAs do not validate each
other's leaf certificates. A `pki-init` one-shot service now provisions `certs/` once (via
`scripts/gen-lab-pki.sh nrf amf`) into a shared `certs_data` named volume that both `nrf` and `amf`
mount at `/build/certs`; `nrf`/`amf` both `depends_on: pki-init: condition:
service_completed_successfully`. `nrf.Dockerfile`'s own entrypoint still calls
`gen-lab-pki.sh nrf` too (harmless -- the script skips regeneration when `ca.key`/the NF's cert
already exist, so it's a no-op against the shared volume; kept so the image is still self-sufficient
if ever run standalone via `docker run` outside Compose, matching ADR-0014's original usage).
`amf.Dockerfile`'s entrypoint does NOT attempt its own PKI generation -- it assumes
`/build/certs` is already populated, since running it standalone without `pki-init` having run
first would produce a cert chaining to nobody NRF trusts anyway.

**Disclosed gap, not fixed here:** the equivalent problem exists in Helm (`deploy/helm/amf/` and
`deploy/helm/nrf/` are separate releases with no shared-secret mechanism) -- see
`deploy/helm/amf/Chart.yaml`'s description for the explicit disclosure. A real fix (shared
`Secret` provisioned by a one-shot `Job`, or an external cert-manager `Issuer`) is genuine,
non-trivial scope, deferred to Phase 8 (lab packaging and conformance) per PROMPT.md rather than
attempted piecemeal per-NF-chart in this turn.

**Verification:** `docker build -f deploy/docker/amf.Dockerfile -t 5gc-amf:test .` actually run in
this environment (see `docs/TRACEABILITY.md` for the result) -- matching the bar ADR-0014 set for
NRF's own image. `docker compose up` (both containers actually mTLS-registering with each other)
was NOT run this session, same disclosed-not-silently-assumed gap ADR-0014 already recorded for
NRF alone.

**Ports:** AMF's SBI port (7778) and metrics port (9465) are NRF's (7777/9464) +1 -- a lab
convention chosen for this session, not a value from any spec (`TS29500`/`TS29501` don't mandate
specific ports for SBI services).

---

## ADR-0020: multipart/related codec in sbi-core, unblocking CreateUEContext and SMF's CreateSMContext

**Date:** 2026-08-05
**Status:** Accepted

**Context:** Starting SMF's turn, `TS29502_Nsmf_PDUSession.yaml`'s `PostSmContexts` (CreateSMContext
-- the actual AMF-triggered PDU Session Establishment trigger, TS 23.502 clause 4.3.2.2.1, and
CLAUDE.md's stated Phase 2 end-state goal) turned out to be `multipart/related`-ONLY, same as
AMF's already-deferred `CreateUEContext`/`RelocateUEContext`/`CancelRelocateUEContext`
(ADR-0019). Unlike AMF's case, SMF's other `/sm-contexts` operations
(`UpdateSmContext`/`ReleaseSmContext`/`RetrieveSmContext`) all depend on an SmContext that only
`CreateSMContext` can create -- deferring it a second time would leave SMF's entire `/sm-contexts`
surface untestable beyond 404s, not just three peripheral operations. Given a second NF in a row
hitting the same wall on its most central operation, the user chose to build multipart/related
support now rather than keep accumulating deferred/unreachable code across NFs.

**Decision:** `sbi_core::multipart` (`libs/sbi-core/include/sbi_core/multipart.hpp` +
`src/multipart.cpp`): `parse(content_type_header, body) -> tl::expected<vector<Part>, string>` and
`encode(parts) -> Encoded{content_type_header, body}`. This is RFC 2046 ("multipart") + RFC 2387
("related") -- standard IETF MIME framing 3GPP SBI reuses verbatim, NOT a 3GPP-specific wire
format; the only 3GPP-specific knowledge (which named parts a given operation expects) stays in
each NF's own handler code, never in this codec. No changes to `http2::Server`/`Client` were
needed -- multipart bodies are just opaque bytes as far as HTTP/2 framing is concerned; this is
purely a body-content codec NF handler code opts into after checking `Content-Type`.

**One assumption disclosed as unverified, not asserted as fact:** whether 3GPP peers send/expect
`Content-Id` values wrapped in RFC 2045 msg-id angle brackets (`<foo>`) or as a bare token matching
`RefToBinaryData.contentId` verbatim. The OpenAPI YAML only declares
`Content-Id: {schema: {type: string}}`, which doesn't settle this, and there is no real external
SBI peer in this lab to interop-test against (`simulators/ransim` speaks NGAP/NAS to a gNB, not
Namf_Communication/Nsmf_PDUSession multipart bodies). The codec parses leniently (accepts either
form) and encodes without brackets (the bare-token convention this project recalls from other
open-source 5GC interop reports, not verified firsthand). Flagged for revisit the first time this
needs to interop with a real external SBI peer.

**Verification:** 8 unit tests (`tests/conformance/test_multipart.cpp`) -- encode-then-parse
round-trips (single part, multi-part with genuinely opaque binary bytes including embedded null
bytes), a hand-crafted body shaped exactly like `CreateUEContext`'s real wire format (proving the
codec works against literal bytes, not just its own `encode()` output), and 4 malformed-input
rejection cases (wrong content-type, missing boundary, no delimiter, unterminated body) -- all
wrapped in try/catch so malformed network input becomes a returned error, never an uncaught
exception. `sbi_core` builds warning-clean under the project's strict flags (`-Wall -Wextra
-Wpedantic -Wshadow -Wconversion -Wsign-conversion`, `5gc_project_options`).

**Applied immediately to retroactively unblock AMF:** `nfs/amf/src/main.cpp`'s `CreateUEContext`
(`PUT /ue-contexts/{ueContextId}`), `RelocateUEContext`, `CancelRelocateUEContext` are now
implemented for real (previously deferred per ADR-0019) via a shared `parse_multipart_json_body<T>`
helper mirroring the existing `parse_json_body<T>` pattern. Their N2/NGAP binary-content fields
(`targetToSourceData.ngapData.contentId`, etc.) are stub placeholders, disclosed in
`nfs/amf/src/main.cpp`'s file header -- this lab has one AMF and no NGAP stack, so there is no real
inter-AMF handover state to populate them with; the point of this pass was proving the multipart
plumbing end-to-end (encode -> real HTTP/2 wire bytes -> amf's parser -> store -> downstream
operations), not modeling real handover semantics.

**Proof, not assertion:** two new real subprocess-to-subprocess integration tests
(`tests/integration/test_amf_namf_communication.cpp`) construct an actual multipart/related
`CreateUEContext` request via `sbi_core::multipart::encode` (the same codec `amf` uses to parse),
send it over real TLS 1.3 + mTLS HTTP/2, and confirm: the response deserializes as real
`UeContextCreatedData`; `EBIAssignment`/`ReleaseUEContext`'s previously-unreachable "found"
branches now work end-to-end and correctly 404 on a second `ReleaseUEContext`;
`RelocateUEContext`/`CancelRelocateUEContext` work over real multipart bodies and correctly 404 for
a nonexistent context; a non-multipart body on a multipart-only operation correctly gets 400, not
silently accepted. All 19 project tests pass, stable across repeated runs.

**Rejected alternative:** keep deferring `CreateSMContext` a third time (this NF's turn) and build
SMF's `/pdu-sessions` collection instead (the I-SMF/inter-SMF scenario, which does have a JSON-only
alternative). Rejected per the user's explicit choice -- `/pdu-sessions` is the less common
inter-SMF/roaming scenario, not the standard AMF-triggered PDU session establishment CLAUDE.md
names as the Phase 2 end-state goal, and deferring a third time would mean SMF's entire
`/sm-contexts` surface (the actually-important one) stays untestable indefinitely.

**Consequence:** SMF's `CreateSMContext` (this NF's next turn) can now be built for real using this
same codec, rather than deferred a third time.

---

## ADR-0021: SMF (Phase 2's third NF) -- /sm-contexts scope, shared json_body.hpp promotion

**Date:** 2026-08-05
**Status:** Accepted

**Context:** SMF implements `Nsmf_PDUSession` (`specs/5G_APIs-REL-19/TS29502_Nsmf_PDUSession.yaml`).
The full file covers two largely-independent operation groups: `/sm-contexts` (the AMF-triggered
collection real UE PDU Session Establishment uses, TS 23.502 clause 4.3.2.2.1 --
CLAUDE.md's Phase 2 end-state goal) and `/pdu-sessions` (the I-SMF/inter-SMF roaming-scenario
collection), plus `SendMoData`/`TransferMoData` (small-data-over-NAS, multipart-only) and two
entirely separate services (`Nsmf_EventExposure.yaml`, `Nsmf_NIDD.yaml`). Agreed with the user:
this turn scopes to `/sm-contexts` only -- `CreateSMContext`, `RetrieveSMContext`,
`UpdateSMContext`, `ReleaseSMContext` -- deferring `/pdu-sessions`, `SendMoData`/`TransferMoData`,
and the two separate services, all disclosed in `nfs/smf/src/main.cpp`'s file header, not silently
dropped.

**`TS29502_Nsmf_PDUSession.yaml` added as a codegen root file**
(`libs/sbi-generated/CMakeLists.txt`) -- none of SMF's DTOs existed in generated output before this
turn. Regenerating grew the type count from 1104 to 1240; `SmContext{Create,Created,Update,Updated,
Release,Released,Retrieve,Retrieved}Data` all landed with their real field shapes (verified by
direct inspection of the generated header before writing any handler code), no new cross-file name
collisions observed among the schemas this turn's handlers actually use.

**No real PCF/UDM/UPF to talk to, same shape of gap AMF had with AUSF/UDM:** `CreateSMContext` does
real request validation (mandatory `servingNfId`/`servingNetwork`/`anType`/`smContextStatusUri`
per `SmContextCreateData`) and real store bookkeeping, but cannot perform the real procedure's
PCF (SM Policy Association)/UDM (subscription data)/UPF (N4/PFCP, Phase 3) interactions -- it
always succeeds (201) rather than modeling the failure modes those absent dependencies would
produce. `UpdateSMContext` acknowledges (204) without fabricating `SmContextUpdatedData` content
(EBI allocation, N1/N2 info) since there is nothing real behind those fields yet. Both disclosed in
`nfs/smf/src/main.cpp`'s file header.

**`sbi_core::http2::problem_response`/`parse_json_body<T>`/`parse_multipart_json_body<T>` promoted
to shared `libs/sbi-core/include/sbi_core/json_body.hpp` + `src/json_body.cpp`.** This exact
pattern was independently written in `nfs/nrf/src/main.cpp` and then `nfs/amf/src/main.cpp` --
SMF made it a third occurrence, past the point where duplicating it again was the right call
(CLAUDE.md's "three similar lines is better than a premature abstraction" -- this is the fourth).
`nfs/nrf`'s and `nfs/amf`'s own local copies are deliberately left as-is (already tested, already
committed) rather than churned to use the new shared header in the same turn that introduces it --
a disclosed, non-blocking cleanup opportunity for later, not silently left unnoticed. `check_bearer`
(JWT-verification-specific, not JSON-body-parsing) was NOT promoted -- still duplicated a third
time in `nfs/smf/src/main.cpp`, consistent with the existing NRF/AMF pattern; small enough that
promoting it wasn't judged worth the extra churn this turn.

**Verification:** manual `curl` end-to-end (real multipart `CreateSMContext` -> real
`RetrieveSMContext`/`UpdateSMContext`/`ReleaseSMContext` on the resulting `smContextRef`, real
Prometheus counters) plus 2 new real subprocess-to-subprocess integration tests
(`tests/integration/test_smf_pdu_session.cpp`): a full lifecycle test (multipart `CreateSMContext`
constructed via `sbi_core::multipart::encode`, response deserializes as real `SmContextCreatedData`,
`smContextRef` extracted from the real `Location` header, then `RetrieveSMContext` with no request
body -- proving the spec's `required: false` is actually honored -- `UpdateSMContext`, and
`ReleaseSMContext` followed by a second release correctly 404ing) and an error-path test (404 on a
nonexistent context, 401 on a tampered token, 400 when `CreateSMContext` gets a plain JSON body
instead of multipart/related). All 21 project tests pass, stable across repeated runs.

**Rejected alternative:** implement `/pdu-sessions` alongside `/sm-contexts` in the same turn since
both were now unblocked by the multipart codec. Rejected to keep this turn's scope matched to what
was actually agreed with the user (the standard AMF-triggered flow) rather than silently expanding
scope just because the blocker was gone -- `/pdu-sessions` remains a clearly-scoped future addition
rather than something started, then left half-verified alongside everything else this turn already
covers.

---

## ADR-0022: Fix tools/sbi-codegen's "one cycle poisons the whole group" topo-sort bug

**Date:** 2026-08-06
**Status:** Accepted

**Context:** Adding `TS29503_Nudm_UECM.yaml`/`TS29503_Nudm_SDM.yaml` as codegen pilot files for
UDM produced a `TS29122_CommonData_grp.cpp` that failed to compile with dozens of "has no member
named X" / "was not declared in this scope" errors across many, mostly unrelated types
(`AllowedNssai`, `Point`, `LocationArea`, `RegistrationDatasetNames`, ...). Root-caused (not
assumed) via a minimal standalone reproduction (`g++ -fsyntax-only` on a tiny test file including
just the generated header) plus a direct Tarjan-SCC probe of the IR graph: a **real, genuine 3GPP
schema cycle** -- `SharedData.sharedAmData` -> `AccessAndMobilitySubscriptionData` ->
`AccessAndMobilitySubscriptionData.sharedDataList` -> `SharedData` (a real "shared subscription
data aggregates per-type data, per-type data can itself be marked shared" pattern, not a generator
artifact) -- combined with a real generator bug in `render.py`'s `_topo_sort_types`: the instant
its DFS found ANY cycle anywhere in a merged group, it discarded the entire computed ordering and
fell back to raw input order for **every type in the group**, not just the two cyclic ones. A
2-type cycle was silently corrupting the emission order for (in this group) over a thousand
otherwise-acyclic, unrelated types.

**A second, related gap found while fixing the first:** `_referenced_names` (the function that
walks a type's fields to build the dependency graph) only ever looked at `ObjectType` fields.
`AliasType` (`using X = std::vector<Y>;`) dependencies on other named types in the same group were
never tracked at all -- both for topo-sort ordering AND for cross-group `#include` computation.
Combined with `header.hpp.j2`'s template structure (which always emits the opaque, then alias,
then open-enum, then object blocks in that fixed category order, regardless of what the topo-sort
computes), any alias depending on a struct/enum type -- e.g. `using RegistrationDatasetNames =
std::vector<RegistrationDataSetName>;` where `RegistrationDataSetName` is an open-enum struct --
was structurally guaranteed to reference it before its definition, independent of the first bug.
This is why fixing only the cycle-poisoning bug still left `RegistrationDatasetNames`-shaped
failures; both needed fixing together.

**Decision:**
- `_topo_sort_types` rewritten to use proper SCC condensation: compute strongly-connected
  components via the existing Tarjan implementation, build the condensation graph (guaranteed
  acyclic by construction -- SCCs cannot cycle with each other), topologically sort *that*, and
  return `(ordered_names, cyclic_names)` where `cyclic_names` is only the (typically tiny) set of
  types actually participating in a real cycle. Every acyclic type elsewhere in the group keeps
  its correct dependency order regardless of an unrelated cycle existing somewhere else in the
  same group. Only `ObjectType` nodes can have outgoing edges (enums/aliases-as-targets never
  originate one via the old field-walk), so a multi-member SCC can only ever consist of
  `ObjectType`s -- meaning `struct X;` forward declaration is always sufficient and correct for
  breaking it, never attempted on an alias (which can't be forward-declared in C++).
- `_referenced_names` extended to also extract dependencies from `AliasType.cpp_underlying` via
  identifier tokenization (regex) rather than adding a structured `TypeRef` field to `AliasType` --
  the only thing that matters for dependency tracking is which names appear, and every call site
  already filters the result against a known-names set, so stray non-type tokens (`std`, `vector`)
  are harmless noise, not false edges.
- `render()` now computes cross-group `#include` deps uniformly for every kind (previously
  `ObjectType`-only), and separately computes `alias_forward_decls`: any struct/enum-shaped type an
  `AliasType` in the group depends on, forward-declared unconditionally (not just when part of a
  detected cycle), since the alias block's fixed position before the enum/object blocks makes that
  dependency direction structurally impossible to satisfy any other way.
- `header.hpp.j2` emits a `// Forward declarations ...` block (the union of both sources above)
  immediately after `namespace sbi_gen {`, before the opaque/alias/enum/object blocks.

**Verification:** minimal standalone compile (`g++ -fsyntax-only` against just the regenerated
header) went from ~40 distinct errors to a clean compile. Full project rebuild from a completely
clean `build/` directory (no stale-cache possibility) succeeds. All 21 pre-existing tests
(NRF/AMF/SMF integration, multipart unit tests, round-trip/structural conformance) still pass
unchanged, proving the fix is purely additive (extra forward declarations, more accurate ordering)
with no behavioral change for code that already compiled correctly.

**Rejected alternative:** patch around this one specific cycle (e.g. demote
`SharedData.sharedAmData` or `AccessAndMobilitySubscriptionData.sharedDataList` to an opaque
`nlohmann::json` fallback to break the cycle without touching the topo-sort algorithm itself).
Rejected -- would have fabricated a simplification not called for by the schema (both fields are
perfectly representable, real 3GPP types; the cycle is a normal, valid C++ mutual-reference
pattern once forward-declared) and would not have fixed the underlying flaw, which was already
guaranteed to resurface -- with a different, unpredictable set of collateral damage -- the next
time any future NF's pilot file introduced a different cycle.

**Consequence:** this is the second real generator bug found only by actually compiling generated
output against a growing pilot-file set (after ADR-0017's cross-file name collision) -- both
precisely the kind of bug `docs/DECISIONS.md` ADR-0010 already anticipated ("this generator is
deliberately not attempting to be a complete, general-purpose OpenAPI-to-C++ compiler on day
one... expected to shrink incrementally as Phase 2+ NF work surfaces schema shapes not yet
handled"). No known residual gaps in this area, but per that same expectation, not asserted as the
last one either.
