# Performance benchmarking plan

ztls is a no-I/O TLS 1.3 state machine, so the benchmark harness should not
invent sockets just to measure them. The useful model is the one rustls uses:
scenario benchmarks over deterministic in-memory transports, with wall-time for
local development and instruction counts later for regression detection.

## Prior art

rustls has two useful generations of benchmarking:

- `examples/internal/bench.rs` measures handshakes and bulk transfer using an
  in-memory `transfer(left, right)` loop. It reports handshake/s and MB/s, and
  separates client-side and server-side timing.
- `ci-bench` is the mature setup. It runs the same scenarios in two modes:
  wall-time and callgrind instruction counts. Wall-time is noisy but reflects
  cache/branch behavior; instruction count is stable enough for regression
  detection. Their scenarios are handshake without resumption, resumed
  handshakes, and transfer of 1 MiB, crossed with TLS version, certificate key
  type, cipher suite, and side (client/server).

BoringSSL's `bssl speed` is lower-level. It times primitive chunks (AEAD,
hashes, ECDH, signatures) over fixed durations and reports operations/sec and
MB/s. That is useful for isolating crypto backend behavior, but it misses TLS
record overhead and state-machine costs. ztls mirrors this with
`zig build bench-evp`, an OpenSSL EVP-only AEAD harness.

Go's `crypto/tls` tests and benchmarks use local in-memory pipes and recorded
reference handshakes. The important lesson for ztls is the same: keep benchmark
I/O deterministic, and separate harness overhead from TLS work.

## What ztls should measure

Start with layers that exist today:

1. **Record protection throughput**

   Measure encrypt and decrypt separately for each mandatory TLS 1.3 AEAD:

   - TLS_AES_128_GCM_SHA256
   - TLS_AES_256_GCM_SHA384
   - TLS_CHACHA20_POLY1305_SHA256

   Use realistic record sizes: 16 bytes, 128 bytes, 1350 bytes, 8192 bytes,
   and 16384 bytes. BoringSSL uses similar chunk-size sweeps because small
   records measure per-record overhead while large records measure primitive
   throughput.

2. **Parser/framing throughput**

   Measure `frame.parseHeader`, `RecordBuffer.next`, `server_hello.parse`, and
   certificate parsing separately. These are attacker-controlled input surfaces
   and hot enough to track regressions, but they should not be mixed into crypto
   throughput numbers.

3. **Client handshake replay**

   Use RFC 8448 / generated OpenSSL fixture bytes to drive `ClientHandshake`
   through a deterministic client-side handshake. This measures exactly the
   client work we own today: transcript hashing, key schedule, certificate
   parse, signature verify, Finished validation, and client Finished generation.
   Keep this row separate from full client/server benchmarks so the measurement
   boundary stays explicit.

   The timed replay includes handshake-state cleanup. Captures before the #121
   ownership fix omit that cleanup and represent a different measurement boundary.

4. **Full in-memory connection**

   Use rustls-style no-I/O scenarios over in-memory client/server state machines:
   full authenticated handshake, client-to-server application data,
   server-to-client application data, and ping/pong small-record loops.
   Keep OpenSSL/libssl memory-BIO and rustls rows in separate harnesses so each
   comparison names its measurement boundary.

## Equivalence methodology

Benchmark rows are only comparable when the row names describe the same TLS
work, not just when `benchstat` can place them in adjacent columns. The analysis
script normalizes ztls, libssl, rustls, and EVP output into labeled tables:
comparable TLS rows, crypto-floor rows, and ztls-only diagnostics. This section
defines which normalized rows are legitimate apples-to-apples comparisons.

A comparable row must have the same protocol phase, the same cipher suite, the
same payload size when payload exists, and no kernel I/O in the timed path. The
transport model differs by implementation — caller-owned buffers for ztls,
memory BIOs for libssl, and in-memory `Vec<u8>` transfer buffers for rustls —
but every comparable row measures TLS work over deterministic memory transport,
not sockets.

| Row group | ztls row | libssl memory-BIO row | rustls row | Comparison status |
| --- | --- | --- | --- | --- |
| Full handshake | `Handshake` | `Handshake` | `rustls_handshake` | **Non-equivalent across implementations; reported separately from comparable TLS rows.** Full TLS 1.3 handshake, no resumption, X25519, server-only EC P-256 certificate, in-memory transport, but the auth work differs: ztls skips chain-anchor trust verification (`insecure_no_chain_anchor = true`) while still performing CertificateVerify signature verification, hostname verification for `ztls.server.test`, and leaf policy checks; rustls `NoVerifier` skips chain policy and `verify_tls13_signature`; libssl `SSL_VERIFY_NONE` skips trust-store validation and hostname checking, and its CertificateVerify behavior is partly opaque. `bench-analyze` emits this row in a non-equivalent handshake section; do not use it for apples-to-apples claims. |
| ClientHello construction | `HandshakeClientStart` | — | `rustls_handshake_client_start` | Diagnostic until audited. libssl does not expose this split below `SSL_do_handshake`, and ztls/rustls key-generation boundaries must be proven before comparison. |
| Server accepts ClientHello | `HandshakeServerAccept` | — | `rustls_handshake_server_accept` | Diagnostic until audited. Both names refer to the ClientHello consumption point, but the exact timed construction/processing boundary still needs proof. |
| Client processes ServerHello | `HandshakeClientServerHello` | — | — | ztls-only profiling row. rustls processes more of the encrypted server flight in the next client step, so there is no honest rustls peer. |
| Server authenticated flight | `HandshakeServerFlight` | — | `rustls_handshake_server_flight` | Diagnostic until audited. ztls includes certificate/signature/encryption work; rustls boundary must be proven before comparison. |
| Client Finished flight | `HandshakeClientFlight` | — | `rustls_handshake_client_flight` | Diagnostic until audited. Both consume the encrypted server flight and emit client Finished, but certificate policy and verification work differ. |
| Server verifies client Finished | `HandshakeServerFinished` | — | `rustls_handshake_server_finished` | Diagnostic until audited. Both complete the server side of the handshake, but libssl is opaque and rustls boundary still needs proof. |
| App data client→server | `AppClientToServer` | `AppClientToServer` | `rustls_app_client_to_server` | Comparable across all three. Each iteration writes one application payload from client to server and reads the same plaintext on the server side over memory transport. |
| App data server→client | `AppServerToClient` | `AppServerToClient` | `rustls_app_server_to_client` | Comparable across all three. Same as client→server with direction reversed. |
| App data ping-pong | `AppPingPong` | `AppPingPong` | `rustls_app_ping_pong` | Comparable across all three. One client→server payload and one server→client payload per iteration; bytes/op is doubled. |
| Prepared app data | `AppPreparedClientToServer` | — | — | ztls-only optimization row for the caller-owned prepared-send path. No cross-implementation peer. |
| Prepared record encrypt | `RecordEncryptPrepared` | — | — | ztls-only optimization row for `RecordLayer.encryptPrepared`. No cross-implementation peer. |

The application-data rows use the shared payload sizes `16`, `128`, `1350`,
`8192`, and `16384` bytes across ztls, libssl, and rustls. The suite names are
normalized as TLS 1.3 suite names in every harness: `TLS_AES_128_GCM_SHA256`,
`TLS_AES_256_GCM_SHA384`, and `TLS_CHACHA20_POLY1305_SHA256`. Session tickets
and resumption are disabled across all three harnesses so the comparable row
isolates fresh full-handshake work: libssl calls
`SSL_CTX_set_num_tickets(server_ctx, 0)`, rustls sets
`server.send_tls13_tickets = 0`, and the ztls bench builds a fresh client and
server per iteration with no resumption handshake in the timed loop. The
`Handshake` row measures the path that ends at `client.completeWrite()` after
`server.processClientFinished` — no `NewSessionTicket` issuance is in the
timed loop.

## Per-row timed-work inventories

These inventories document the exact work each harness performs inside the
timed loop for the four comparable TLS row groups. They exist so that a
wall-time delta can be tied to specific work, not just to adjacent `benchstat`
columns. Where harnesses differ, the difference is called out explicitly rather
than papered over.

### `Handshake` — full TLS 1.3 handshake, no resumption

**ztls** (`benchZtlsHandshake` in `src/bench/record_protection.zig`):

- Setup outside loop: one warm-up `connectPair` call (full handshake, then
  `deinit`). Deterministic X25519 client and server keypairs are generated
  once via `deterministicClientKeypair` / `deterministicServerKeypair`. Server
  certificate DER and P-256 scalar are `embed`-loaded at comptime.
- Setup inside loop: `connectPair` constructs a fresh `ClientHandshake` and
  `ServerHandshake`, then drives the full handshake: `client.start` (ClientHello
  construction + X25519 keygen), `server.acceptClientHello` (ServerHello + key
  share processing), `server.sendPreparedAuthenticatedFlight` (server cert
  parse + ECDSA P-256 sign for CertificateVerify + record encryption of the
  server flight), `client.handleRecord` (record decrypt + cert parse +
  CertificateVerify **signature verification** against the cert public key +
  transcript hash + key schedule + client Finished MAC), `server.processClientFinished`
  (client Finished MAC verify + server key schedule promotion), then
  `pair.client.deinit()` and `pair.server.deinit()` secure-zero TLS state and
  key material before the iteration ends.
- Cert/signature/policy work: chain-anchor trust check skipped
  (`insecure_no_chain_anchor = true`); CertificateVerify ECDSA P-256 signature
  **verification** is performed; hostname verification runs against
  `ztls.server.test`; leaf policy checks still run for X.509v3 version,
  KeyUsage.digitalSignature, EKU serverAuth, and certificate signature algorithm.
- Transcript/key-schedule: full HKDF/HMAC/SHA transcript hash and key schedule,
  both client and server sides.
- Record framing: real record headers, AAD, nonce construction, AEAD
  encrypt/decrypt for the encrypted handshake flights.
- Memory transport: caller-owned stack buffers (`[4096]u8`, `[8192]u8`);
  `completeWrite()` advances the write cursor. No heap allocation in the TLS
  engine path.
- Allocation: zero ztls-owned heap allocation. `deinit` performs secure-zeroing
  of AEAD contexts, transcript state, and key material (no heap free) inside the
  timed loop.
- Ticket/resumption: disabled in this benchmark harness; every iteration runs a
  full handshake and neither issues a ticket nor offers a PSK.
- ALPN/SNI: SNI hostname string is set (`ztls.server.test`) but no ALPN
  negotiation in the benchmark harness.
- Measurement shape: Go-bench-style per-iteration timing via `b.loop()`,
  producing per-iteration variance.

**libssl** (`benchHandshake` in `bench/bio.zig`):

- Setup outside loop: `makeContexts` creates `SSL_CTX` pair, sets TLS 1.3 min/max,
  cipher suite, X25519 group, `SSL_VERIFY_NONE` on both sides, `SSL_CTX_set_num_tickets(0)`,
  loads server cert/key PEM files. One warm-up `connected` call (full handshake
  + `freeConn`).
- Setup inside loop: `connected` calls `makeConn` (`SSL_new` for client and
  server, `BIO_new_bio_pair` for both directions, `SSL_set_bio`,
  `SSL_set_connect_state` / `SSL_set_accept_state`) then `doHandshake` (a
  poll loop calling `SSL_do_handshake` on each side until both report
  `SSL_is_init_finished`). After the loop body: `freeConn` (`SSL_free` on
  both).
- Cert/signature/policy work: `SSL_VERIFY_NONE` skips trust-store validation
  and hostname checking. libssl internally processes the CertificateVerify
  message as protocol; whether it verifies the signature without a trust store
  is opaque and version-dependent.
- Transcript/key-schedule: internal to libssl; opaque but includes HKDF/HMAC/SHA.
- Record framing: internal to libssl; includes record headers, AAD, nonce, AEAD.
- Memory transport: BIO memory pairs (`BIO_new_bio_pair`); `SSL_write` / `SSL_read`
  over the BIO pair. No kernel sockets.
- Allocation: `SSL_new` and `BIO_new_bio_pair` allocate heap objects per
  iteration. `SSL_free` deallocates. This is per-connection allocation overhead
  that ztls does not have.
- Ticket/resumption: disabled (`SSL_CTX_set_num_tickets(server_ctx, 0)`).
- ALPN/SNI: no SNI or ALPN is configured in the libssl memory-BIO harness.
- Measurement shape: Go-bench-style per-iteration timing via `b.loop()`.

**rustls** (`rustls_handshake` in `bench/rustls/src/main.rs`):

- Setup outside loop: `load_config` creates `ClientConfig` and `ServerConfig`
  from PEM files, `NoVerifier` as the client cert verifier,
  `server.send_tls13_tickets = 0`.
- Setup inside loop: `connected` calls `make_conn` (`ClientConnection::new` +
  `ServerConnection::new` + fresh `Vec` transfer buffers) then `transfer` (a
  loop calling `transfer_step` which does `write_tls` / `read_tls` /
  `process_new_packets` on both sides until neither is handshaking).
- Cert/signature/policy work: `NoVerifier.verify_server_cert` returns `Ok(())`;
  `NoVerifier.verify_tls13_signature` returns `Ok(())`. **No signature
  verification is performed.** rustls internally parses the certificate and
  CertificateVerify messages (parsing overhead present) but does no signature
  math.
- Transcript/key-schedule: internal to rustls; includes HKDF/HMAC/SHA via the
  configured crypto provider (ring).
- Record framing: internal to rustls; includes record headers, AAD, nonce, AEAD.
- Memory transport: `Vec<u8>` transfer buffers with `Cursor`; `write_tls` /
  `read_tls` / `process_new_packets`.
- Allocation: `ClientConnection::new` and `ServerConnection::new` allocate
  heap objects per iteration. `Vec` transfer buffers are dropped per iteration.
- Ticket/resumption: disabled (`server.send_tls13_tickets = 0`).
- ALPN/SNI: `ServerName::try_from("test.local")` is set; no ALPN in the
  benchmark.
- Measurement shape: Go-bench-style per-handshake samples. The rustls
  harness auto-calibrates iteration counts to `--benchtime` and emits
  `--count` (a.k.a. `--samples`) independent samples, each a calibrated
  per-handshake timing, matching the ztls/libssl Go-bench approach. All
  three harnesses produce real per-sample variance for benchstat.

**Why the `Handshake` row is not a comparable TLS row:**

1. **Signature verification:** ztls does real ECDSA P-256 verify; rustls does
   none; libssl is opaque. This is the most important work asymmetry.
2. **Hostname and leaf policy checks:** ztls verifies `ztls.server.test` and
   still runs leaf policy checks for X.509v3 version, KeyUsage.digitalSignature,
   EKU serverAuth, and certificate signature algorithm. rustls `NoVerifier` and
   libssl `SSL_VERIFY_NONE` skip this policy work.
3. **Per-iteration allocation and cleanup:** libssl and rustls allocate and free
   connection objects per iteration; ztls uses stack-resident state machines but
   does secure-zero AEAD contexts, transcript state, and key material during
   `deinit`. The row measures different amounts of allocator and cleanup work.
4. **Measurement shape:** all three harnesses now use calibrated Go-bench
   per-handshake samples with `--count`/`--samples` controlling sample count,
   so the statistics are directly comparable. The residual non-equivalence is
   the auth-work asymmetry above, not the measurement method.
5. **Cert loading:** ztls loads cert DER at comptime; libssl/rustls load PEM
   files at runtime in setup (outside the loop). This does not affect the
   timed region but affects startup cost.

### `AppClientToServer` — one record encrypt (client) + one record decrypt (server)

**ztls** (`benchZtlsAppData` with `.client_to_server`):

- Setup outside loop: one `connectPair` (full handshake) to get a connected
  client/server pair. Connection is reused across all iterations. `payload`
  is a stack array filled with `0xa5`.
- Work inside loop: `client.sendApplicationData(&payload, &wire)` (record
  framing + nonce + AAD + AEAD encrypt), `client.completeWrite()`,
  `server.receiveApplicationData(wire[0..record.len])` (record parse + AEAD
  decrypt + inner content-type check). `b.setBytes(size)`.
- Connection reuse: one pair for all iterations. No per-iteration connection
  setup.
- Allocation: zero. All buffers are stack arrays.
- Warm-up: the `connectPair` call is setup, not a warm-up write. No explicit
  warm-up write/read before the timed loop.

**libssl** (`benchApp` with `.client_to_server`):

- Setup outside loop: `makeContexts` + one `connected` pair. One warm-up
  write/read (`sslWriteAll` client, `sslReadExact` server) before the timed
  loop.
- Work inside loop: `sslWriteAll(conn.client, payload[0..size])` (may loop
  internally if `SSL_write` returns short), `sslReadExact(conn.server,
  recvbuf[0..size])` (may loop internally on short reads).
- Connection reuse: one connected `SSL` pair for all iterations.
- Allocation: no per-iteration allocation; the `SSL` objects and BIOs are
  reused.
- Transport: `SSL_write` / `SSL_read` over the BIO pair. The BIO layer copies
  bytes between the SSL internal buffers and the BIO memory buffers.

**rustls** (`bench_app` with dir=0):

- Setup outside loop: `load_config` + one `connected` pair. No explicit
  warm-up write/read before the timed loop (the first iteration is in the
  timed region).
- Work inside loop: `conn.client.writer().write_all(&payload[..size])`,
  `transfer(&mut conn)` (flushes `write_tls` and feeds `read_tls` +
  `process_new_packets` on both sides), `read_exact_app(conn.server.reader(),
  size, recv)`. `iters = max(TARGET_BYTES / size, 256)`.
- Connection reuse: one connected pair for all iterations.
- Allocation: no per-iteration allocation; `Conn` and its `Vec` buffers are
  reused.
- Measurement shape: Go-bench-style calibrated per-iteration samples.
  The rustls harness auto-calibrates iteration counts to `--benchtime` and
  emits `--count` independent samples, matching the ztls/libssl approach.

**Key asymmetries for app-data rows:**

1. **Warm-up:** libssl does one warm-up write/read; ztls and rustls do not.
   This may cause the first timed iteration to include cold-cache effects for
   ztls/rustls but not for libssl.
2. **Transport overhead:** libssl's BIO layer and `SSL_write`/`SSL_read`
  internal dispatch add wrapper overhead that ztls's direct `sendApplicationData`/
  `receiveApplicationData` API avoids. rustls's `writer().write_all` + `transfer` +
  `reader().read` + `process_new_packets` is a different wrapper shape. These
  wrappers are part of what the row measures; the delta is explainable only
  with perf/disassembly evidence.
3. **Measurement shape:** all three harnesses now use calibrated Go-bench
  per-iteration samples with `--count`/`--samples` controlling sample count.
  The inner iteration count is auto-calibrated to `--benchtime` in all three.

### `AppServerToClient` — one record encrypt (server) + one record decrypt (client)

Same structure as `AppClientToServer` with direction reversed. ztls uses
`server.sendApplicationData` + `client.handleRecord` (the server-to-client path
uses `handleRecord` rather than `receiveApplicationData` because the client
dispatches through the event union). libssl uses `sslWriteAll(conn.server, ...)` +
`sslReadExact(conn.client, ...)`. rustls uses `conn.server.writer().write_all` +
`transfer` + `read_exact_app(conn.client.reader(), ...)`. The same warm-up
and transport asymmetries apply.

### `AppPingPong` — one client→server + one server→client per iteration

**ztls** (`benchZtlsPingPong`): per iteration, `client.sendApplicationData` +
`client.completeWrite` + `server.receiveApplicationData` +
`server.sendApplicationData` + `server.completeWrite` + `client.handleRecord`.
`b.setBytes(size * 2)`. One connected pair reused. No explicit warm-up.

**libssl** (`benchApp` with `.ping_pong`): per iteration, `sslWriteAll(client)` +
`sslReadExact(server)` + `sslWriteAll(server)` + `sslReadExact(client)`. One
warm-up round before the timed loop. `b.setBytes(size * 2)`.

**rustls** (`bench_app` with dir=2): per iteration, `client.writer().write_all` +
`transfer` + `server.reader().read_exact` + `server.writer().write_all` +
`transfer` + `client.reader().read_exact`. No explicit warm-up.
`b.setBytes(size * 2)` equivalent (bytes column = `iters * size`).

The same transport asymmetries apply. The `bytes/op` is doubled for all three,
so throughput columns are directly comparable.

EVP rows are deliberately not TLS-to-TLS rows. `RecordEncrypt` /
`RecordDecrypt` in ztls include TLS record framing, the inner content-type byte,
AAD construction, sequence-number-to-nonce construction, and AEAD
encrypt/decrypt. EVP `Encrypt` / `Decrypt` and `BulkEncryptOnce` /
`BulkDecryptOnce` measure only the raw OpenSSL AEAD primitive boundary with a
hard-coded AAD shape. They are useful as a crypto floor for interpreting ztls
record overhead, but they must not be presented as libssl or rustls equivalents.

Parser and framing microbenchmarks are also intentionally non-comparable:
`frame.parseHeader`, `RecordBuffer.next`, `server_hello.parse`, certificate
parsing, `WireReader`, `NewSessionTicket.parse`, nonce construction, and
SIMD/memory helper rows are ztls regression signals, not external TLS library
comparisons.

When publishing numbers, include only the comparable row groups in
ztls-vs-libssl-vs-rustls tables. Put ztls-only and EVP rows in separate tables
with labels that describe their narrower boundary. Do not quote mixed geomeans;
`bench-analyze` strips benchstat geomean rows so result review stays row-level.

## Methodology

- Build benchmarks with `-Doptimize=ReleaseFast` and a native CPU target. The
  build's default is native CPU; generic AArch64 silently selects std.crypto's
  software AES/GHASH paths and is not a useful performance target.
- Print machine/build metadata with each run: target, CPU model if available,
  Zig version, optimization mode, git revision. If a benchmark says
  `cpu generic`, do not use it for OpenSSL comparisons.
- Output machine-readable rows (`csv`-ish is enough): benchmark name, bytes,
  iterations, elapsed ns, throughput/op rate.
- Warm up before measuring where branch/cache effects matter.
- Avoid claiming performance from one local run. Commit the harness first; use
  `perf`, Instruments, or callgrind to explain results after they exist.
- Prefer instruction-count regression tracking later. Wall-time in containers or
  laptops is useful for development, not for 1% claims.

## Profiling tools

The devshell includes Linux-only `perf` and `valgrind`/`callgrind_annotate`.
Use wall-time benchmark output to choose a suspicious scenario, then profile the
compiled benchmark binary rather than adding timing probes to library code.
Containerized Linux may expose only a subset of perf events; if hardware cycles
show as unsupported, use callgrind for instruction counts or rerun on bare
metal.

Typical local development flow:

```sh
just bench --filter RecordEncrypt/TLS_AES_128_GCM_SHA256/1350
just bench-disasm
just bench-disasm-libcrypto
just bench-perf --filter record_encrypt --filter aes_128
perf report --input zig-out/benchmark.perf.data
```

Full comparison captures are a separate workflow:

```sh
just bench-capture-default
```

Each capture writes one run directory under `zig-out/perf/<timestamp>/` with
`metadata.txt`, `ztls.txt`, `evp.txt`, `libssl.txt`, and `rustls.txt`. This shape
is intended for remote benchmark hosts: rsync the run directory back, then run
`just bench-analyze zig-out/perf/<timestamp>` to compare the captured files with
`benchstat`. `bench-capture` maps `--count=N` to rustls `--samples=N` so rustls
emits independent outer samples; the analyzer excludes rustls groups with fewer
than two samples instead of producing fake `n=1` comparisons.

Committed capture evidence lives under `docs/research/perf/`. The historical
first EC2 result set is `docs/research/perf/20260613-182405-ec2-c7i-large/`.
The #11 remote-runner evidence is
`docs/research/perf/20260705-183821-ec2-c7i-large/` and
`docs/research/perf/20260705-194022-ec2-c7i-2xlarge/`, captured on clean EC2
hosts with raw ztls/EVP/libssl/rustls outputs, full metadata, and benchstat
analysis committed together. The first #31 row-level perf/disassembly evidence
is `docs/research/perf/20260705-215953-ec2-c7i-2xlarge-row-perf/`, captured on a
clean pinned `c7i.2xlarge` host for selected AES-GCM and ChaCha20-Poly1305
application-data rows. The non-equivalent full-handshake row has separate
transparency evidence in
`docs/research/perf/20260706-000535-ec2-c7i-2xlarge-handshake-row-perf/`.

All benchmark binaries accept fuzzy `--filter` plus structured filters:
`--bench <name>`, `--suite <substring>`, and `--size <bytes>`. `--bench` is an
exact row-name match; suite remains substring-based for convenience. Use the
structured filters for perf/disassembly work so one profile means one scenario,
not a whole family of rows.

The `record_encrypt_prepared` and `ztls_app_prepared_client_to_server` rows use
`RecordLayer.encryptPrepared` / `sendPreparedApplicationData`, where the caller
has already serialized plaintext into `out[5..]`. These rows measure the
copy-avoiding send path separately from the normal slice-to-record API.

The raw Zig build steps remain available when you want to bypass `just`:

```sh
zig build bench
zig build bench-bin
perf record --call-graph dwarf ./zig-out/bin/benchmark
perf report
```

For instruction counts, use `--filter` to avoid running callgrind over the full
suite; callgrind is deterministic but slow.

```sh
zig build bench-bin
valgrind --tool=callgrind --callgrind-out-file=callgrind.out \
  ./zig-out/bin/benchmark --filter chacha20
callgrind_annotate callgrind.out
```

For raw OpenSSL crypto comparison:

```sh
zig build bench-evp
zig build bench-evp-bin
zig-out/bin/evp_bench --filter aes_128
```

These EVP rows are not a TLS comparison. They isolate OpenSSL's AEAD
implementation and EVP setup/update/final overhead so ztls record numbers can
be interpreted against the crypto floor. The `Encrypt` / `Decrypt` rows keep the
EVP context and cipher/key setup alive across iterations, resetting only the IV
per operation; `BulkEncryptOnce` / `BulkDecryptOnce` create and initialize a new
EVP context inside each timed operation. This still does not make EVP a
no-allocation ztls core backend — OpenSSL 3 provider contexts allocate behind
the API.

For libssl machinery without kernel sockets:

```sh
zig build bench-openssl
zig build bench-openssl-bin
zig-out/bin/bio_bench --filter handshake
zig-out/bin/openssl_bio_bench --filter ping_pong
```

The memory-BIO rows include libssl and BIO overhead but exclude TCP/syscall
noise. That is the closest current comparison to ztls' no-I/O state-machine
model.

## Row-oriented perf and disassembly tooling

For explaining a wall-time delta on a specific row, the blunt `bench-perf` /
`bench-disasm` recipes above are not enough — they profile the entire binary.
The row-oriented tooling captures perf and disassembly for one implementation
and one row at a time, with stable output paths and metadata. `bench-perf-row`
accepts only ztls, libssl, and rustls TLS rows; EVP rows are raw-crypto floor
measurements and stay out of TLS row perf comparisons.

```sh
# Capture perf stat + perf record for one row (Linux only):
just bench-perf-row impl=ztls bench=AppPingPong suite=TLS_AES_128_GCM_SHA256 size=1350
just bench-perf-row impl=openssl bench=AppPingPong suite=TLS_AES_128_GCM_SHA256 size=1350
just bench-perf-row impl=rustls bench=AppPingPong suite=TLS_AES_128_GCM_SHA256 size=1350

# Disassemble a benchmark binary and its linked libraries (any host):
just bench-disasm-row impl=ztls
just bench-disasm-row impl=openssl
just bench-disasm-row impl=rustls
```

Output goes under `zig-out/perf/<timestamp>/` with row-specific subdirectories:

```text
zig-out/perf/<timestamp>/
  perf-row-<impl>-<bench>-<suite>-<size>/
    metadata.txt          # git rev, CPU, kernel, command line, linked libs,
                          # iteration counts for stat/record normalization
    perf.data             # raw perf record output
    perf-stat.txt         # perf stat counter summary
    perf-report.txt       # top symbols from perf report
    bench-output-stat.txt # benchmark stdout from the perf stat run
    bench-output-record.txt # benchmark stdout from the perf record run
  disasm-<impl>/
    metadata.txt
    binary.asm            # full disassembly of the benchmark binary
    symbols.txt           # nm symbol table
    libcrypto.asm         # if dynamically linked
    libssl.asm            # if dynamically linked (libssl binary only)
```

`zig-out/perf/` is local staging. Durable evidence is committed under
`docs/research/perf/<timestamp-host>/` alongside the wall-time capture and
benchstat analysis. Perf data is binary and large; commit it only for selected
durable rows. Disassembly text and annotated symbol output should be committed
for durable rows.

These scripts refuse to run `perf` on non-Linux hosts. Disassembly works on
any host via `objdump` (Linux) or `otool` (macOS fallback), but disassembly
produced on the wrong architecture (e.g. aarch64 when the committed capture is
x86_64) is not useful for explaining that capture. Use the row tooling on the
same host class as the wall-time capture you want to explain.

Committed row-level perf/disassembly evidence lives under
`docs/research/perf/20260705-215953-ec2-c7i-2xlarge-row-perf/` for selected
AES-GCM and ChaCha20 application-data rows, produced by `just
bench-remote-perf-rows` on a clean pinned `c7i.2xlarge` host. The non-equivalent
full-handshake row has separate transparency evidence under
`docs/research/perf/20260706-000535-ec2-c7i-2xlarge-handshake-row-perf/`.
Producing fresh durable Linux x86_64 perf evidence requires the EC2 workflow
(#11) or equivalent bare-metal access.

## Results and conclusions

This section states what the committed evidence shows. It is the performance
claim, not the methodology. The methodology above defines the boundary; the
captures under `docs/research/perf/` are the raw evidence; the row-perf
explanations tie wall-time deltas to counters and symbols. This section folds
those into the claim ztls can make.

### Evidence basis

Three n=10 wall-time captures cover the three platforms:

- **x86_64:**
  `docs/research/perf/20260712-102422-ec2-c7i-2xlarge/benchstat.txt` — a clean
  `c7i.2xlarge` (Intel Xeon Platinum 8488C, x86_64) EC2 host, OpenSSL 3.6.3,
  rustls 0.23.40, Zig 0.15.2 ReleaseFast, git revision
  `2c102a50995f56fad50adf4afb8ec092757480cd`, `--count 10 --benchtime 500ms`.
  This n=10 capture supersedes the provisional n=5 capture
  (`docs/research/perf/20260705-194022-ec2-c7i-2xlarge/`) as the canonical
  x86_64 baseline. A second committed capture on `c7i.large`
  (`docs/research/perf/20260705-183821-ec2-c7i-large/`) confirms the same
  ordering on a smaller instance shape.

- **aarch64 Linux:**
  `docs/research/perf/20260712-201912-ec2-c7g-2xlarge/benchstat.txt` — a clean
  `c7g.2xlarge` (AWS Graviton3, aarch64) EC2 host, OpenSSL 3.6.3, rustls 0.23.41,
  Zig 0.15.2 ReleaseFast, git revision `e39f5a6dd38bbad644a4a2187d51e7370df6caaf`,
  `--count 10 --benchtime 500ms`.

- **macOS (Apple Silicon):**
  `docs/research/perf/20260713-003534-macos-m1max/benchstat.txt` — an Apple M1 Max
  (arm64, Darwin 24.6), OpenSSL 3.6.3, rustls 0.23.41, Zig 0.15.2 ReleaseFast,
  git revision `80083f50505d46bbbea6e6a4cee688925667a9a5`, `--count 10 --benchtime
  500ms`.

Row-level perf/disassembly evidence for the x86_64 headline AES-GCM row and
the small-record ChaCha20 row is under
`docs/research/perf/20260705-215953-ec2-c7i-2xlarge-row-perf/explanations/`.

All three n=10 captures produce formal confidence intervals (`± 0%` to `± 5%`
across rows) and p=0.000 for every comparable row. The deltas are large
(the smallest ztls win on a comparable AES-GCM row is +69.86% on x86_64; the
largest is +261%), so the result is decisive, not marginal.

### The claim

Across the 45 comparable TLS application-data rows (3 directions × 5 payload
sizes × 3 cipher suites), on all three platforms (x86_64 `c7i.2xlarge`,
aarch64 `c7g.2xlarge`, and macOS Apple M1 Max):

1. **ztls is faster than OpenSSL libssl on every comparable app-data row, on
   all three platforms.** The delta ranges from +4% (ChaCha20, 16384B
   ping-pong, aarch64) to +261% (AES-128-GCM, 16B client→server, x86_64).
   ztls reaches the OpenSSL AEAD primitive with substantially less TLS
   wrapper work than libssl's memory-BIO path.

2. **ztls is faster than rustls on all AES-GCM rows on all three platforms**
   (30 rows each: AES-128-GCM and AES-256-GCM, all three directions, all five
   sizes). On x86_64 the delta ranges from +69.86% to +131%; on aarch64 from
   +39.30% to +78%; on macOS from +59.51% to +127%. ztls executes fewer cycles,
   fewer instructions, and fewer branches than rustls on the x86_64 AES-GCM
   ping-pong row (see the row-perf explanation: ztls ~54.8% of rustls
   cycles/op, ~53.6% of rustls instructions/op).

3. **ztls is faster than rustls on large ChaCha20 records on all three
   platforms** (8192B and 16384B: x86_64 +66% to +87%, aarch64 +4% to +8%,
   macOS +20% to +21%) and approximately ties at 1350B.

4. **The ChaCha20 small-record comparison with rustls is platform-dependent.**
   On x86_64, ztls is slower than rustls on small ChaCha20 records (16B and
   128B: -50% to -56%) — rustls's ring ChaCha20-Poly1305 path is cheaper for
   tiny records than ztls's OpenSSL EVP path. The row-perf evidence shows the
   ztls samples are overwhelmingly in OpenSSL's ChaCha20 symbols, not in ztls
   record framing — so the fix is a backend-specific faster ChaCha path, not
   record-path work. On aarch64 (Graviton), this loss largely disappears: 16B
   is a tie, rustls is ~20% faster at 128B, ztls wins from 1350B upward. On
   macOS (Apple Silicon), ztls actually WINS at 16B (+8% to +12%), loses only
   at 128B (-19% to -24%), and wins from 1350B upward. OpenSSL's ARM NEON
   ChaCha20 is more competitive with ring's ARM path than the x86_64 EVP path
   is with ring's AVX path. The x86_64 small-record loss is documented, not
   hidden.

### Headline rows

The rows that matter most for the positioning story (real-world TLS payloads
are typically AES-GCM, with 1350B near the common MTU boundary):

| Row | ztls | OpenSSL libssl | rustls | ztls vs libssl | ztls vs rustls |
|---|---:|---:|---:|---:|---:|
| **x86_64 (c7i.2xlarge)** ||||||
| AppPingPong AES-128-GCM 1350 | 790.7 ns | 1820.5 ns | 1447.5 ns | 2.30× faster | 1.83× faster |
| AppPingPong AES-128-GCM 16384 | 4.183 µs | 7.422 µs | 9.654 µs | 1.77× faster | 2.31× faster |
| AppClientToServer AES-128-GCM 1350 | 392.0 ns | 932.1 ns | 720.9 ns | 2.38× faster | 1.84× faster |
| AppPingPong ChaCha20 16384 | 17.16 µs | 20.77 µs | 32.08 µs | 1.21× faster | 1.87× faster |
| AppPingPong ChaCha20 16 | 2.267 µs | 3.947 µs | 1.018 µs | 1.74× faster | 0.45× (loss) |
| **aarch64 (c7g.2xlarge, Graviton4)** ||||||
| AppPingPong AES-128-GCM 1350 | 1.929 µs | 3.602 µs | 2.714 µs | 1.87× faster | 1.41× faster |
| AppPingPong AES-128-GCM 16384 | 11.08 µs | 14.21 µs | 19.74 µs | 1.28× faster | 1.78× faster |
| AppPingPong ChaCha20 16384 | 54.91 µs | 57.09 µs | 59.56 µs | 1.04× faster | 1.08× faster |
| AppPingPong ChaCha20 16 | 1.868 µs | 3.408 µs | 1.897 µs | 1.82× faster | 1.02× (tie) |
| **macOS (Apple M1 Max)** ||||||
| AppPingPong AES-128-GCM 1350 | 1.040 µs | 2.087 µs | 1.883 µs | 2.01× faster | 1.81× faster |
| AppPingPong AES-128-GCM 16384 | 8.221 µs | 11.593 µs | 14.497 µs | 1.41× faster | 1.76× faster |
| AppPingPong ChaCha20 16384 | 37.23 µs | 42.30 µs | 45.23 µs | 1.14× faster | 1.21× faster |
| AppPingPong ChaCha20 16 | 1.226 µs | 2.153 µs | 1.372 µs | 1.76× faster | 1.12× faster |

### Why ztls wins (mechanism, not assertion)

The row-perf explanations tie the wall-time deltas to objective counter and
symbol evidence, so the claim is not just adjacent benchstat columns:

- **vs OpenSSL libssl:** ztls's caller-owned record path calls the OpenSSL
  AEAD primitive directly. libssl's memory-BIO path adds `WPACKET`,
  `EVP_CIPHER_CTX_ctrl`, `EVP_CipherInit_ex`, and `tls13_cipher` wrapper work
  on top of the same primitive. On `AppPingPong/AES-128-GCM/1350`, ztls
  executes 42.7% of libssl's cycles/op and 41.5% of its instructions/op.

- **vs rustls (AES-GCM):** ztls reaches OpenSSL's VAES-AVX512 AES-GCM path
  with less buffer/copy/allocator work than rustls's in-memory `Vec` transfer
  shim. On the same row, ztls executes 54.8% of rustls's cycles/op and 53.6%
  of its instructions/op. rustls shows `ChunkVecBuffer::write_to`,
  `__memmove_avx512_unaligned_erms`, and `__libc_malloc2` in its hot symbols.

- **vs rustls (ChaCha20, small records):** rustls's ring ChaCha20-Poly1305
  path is cheaper for tiny records than ztls's OpenSSL EVP ChaCha20-Poly1305
  path. On `AppClientToServer/ChaCha20/16`, rustls executes 45.0% of ztls's
  cycles/op. The ztls samples are dominated by OpenSSL's
  `chacha20_poly1305_aead_cipher` / `ChaCha20_avx512` symbols, not ztls
  framing code. The cycle gap exceeds the instruction gap, so the primitive
  implementation efficiency matters more than wrapper code volume here.

### What this is not

- Not a handshake performance claim. The `Handshake` row is non-equivalent
  (ztls does real CertificateVerify verification; rustls `NoVerifier` does
  none; libssl `SSL_VERIFY_NONE` is opaque). No cross-implementation handshake
  performance claim is allowed from the current evidence.
- The committed evidence covers x86_64 Linux, aarch64 Linux, and macOS
  (Apple Silicon). Other macOS hosts (Intel Macs) and other Linux distros are
  not measured. The claim is platform-bounded to what was captured.
- Not a crypto-primitive claim. EVP rows are a crypto floor, not a TLS
  comparison. ztls-only diagnostic rows are not cross-implementation.
- Not a claim that ignores the ChaCha20 small-record loss. That loss is real,
  explained, and documented above. It is x86_64-specific and shrinks or reverses
  on ARM/MacOS.

## Acceptance thresholds and regression gate

### Repetition policy

Benchmark evidence is not CI-gated — EC2 benchmark runs are too expensive and
too noisy for PR-level CI. Instead, the gate is a committed baseline plus a
manual re-run policy:

1. **Baseline.** A committed capture under `docs/research/perf/` is the
   reference baseline for regression detection. The canonical baseline is the
   n=10 `20260712-102422-ec2-c7i-2xlarge` capture (formal CIs, p=0.000).
   The baseline's `benchstat.txt` is the comparator.

2. **When to re-run.** Re-run `just bench-remote-capture --instance-types
   c7i.2xlarge --count 10 --benchtime 500ms` before any release, after any
   change to the record protection path (`src/aead.zig`, `src/record.zig`,
   `src/crypto/backend*.zig`), or after any change to the benchmark harness
   (`src/bench/`, `bench/`). A re-run that does not regress the headline rows
   beyond their thresholds supersedes the old baseline.

3. **What passes.** A re-run passes if, on every comparable AES-GCM row, ztls
   `sec/op` does not regress by more than 15% versus the baseline, and ztls
   remains faster than libssl on every comparable row. The 15% threshold is
   generous because the current deltas are 66–253%: a 15% ztls regression
   would not change the claim. The threshold exists to catch silent
   regressions, not to chase 1% noise.

4. **What fails.** A ztls regression beyond 15% on any headline AES-GCM row,
   or ztls losing to libssl on any comparable AES-GCM row, fails the gate. The
   change must either be fixed or the conclusion and baseline must be updated
   with an honest explanation in the same change.

### Regression check recipe

`just bench-regression-check` runs a fresh capture on EC2 and compares the
comparable TLS rows against the committed baseline with benchstat. It requires
the same AWS access as `bench-remote-capture`. See the recipe in `just/bench.just`.
