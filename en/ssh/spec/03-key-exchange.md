# 03 · Algorithm Negotiation and Key Exchange

> Normative basis: RFC 4253 §7–§9 (Key Exchange / Key Derivation / Rekey), §8 (DH group14);
> RFC 5656 (ECDH, NIST curves); RFC 8731 (curve25519-sha256); RFC 8268 (group14/16 + SHA-2);
> RFC 4419 (group exchange); RFC 8308 (Extension Negotiation);
> `kex-strict-*-v00@openssh.com` in OpenSSH `PROTOCOL` (Terrapin mitigation, CVE-2023-48795);
> RFC 10042 (ML-KEM hybrids: `mlkem768x25519-sha256` and the two NIST-curve ones; draft-kampanakis-curdle-ssh-pq-ke before publication);
> FIPS 203 (ML-KEM); the sntrup761 hybrid in OpenSSH `PROTOCOL`.
>
> Corresponding implementation: `Crypto/` (L3) and `Session/` (the `KeyExchange` / `Rekeying` states of L4).
>
> **This is the longest document in the whole specification, and the one that least tolerates mistakes.** Every byte-order error here
> surfaces as the same "signature verification failed", and is extremely expensive to track down.
> 中文：[`../../../zh/ssh/spec/03-key-exchange.md`](../../../zh/ssh/spec/03-key-exchange.md)

---

## 1 Overview sequence

```mermaid
sequenceDiagram
    participant C as Client (us)
    participant S as Server

    Note over C,S: Version exchange complete, sequence number = 0

    par Both sides send simultaneously, without waiting
        C->>S: SSH_MSG_KEXINIT (I_C)
    and
        S->>C: SSH_MSG_KEXINIT (I_S)
    end

    Note over C,S: Each side computes the mutually supported algorithm set per the rules of §2

    C->>S: KEX-method-specific INIT (30) —— client public key
    S->>C: KEX-method-specific REPLY (31) —— K_S ‖ server public key ‖ sig(H)

    Note over C: ① Compute shared secret K<br/>② Assemble exchange hash H (§4)<br/>③ Verify sig(H) with K_S<br/>④ Host key policy rules on K_S (§5)

    par Both sides send simultaneously
        C->>S: SSH_MSG_NEWKEYS (21)
    and
        S->>C: SSH_MSG_NEWKEYS (21)
    end

    Note over C,S: Each side switches to the new keys; with strict KEX both sequence numbers reset to 0
```

**Two concurrency facts that must be remembered**:

1. `KEXINIT` is **sent by both sides simultaneously**; it is not request-response. Either may arrive first; both are legal.
2. `NEWKEYS` is also bidirectional, and **the directions are independent**:
   - **After sending** `NEWKEYS`, the next packet we send uses the new send keys;
   - **After receiving** `NEWKEYS`, the next packet we receive uses the new receive keys.
   The two switch points **do not wait for each other**. Merging them into a single "switch moment" is a common mistake;
   the symptom is sporadic decryption failures on fast links.

---

## 2 `SSH_MSG_KEXINIT` (20)

### 2.1 Field table

| # | Type | Field | Description |
| :-: | --- | --- | --- |
| 1 | `byte` | `SSH_MSG_KEXINIT` = 20 | |
| 2 | `byte[16]` | `cookie` | **MUST** be a cryptographically random value. Prevents either side from determining `H` alone |
| 3 | `name-list` | `kex_algorithms` | Contains indicators, see §2.3 |
| 4 | `name-list` | `server_host_key_algorithms` | |
| 5 | `name-list` | `encryption_algorithms_client_to_server` | |
| 6 | `name-list` | `encryption_algorithms_server_to_client` | |
| 7 | `name-list` | `mac_algorithms_client_to_server` | |
| 8 | `name-list` | `mac_algorithms_server_to_client` | |
| 9 | `name-list` | `compression_algorithms_client_to_server` | |
| 10 | `name-list` | `compression_algorithms_server_to_client` | |
| 11 | `name-list` | `languages_client_to_server` | Always sent empty |
| 12 | `name-list` | `languages_server_to_client` | Always sent empty |
| 13 | `boolean` | `first_kex_packet_follows` | See §2.4 |
| 14 | `uint32` | `0` (reserved) | **MUST** send 0; a non-zero value received **MUST** be ignored rather than treated as an error |

**The payload of the whole message (from the message number byte up to the final `uint32`) MUST be saved verbatim** ——
it is exactly `I_C` / `I_S` in the exchange hash (§4).

> Implementation note: what is saved is the **payload**, not the whole frame. It excludes `packet_length`, `padding_length`, padding and MAC.

### 2.2 Negotiation rule (RFC 4253 §7.1)

For each algorithm category, independently:

> Take the first name in the **client's list** that **also appears in the server's list**.

Note three things:

1. **The client's order prevails** —— so the order of our lists is our preference (General Provisions §7).
2. **Each category is negotiated independently**, without affecting the others —— with one exception:
   the eligible set of host key algorithms is constrained by the KEX method (some KEX methods require the host key to be capable of signing/encryption;
   all the KEX methods we support require only signing, so this constraint always holds in this implementation).
3. **No intersection in any category → negotiation fails**, throwing `SshNegotiationException`,
   **with both sides' complete lists and the peer's version string included in the exception** (see [`08-failures.md`](08-failures.md)).
   This is this library's most direct improvement over existing libraries: what the user gets is not
   "No common encryption algorithm.", but "the peer offered only aes128-cbc;
   we support chacha20-poly1305@openssh.com, aes256-gcm@openssh.com, …" ——
   from which it is obvious at a glance that the peer has nothing but CBC left, and this library does not implement CBC (General Provisions §6.3).

**The AEAD special case**: when the negotiated encryption algorithm is AEAD (`*-gcm@openssh.com`,
`chacha20-poly1305@openssh.com`), **the result of the MAC list negotiation for that direction is ignored**;
integrity is provided by the AEAD itself. We still **MUST** send a non-empty MAC list ——
not sending one would make it impossible for peers that support only non-AEAD to negotiate with us.

〔Decision〕**Our own lists are validated before dialing** (`SshAlgorithmSet.Validate()`, called when connecting starts):

- none of the eight lists may be empty —— an empty list cannot be negotiated with any peer;
- every name in the key exchange list is either a method this library implements (the fixed table in `SshKeyExchangeFactory`; nothing can be registered at runtime) or one of the indicators of §2.3;
- every name in the encryption, MAC and compression lists must be one this library implements (for compression that is only `none` and `zlib@openssh.com`).

Otherwise `ArgumentException` is thrown on the spot and **no dialing happens at all**.
Rationale: a name we do not implement that slips into the list only gets negotiated when the peer happens to have nothing else left ——
the failure then happens during key derivation, surfaces as an unexplained "not implemented", and shows up only when connecting to that one device.
Reporting it here points the error at the configuration itself.
Host key algorithm names are **not checked here**: they are guarded by host key parsing and signature verification (§5.3), where an unknown type gets an explicit error.

〔Decision〕**Each list is copied into a read-only snapshot when it is set**, so later changes to the caller's own copy do not affect the list already handed over.
The caller's collection used to be stored as-is: pass in a `List`, change it after validation, and since the connection keeps that list in its re-keying context,
the next re-key uses the changed, unvalidated list; the arrays in `SshAlgorithmSet.Default` could be changed by a downcast, and the two directions of encryption and of MAC even shared one array.
Setting `null` throws `ArgumentNullException` on the spot. For the same reason `SshAlgorithmSet` compares equal by list contents (order included), not by reference. The same rule applies to `AgentForwardOptions.AllowedKeys` and `SftpFileAttributes.Extended`.

### 2.3 The three indicators hidden in `kex_algorithms`

These three names **are not key exchange methods**; they are flags stuffed into the same list.
The client **MUST** put them in the list, but **MUST NOT** treat them as a negotiation result.

| Name | Sent by | Meaning |
| --- | --- | --- |
| `ext-info-c` | Client | I support RFC 8308 extension negotiation; please send me `SSH_MSG_EXT_INFO` |
| `ext-info-s` | Server | The same thing on the server side (as a client we only read it, never send it) |
| `kex-strict-c-v00@openssh.com` | Client | I support strict KEX (§6) |
| `kex-strict-s-v00@openssh.com` | Server | The server supports strict KEX |

〔Decision〕**`ext-info-c` and `kex-strict-c-v00@openssh.com` are always sent, and only in the first KEXINIT.**
RFC 8308 §2.2 explicitly requires `ext-info-c` to appear only in the **first** KEXINIT;
sending it again during rekeying is a protocol violation, and some servers will disconnect.

**Indicators MUST be placed at the end of the list**, to avoid being mistakenly selected as a negotiation result (although matching by name would not select them anyway,
placing them at the end makes it obvious at a glance that they are not candidates).

### 2.4 `first_kex_packet_follows` (guessed KEX)

The sender may send, **immediately** after KEXINIT, the KEX INIT packet it guesses will be needed, saving one RTT.
If the guess is wrong (the negotiated KEX method or host key algorithm differs from the guess), the receiver **MUST ignore** that packet.

〔Decision〕**We always send `false`, and correctly handle a peer's `true` on receipt.**

Rationale:
- Not used on the sending side: a correct guess saves 1 RTT; a wrong guess wastes one public key (for the ML-KEM hybrid that is a 1KB+ packet)
  and requires handling the state branch "what I guessed differs from what was negotiated". **The complexity of that branch is not worth that one RTT** ——
  our means of saving RTTs are the send coalescing and adaptive windows of §7, which are effective throughout the connection,
  whereas guessed KEX is effective only once, at connection setup.
- The receiving side **MUST** implement it: OpenSSH servers use it in some configurations.
  On receiving `first_kex_packet_follows = true`: if the negotiation result matches the peer's first preference, process that packet normally;
  otherwise **discard it** (the entire packet is discarded; the sequence number is incremented as usual).

> The rule for deciding "did the peer guess correctly" (RFC 4253 §7.1):
> whether both the **first** entry of the peer's `kex_algorithms` and the **first** entry of its `server_host_key_algorithms`
> equal the final negotiation result. Only if both are equal does the guess count as correct.

---

## 3 Key exchange methods

### 3.1 Common shape

All KEX methods we support have the same two-step shape; only the public key content differs:

| Direction | Number | Content |
| --- | :-: | --- |
| C → S | 30 | The client's ephemeral public key `Q_C` (`string`) |
| S → C | 31 | `string K_S` ‖ `string Q_S` ‖ `string signature` |

- `K_S` is **the blob of the server's host public key** (format in §5.1).
- `signature` is the signature over **the exchange hash `H`** made with the host private key (format in §5.2).
- The algorithm for the shared secret `K` varies (see below), but it **always enters `H` as either an `mpint` or a `string`**
  —— this differs between methods and is the easiest place to go wrong; it is listed item by item below.

> Numbers 30/31 are **method-specific**; different KEX methods may assign them different meanings
> (see the comment in `Protocol/SshMessageNumber.cs`: 30–49 are deliberately kept out of the global enum).
> Almost all the methods we support use the 30/31 pair; only `diffie-hellman-group-exchange-*`
> has an additional set of preceding messages and then switches to 32/33; see §3.5.

### 3.2 `curve25519-sha256` (RFC 8731)

| Item | Value |
| --- | --- |
| Hash | SHA-256 |
| `Q_C` / `Q_S` | 32-byte X25519 public key, encoded as `string` |
| `K` | X25519 shared secret (32 bytes), **encoded into `H` as `mpint`** |

**Three MUSTs**:

1. `Q_C` / `Q_S` **MUST** be exactly 32 bytes long; otherwise it is a protocol error.
2. **If the X25519 result is all zeros, the exchange MUST be aborted** (the contributory behaviour requirement of RFC 7748 §6.1).
   All zeros means the peer supplied a low-order point.
3. `K` enters `H` as an `mpint` —— meaning **a `0x00` must be prepended when the top bit is 1, and leading zeros must be stripped**
   (General Provisions §3.1). Stuffing it in directly as a fixed 32 bytes is the most common mistake; the symptom is
   "about 1/256 of connections fail signature verification" —— a probabilistic failure that is extremely hard to diagnose.

`curve25519-sha256@libssh.org` is **exactly the same**; only the name differs (for historical reasons).
Both names are sent, and they share one implementation.

### 3.3 `ecdh-sha2-nistp256 / 384 / 521` (RFC 5656)

| Curve | Hash | `Q` encoding |
| --- | --- | --- |
| nistp256 | SHA-256 | Uncompressed point `0x04 ‖ X ‖ Y`, as `string` |
| nistp384 | SHA-384 | Same as above |
| nistp521 | SHA-512 | Same as above |

- `K` is the **X coordinate** of the shared point, encoded into `H` as `mpint`.
- **The peer's public key point MUST be verified to be on the curve** and not the point at infinity.
  .NET's `ECDiffieHellman.ImportSubjectPublicKeyInfo` / `ECParameters` validation does this,
  **but it MUST be confirmed that the exception is correctly translated into a protocol error rather than leaking out**.
  〔Decision〕**The library checks first, before importing**: both coordinates are less than p, and y² = x³ − 3x + b (mod p) holds (the three SEC 2 curves all have a = −3).
  The platform layer differs per platform (CNG on Windows, OpenSSL on Linux, Apple on macOS) and used to be verified only on Windows;
  an encoding with a coordinate not less than p is congruent to the point minus p, so the equation still holds and it must be rejected separately. All zeros (the point at infinity cannot be written) gives 0 = b and is rejected along the way.
- 〔Note〕The coordinates of nistp521 are 66 bytes (521 bits); `0x04 ‖ X ‖ Y` totals 133 bytes.
  Implementations that hard-code an assumption of 64 or 65 bytes will crash on this curve.

### 3.4 `diffie-hellman-group14-sha256` / `group16-sha512` (RFC 8268)

| Name | Group | Hash |
| --- | --- | --- |
| `diffie-hellman-group14-sha256` | MODP 2048-bit (RFC 3526 Group 14) | SHA-256 |
| `diffie-hellman-group16-sha512` | MODP 4096-bit (RFC 3526 Group 16) | SHA-512 |
| `diffie-hellman-group14-sha1` | Group 14 | SHA-1. **Off by default**, 〔Interop〕old devices |

- `e = g^x mod p` (client), `f = g^y mod p` (server), both as `mpint`.
- `K = f^x mod p`, as `mpint`.
- **MUST validate** `1 < e,f < p-1`. Not validating amounts to accepting small-subgroup attacks.
- The bit length of the private exponent `x` **SHOULD** be at least twice the hash output (the recommendation of RFC 4253 §8).
  〔Decision〕Uniformly use **2× the hash length** (group14-sha256 → 512 bits), not the full bit width of the group ——
  the full width brings no additional security, it only makes modular exponentiation much slower.

### 3.5 `diffie-hellman-group-exchange-sha256` (RFC 4419)

> **Implementation status (2026-10-06)**: **implemented** (`DiffieHellmanGroupExchange`). In the default list it comes after the elliptic curves and before the DH standard groups ——
> the client's order wins, so it is only chosen when nothing else can be agreed. Checked against a real OpenSSH 10.3 (initial exchange and rekey);
> since OpenSSH 10 the server does not enable the DH methods by default, so the interop environment appends it to the server's list with `scripts/ssh/interop/kex-gex.sh`.

**Two more messages than the other methods**, because the group is supplied by the server on the fly according to the client's request:

| Direction | Number | Content |
| --- | :-: | --- |
| C → S | 34 `GEX_REQUEST` | `uint32 min` ‖ `uint32 n` (preferred) ‖ `uint32 max` |
| S → C | 31 `GEX_GROUP` | `mpint p` ‖ `mpint g` |
| C → S | 32 `GEX_INIT` | `mpint e` |
| S → C | 33 `GEX_REPLY` | `string K_S` ‖ `mpint f` ‖ `string signature` |

> Note that the numbers **conflict with other methods**: here 31 is `GEX_GROUP`, whereas in curve25519 31 is `KEX_ECDH_REPLY`.
> This is exactly why the 30–49 range must be interpreted according to "the currently negotiated KEX method" and cannot have a global enum.

- 〔Decision〕`min = 2048`, `n = 3072`, `max = 8192`.
  **A `p` smaller than 2048 bits supplied by the server is not accepted** —— after logjam (CVE-2015-4000), 1024 bits is unacceptable.
- **MUST validate** that `p` is prime, that `g` is in a reasonable range (`1 < g < p-1`), and that the bit length of `p` falls within our requested `[min, max]`.
  The cheap checks come first (bit length, parity, the range of `g`), then the primality test.
- Primality testing uses BouncyCastle's `Primes.HasAnySmallFactors` and `Primes.IsMRProbablePrime` (Miller-Rabin, random bases, **64 rounds**,
  so a composite passes with probability ≤ 4⁻⁶⁴). 〔Decision〕**We do not write Miller-Rabin ourselves** —— the BCL has no such API and BC does (the ssh library's AGENTS 3.3: "do not write cryptographic primitives").
- 〔Decision〕The primality test is the real cost of this method: BC running 64 rounds on one thread takes about 2 seconds at 3072 bits and over half a minute at 8192 bits. Three things bring it down:
  1. **Rounds in parallel**: each round uses an independent random base, and the rounds are spread over the thread pool by core count (each call is `IsMRProbablePrime(p, random, 1)`);
  2. **Overlapped with the round trip**: it starts in the background as soon as `GEX_GROUP` arrives, while `GEX_INIT` is sent and `GEX_REPLY` awaited; its verdict is awaited only before computing the shared secret;
  3. **Cached**: a verified `p` is remembered in the process keyed by `SHA-256(p)` (at most 64, cleared when full), so a server reusing a group is not tested again.
     Only "is prime" is remembered —— a connection with a composite `p` has failed anyway.

  Against a real OpenSSH (a 3072-bit group) a whole connection takes about 0.4–0.5 seconds.
- The inputs of `H` **include** `min ‖ n ‖ max ‖ p ‖ g`; see §4.2.

### 3.6 Post-quantum hybrids: `mlkem768x25519-sha256` and `sntrup761x25519-sha512`

Both have the same shape: **a KEM run in parallel with X25519**, with the shared secret being the hash of both results.
The basis of `mlkem768x25519-sha256` is RFC 10042 §2.3.3 (draft-kampanakis-curdle-ssh-pq-ke before publication), which agrees with this section;
the two other methods in the same RFC, which replace X25519 with a NIST curve, are in §3.7.

| Method | KEM | Hash | Client sends | Server sends |
| --- | --- | --- | --- | --- |
| `mlkem768x25519-sha256` | ML-KEM-768 | SHA-256 | `ek_pq ‖ Q_C` (1184 + 32 bytes) | `ct_pq ‖ Q_S` (1088 + 32 bytes) |
| `sntrup761x25519-sha512` | sntrup761 | SHA-512 | `pk_pq ‖ Q_C` (1158 + 32) | `ct_pq ‖ Q_S` (1039 + 32) |

- The two parts are **concatenated and encoded as a single `string`**, not as two `string`s.
- Shared secret: `K = HASH(K_pq ‖ K_x25519)`, where `HASH` is the method's hash.
  〔Critical〕**Here `K` is a `string` (fixed at 32 or 64 bytes), not an `mpint`.**
  This is the **fundamental difference** from §3.2/§3.3/§3.4 —— the post-quantum hybrid methods deliberately switched to a fixed-length `string`
  precisely to avoid the `mpint` leading-zero problem. **Get this wrong and the symptom is, again, probabilistic signature failure.**
- ML-KEM is available in the .NET 11 BCL (`System.Security.Cryptography.MLKem`);
  sntrup761 is not, and must be implemented ourselves or taken from BouncyCastle.
  〔Decision〕When `MLKem.IsSupported` (CNG on Windows, OpenSSL 3.5 onwards) ML-KEM-768 goes through the BCL, otherwise it falls back to BouncyCastle;
  a test pins down that the two implementations interoperate (one side generates, the other encapsulates). It used to go through BouncyCastle unconditionally.
  〔Decision〕**M1 does only `mlkem768x25519-sha256`**; sntrup761 is deferred to M5,
  because OpenSSH 9.9+ already ranks ML-KEM first, and sntrup761 is only for compatibility with 8.5–9.8.
- `sntrup761x25519-sha512@openssh.com` is the old name of the same algorithm (used by OpenSSH < 9.9).

### 3.7 FIPS-oriented post-quantum hybrids: `mlkem768nistp256-sha256` and `mlkem1024nistp384-sha384`

> Basis: RFC 10042 §2.1–§2.5 (shape of the hybrid exchange, message numbers, method names, shared secret `K`, exchange hash), §3 (message size), §5 (fresh ephemeral keys for every exchange);
> FIPS 203 Table 3 (ML-KEM sizes), §7.3 (decapsulation input checks), §3.3 (destruction of intermediate values);
> RFC 5656 §4 and SEC 1 §2.3.3–§2.3.5, §3.2.2 (EC point encoding, fixed-length field element encoding, public key validation).
>
> **Implementation status (2026-10-07)**: **implemented** (F12, `HybridKeyExchange`); the results against a real server are in §3.7.7.

The shape is exactly that of §3.6 —— **a KEM run in parallel with one elliptic-curve DH** —— except that the classical half is the NIST-curve ECDH of §3.3 instead of X25519.
Both use only FIPS-approved primitives (ML-KEM, ECDH on P-256 / P-384, SHA-2): servers in FIPS mode, which offer neither X25519 nor sntrup761, reach post-quantum key exchange through them.

| Method | KEM | Curve | Hash | Client sends `C_INIT` | Server sends `S_REPLY` | `K_CL` | `K` |
| --- | --- | --- | --- | --- | --- | --- | --- |
| `mlkem768nistp256-sha256` | ML-KEM-768 | P-256 | SHA-256 | `ek_pq ‖ Q_C`: 1184 + 65 = **1249** bytes | `ct_pq ‖ Q_S`: 1088 + 65 = **1153** bytes | 32 bytes | 32 bytes |
| `mlkem1024nistp384-sha384` | ML-KEM-1024 | P-384 | SHA-384 | `ek_pq ‖ Q_C`: 1568 + 97 = **1665** bytes | `ct_pq ‖ Q_S`: 1568 + 97 = **1665** bytes | 48 bytes | 48 bytes |

- `ek_pq` is the ML-KEM encapsulation key and `ct_pq` the ML-KEM ciphertext (sizes per FIPS 203 Table 3; the ML-KEM shared secret is always 32 bytes).
- `Q_C` / `Q_S` are uncompressed EC points `0x04 ‖ X ‖ Y` (32-byte coordinates on P-256, 48-byte on P-384), encoded as in §3.3.

#### 3.7.1 Messages

The numbers are the 30 / 31 of §3.1; RFC 10042 calls them `SSH_MSG_KEX_HYBRID_INIT` / `SSH_MSG_KEX_HYBRID_REPLY`
(OpenSSH's debug log still shows them as `SSH2_MSG_KEX_ECDH_INIT` / `SSH2_MSG_KEX_ECDH_REPLY` for these two methods —— it is the same pair of numbers).

`SSH_MSG_KEX_HYBRID_INIT` (30, C → S)

| # | Type | Field | Notes |
| :-: | --- | --- | --- |
| 1 | `byte` | 30 | |
| 2 | `string` | `C_INIT` | `ek_pq` immediately followed by `Q_C`, **the two parts concatenated into one `string`** (not two). KEM first, EC point second |

`SSH_MSG_KEX_HYBRID_REPLY` (31, S → C)

| # | Type | Field | Notes |
| :-: | --- | --- | --- |
| 1 | `byte` | 31 | |
| 2 | `string` | `K_S` | Server host public key blob (§5.1) |
| 3 | `string` | `S_REPLY` | `ct_pq` immediately followed by `Q_S`, again one `string`, KEM first |
| 4 | `string` | `signature` | Signature over `H` made with the host private key (§5.2) |

The inputs of the exchange hash `H` are exactly the eight items of §4.1: item 6 is `string C_INIT`, item 7 is `string S_REPLY`, item 8 is `string K`, and `HASH` is the method's hash.

#### 3.7.2 Shared secret `K`

1. `K_PQ`: decapsulate `ct_pq` with the ML-KEM decapsulation key generated for this exchange, giving 32 bytes.
2. `K_CL`: ECDH between our EC private key and `Q_S`; take the **X coordinate** of the shared point and encode it big-endian at a **fixed length** —— 32 bytes on P-256, 48 bytes on P-384,
   **leading zeros kept** (the field-element-to-octet-string conversion of SEC 1 §2.3.5; RFC 10042 §2.4 phrases it as re-encoding the `mpint` that plain ECDH would produce as a fixed-length byte string).
3. `K = HASH(K_PQ ‖ K_CL)`: **the KEM result first**, `HASH` being the method's hash. This gives 32 bytes (SHA-256) or 48 bytes (SHA-384).
4. `K` is encoded as a **`string`** both in the exchange hash (§4.1 item 8) and in key derivation (§7) (a `uint32` length of 32 / 48 followed by the raw bytes), **not as an `mpint`**.

〔Critical〕There are two "fixed lengths" here, each matching a probabilistic signature failure whose only symptom is "signature verification failed":

- If `K_CL` has its leading zeros stripped the way an `mpint` would (§3.3 habits), or the X coordinate returned by the platform is short and not padded, it breaks only when the first byte of X is 0 —— about **1/256** of exchanges;
- If `K` is encoded as an `mpint`, an extra `0x00` appears whenever the top bit is 1 —— about **1/2** of exchanges.

〔Decision〕The X coordinate returned by the platform's ECDH primitive is always **right-aligned and left-padded with zeros** to the coordinate length before use; if it is still longer than the coordinate after stripping leading zeros, that is the library's own bug (`InvalidOperationException`), not the peer's fault.

〔Note〕What can and cannot be reused from the neighbouring sections:

| Item | §3.6 `mlkem768x25519-sha256` | §3.7 the two NIST-curve hybrids | §3.3 `ecdh-sha2-nistp*` |
| --- | --- | --- | --- |
| Message numbers and outer shape | 30 / 31, each public value one `string` | Same as left | Same as left |
| Concatenation order | KEM first, classical second | **Same as left** | — |
| Classical public key | 32-byte X25519 | Uncompressed point, 65 / 97 bytes | Uncompressed point, 65 / 97 / 133 bytes |
| Classical validation | Length; result must not be all zeros | First byte `0x04`, coordinates less than p, on the curve (**the §3.3 checks, reused as is**) | Same as left |
| How the classical result enters `K` | 32 bytes (X25519 output is fixed-length anyway) | X coordinate, **fixed 32 / 48 bytes, leading zeros kept** | The X coordinate **is `K` itself, as `mpint`** |
| `K` | `HASH(K_PQ ‖ K_CL)`, as `string` | **Same as left** | X coordinate, as `mpint` |
| Hash | SHA-256 | SHA-256 / **SHA-384** | SHA-256 / 384 / 512 |

So the hybrid skeleton of §3.6 (concatenation, length check, computing `K` and encoding it as `string`) and the point encoding and curve validation of §3.3 can all be reused directly;
what **cannot** be reused is the shared-secret output of §3.3 (an X coordinate meant to be encoded as `mpint`), nor the existing two-way hash choice of §3.6 (SHA-256, otherwise SHA-512) ——
SHA-384 must be a branch of its own: falling into SHA-512 raises no error at all, it just makes every signature fail.

#### 3.7.3 Order of checks after the client receives 31

A step that fails stops everything after it:

```mermaid
flowchart TD
    A[KEX_HYBRID_REPLY received] --> B{S_REPLY exactly<br/>1153 / 1665 bytes?}
    B -->|no| X[KEX failure<br/>ProtocolError, DISCONNECT 3]
    B -->|yes| C{first byte of Q_S == 0x04?}
    C -->|no| X
    C -->|yes| D{both coordinates less than p<br/>and on the curve? see §3.3}
    D -->|no| X
    D -->|yes| E[decapsulate ct_pq to K_PQ<br/>ECDH to K_CL, padded to fixed length]
    E -->|platform primitive throws| X
    E --> F[K = HASH K_PQ ‖ K_CL<br/>wipe K_PQ, K_CL and the concatenation buffer]
    F --> G[compute H, verify signature, policy verdict, see §5.3]
```

1. **Total length**: the length of `S_REPLY` must equal exactly the sum of the method's `ct_pq` and `Q_S` (1153 / 1665). RFC 10042 §2.1 requires this check **before** decapsulation (against length-extension attempts).
   This step is also the "ciphertext type check" of FIPS 203 §7.3: the point encoding has a fixed length (next item), so when the total is right, the ciphertext length is right too.
2. **Point encoding**: the first byte of `Q_S` must be `0x04` (uncompressed).
3. **Point on the curve**: per the 〔Decision〕 in §3.3 the library checks first (both coordinates less than p, and y² = x³ − 3x + b (mod p)), then hands the point to the platform for import.
   P-256 / P-384 have cofactor 1, so "on the curve and not the point at infinity" is the full validation of SEC 1 §3.2.2; no multiplication by the order is needed.
4. **Decapsulation**: 〔Decision〕the other two checks of FIPS 203 §7.3 (the decapsulation key type check and hash check) are not performed —— that key was generated by us in this very exchange and never left the process;
   FIPS 203 explicitly lets the decapsulating party obtain the "has been checked" assurance by other means, and only the ciphertext check (step 1) is required on every execution.
   ML-KEM decapsulation **cannot fail as such**: given a modified ciphertext it still returns a pseudo-random `K_PQ` (implicit rejection), so `K` differs from the server's,
   which shows up as **signature verification failure** (§5.3 → `HostKeyRejected`). This is the expected behaviour, not an error to be detected separately; besides, `S_REPLY` itself is part of `H`, so a modified reply can never pass signature verification anyway.
5. **ECDH and combination**: see §3.7.2. Any exception thrown by a platform primitive in steps 4 and 5 is treated as a KEX failure (caught broadly, as in §3.3: platforms throw different exception types).

〔Decision〕**Only uncompressed points are sent and accepted.** RFC 10042 follows RFC 5656 in allowing point compression; we do not use it and do not accept it (a wrong total length, or a first byte of `0x02` / `0x03`, is rejected). Reasons:

- RFC 10042 requires the total length to be checked against "the expected length for the method" before decapsulation —— that expected length is a single number only if the point encoding has a fixed length;
- It is the same rule as §3.3 (`ecdh-sha2-*` has long accepted uncompressed points only, pinned down by a test);
- 〔Interop〕AlmaLinux 10.2's OpenSSH 9.9p1 (with RHEL 10.2's downstream patch) sends uncompressed points for both methods: capturing the cleartext first exchange in a container,
  its server's `S_REPLY` is 1153 / 1665 bytes with `0x04` as the byte after the ciphertext; its client's `C_INIT` is 1249 / 1665 bytes, likewise with `0x04` after `ek_pq`.
  If a server that sends compressed points ever turns up, record which one and which version, then revisit.

#### 3.7.4 How failures are reported

| Situation | Local reason | `DISCONNECT` sent to the peer |
| --- | --- | --- |
| Wrong `S_REPLY` total length, `Q_S` not uncompressed, `Q_S` not on the curve, a platform primitive throws | `ProtocolError` (`SshKeyExchangeException`, `Phase = KeyExchange`; during a rekey the phase is `Rekeying`, see [`08-failures.md`](08-failures.md) §2.1) | `KEY_EXCHANGE_FAILED` (3) |
| `ct_pq` modified (implicit rejection) → signature fails | `HostKeyRejected` | `HOST_KEY_NOT_VERIFIABLE` (9) |

〔Decision〕**When a peer public value fails its checks during key exchange, the `DISCONNECT` reason code is `KEY_EXCHANGE_FAILED` (3), not `PROTOCOL_ERROR` (2).**
RFC 10042 §2.1 makes it a MUST for the hybrid methods (a wrong length and a decapsulation failure must both disconnect with 3); RFC 8731 §3 makes it a SHOULD for curve25519.
The rule **applies to every method**: every `SshKeyExchangeException` thrown in §3.2–§3.7 when a peer public value fails its checks (length, encoding, not on the curve, all-zero X25519, DH out of range, a non-prime GEX `p` or an out-of-range `g`) sends 3 ——
RFC 4253 / 5656 / 4419 name no reason code, and one rule is easier to remember than a per-method table, and harder to miss. The local `SshFailureReason` does not change: it is still `ProtocolError` (the peer supplied an invalid value).
The description text says something like "key exchange failed"; it must not borrow the negotiation failure's "no matching algorithms". 〔History〕Such failures used to send 2 across the board ([`08-failures.md`](08-failures.md) §6).

#### 3.7.5 Ephemeral keys and platforms

- 〔Decision〕**Every exchange generates a fresh ML-KEM key pair and a fresh ECDH key pair**, every rekey included (a MUST in RFC 10042 §5); they are destroyed when the exchange ends,
  and the decapsulation key is never kept for the next one (FIPS 203 §3.3: intermediate values are destroyed as soon as they are no longer needed). `K_PQ`, `K_CL` and the concatenation buffer are wiped once `K` is computed.
- 〔Decision〕ML-KEM is handled as in §3.6: through the BCL when `MLKem.IsSupported` (`MLKemAlgorithm.MLKem768` / `MLKemAlgorithm.MLKem1024`), otherwise falling back to BouncyCastle (`ml_kem_768` / `ml_kem_1024`).
  The test that the BCL and BouncyCastle interoperate (one side generates, the other encapsulates) gets a 1024 case next to the 768 one. ECDH goes through the BCL's `ECDiffieHellman` (`nistP256` / `nistP384`), as in §3.3, available on every platform.
  **Both names are always in the lists, regardless of platform**: one of the two paths is always available, so the KEXINIT is the same on every OS and the method agreed with a given server does not depend on the client's OS —— one variable fewer when diagnosing.
- Message size: the largest `C_INIT` is 1665 bytes, and the reply plus host key and signature is still far below the 32768 / 35000 bytes RFC 4253 §6.1 requires to be supported; no special handling is needed (RFC 10042 §3).
- Name constants: `SshAlgorithmNames.MlKem768Nistp256Sha256` (`mlkem768nistp256-sha256`) and `SshAlgorithmNames.MlKem1024Nistp384Sha384` (`mlkem1024nistp384-sha384`),
  in the same style as the existing `MlKem768X25519Sha256` and `EcdhSha2Nistp256`; one row each in the `SshKeyExchangeFactory` table, and the algorithm catalog (00 §6.6) lists them as a result. All `internal`; no new public members.

Where they go in the default list and in `SshAlgorithmSet.FipsApprovedOnly`, and why, is in [`00-overview.md`](00-overview.md) §6.1 and §6.6:
both lists place them before the elliptic curves without post-quantum protection; in the default list they come after `mlkem768x25519-sha256` and before sntrup761; in both lists 768 / P-256 comes first.

〔Interop〕Servers that implement these two (looked at in Docker on 2026-10-06):

- **AlmaLinux 10.2** (a rebuild of RHEL 10.2), OpenSSH 9.9p1 with RHEL's downstream patch: both. The lists the system crypto policies give sshd (`/usr/share/crypto-policies/<policy>/opensshserver.txt` in the image):
  DEFAULT is `mlkem768x25519-sha256`, `mlkem768nistp256-sha256`, `mlkem1024nistp384-sha384`, then curve25519, ECDH, DH (no sntrup761);
  FIPS puts the two nistp hybrids first, then ECDH, `diffie-hellman-group-exchange-sha256` and the DH standard groups (no X25519 and no sntrup761); FUTURE keeps only the three ML-KEM hybrids.
- **Upstream OpenSSH 10.6p1** (the Alpine edge package): `ssh -Q kex` lists `mlkem768nistp256-sha256` but not `mlkem1024nistp384-sha384`; neither the client's nor the server's default list contains it,
  so it has to be added explicitly (`KexAlgorithms +mlkem768nistp256-sha256`). Its release notes do not mention it; `ssh -Q kex` is what counts.

〔History〕Before F12 these two were not implemented: one wrong byte in the exchange hash also shows up only as "signature verification failed", and with no server to check the wire format against, an implementation could only vouch for itself ——
which is why the FIPS preset of 00 §6.6 at first did not include them. On 2026-10-06 AlmaLinux 10.2 was found as a verification target and the draft had been published as RFC 10042, so this section was written.

#### 3.7.6 Test vectors

RFC 10042 gives no test vectors. The new rows of the §4.1 table are pinned down by two things: self-consistent vectors from the in-memory server side (`TestKexResponder` extended with these two methods),
and the checks against a real server in §3.7.7. The server side **must independently** compute `K_CL` and `K` at fixed length and must not call the code under test —— otherwise both sides are wrong in the same way and the test still passes.

#### 3.7.7 〔Verified〕Results against a real server

The target is the `ssh-pq` service in `docker-compose.test.yml` at the repository root (AlmaLinux 10.2's OpenSSH 9.9p1, account `vela-pq` / `velapass`), with three sshd processes in one container:
local port 2226 is configured like a server in FIPS mode (the two nistp hybrids plus plain ECDH, no X25519 and no sntrup761); 2227 offers only `mlkem1024nistp384-sha384` (plus `ecdh-sha2-nistp384`);
2228 follows RHEL 10.2's DEFAULT policy (the three ML-KEM hybrids, the X25519 one first, then curve25519 and plain ECDH). When the target is absent the interop cases are recorded as skipped (Inconclusive).

1. **Handshake + command**: each of the two connects, authenticates and runs a command, and the key exchange in `SshConnection.Algorithms` is that name.
2. **Rekeying**: each rekeys three times with commands still working after each, and `SshConnection.Rekeyed` reports that name.
3. **Fixed-length `K_CL`**: each rekeys 1200 times in a row on one connection, all successfully (about a 99% chance of hitting an X coordinate whose first byte is 0);
   an in-memory case also exchanges repeatedly until it hits a leading zero and then asserts that both ends get the same `K`. With `K_CL` changed to drop leading zeros, both of these fail.
4. **A server offering only the 1024 one** (2227): `Default` and `FipsApprovedOnly` both negotiate `mlkem1024nistp384-sha384` and do not fall back to ECDH.
   No server offering only the 768 one was started separately: 2226 offers both, and both lists pick 768.
5. **The default list**: against 2226 (no X25519) it negotiates `mlkem768nistp256-sha256` (previously `ecdh-sha2-nistp256`); against 2228 (RHEL's DEFAULT) it still negotiates `mlkem768x25519-sha256`.
6. **The FIPS preset**: against both 2226 and 2228 it negotiates `mlkem768nistp256-sha256`, and commands work. No server offering only plain ECDH was started separately.
7. **Negative (in memory)**: `S_REPLY` one byte longer or shorter; `Q_S` starting with `0x02` / `0x03`; one bit of Y flipped; X equal to p; the all-zero point → `SshKeyExchangeException` (`ProtocolError`);
   one bit of the KEM ciphertext flipped → the exchange itself raises no error and the computed `K` differs. Disconnect code: for five methods (the two nistp hybrids, `mlkem768x25519-sha256`, `ecdh-sha2-nistp256`, `curve25519-sha256`)
   each given a public value one byte short, the server receives reason code 3 every time (§3.7.4).
8. **Negative (real server)**: a byte-flipping relay between the client and 2226 (the first exchange is in the clear): flipping a bit of the EC point in `S_REPLY` → `ProtocolError` on our side;
   flipping a bit of the KEM ciphertext → `HostKeyRejected` on our side. The peer reason code in the server log is not checked automatically (the cases do not read `docker logs`).
9. **Wire lengths**: the same relay records `C_INIT` as 1249 / 1665 bytes and `S_REPLY` as 1153 / 1665 bytes.
10. Not done: comparison against the two other implementations, upstream OpenSSH 10.6p1 and Apache MINA SSHD 2.20.

〔Verified〕Found along the way: the `Rekeyed` event used to be raised before the "in progress" flag was cleared, so a subscriber that started another rekey on receiving it was swallowed as a no-op —— the back-to-back rekeys of item 3 stalled right there.
It is now raised after the flag is cleared (§8.1).

---

## 4 Exchange hash `H`

### 4.1 Common inputs (all methods except GEX)

`H = HASH(...)`, with the inputs concatenated in order, **each item encoded according to its SSH type**:

| # | Type | Content |
| :-: | --- | --- |
| 1 | `string` | `V_C` —— client identification string (CR LF removed, original bytes) |
| 2 | `string` | `V_S` —— server identification string (CR LF removed, original bytes) |
| 3 | `string` | `I_C` —— the **payload** of the client's KEXINIT (including the message number byte) |
| 4 | `string` | `I_S` —— the payload of the server's KEXINIT |
| 5 | `string` | `K_S` —— server host public key blob |
| 6 | Method-dependent | Client public key (`Q_C` / `e`) |
| 7 | Method-dependent | Server public key (`Q_S` / `f`) |
| 8 | Method-dependent | Shared secret `K` |

The types of items 6/7/8 depend on the method:

| Method | `Q_C`/`e` | `Q_S`/`f` | `K` |
| --- | --- | --- | --- |
| curve25519 | `string` | `string` | **`mpint`** |
| ecdh-nistp* | `string` | `string` | **`mpint`** |
| dh-group14/16 | **`mpint`** | **`mpint`** | **`mpint`** |
| mlkem768x25519 / mlkem768nistp256 / mlkem1024nistp384 / sntrup761x25519 | `string` | `string` | **`string`** |

> **Make this table the data source for unit tests.** One known vector per row, asserting `H` byte by byte.
> This is the place in the entire specification most worth writing tests for first.

### 4.2 Additional inputs for GEX

`diffie-hellman-group-exchange-*` inserts the following between item 5 and item 6:

| # | Type | Content |
| :-: | --- | --- |
| 5.1 | `uint32` | `min` (the minimum bit length we requested) |
| 5.2 | `uint32` | `n` (preferred bit length) |
| 5.3 | `uint32` | `max` |
| 5.4 | `mpint` | `p` |
| 5.5 | `mpint` | `g` |

〔Note〕RFC 4419 has an old "send only `n`" variant (`SSH_MSG_KEX_DH_GEX_REQUEST_OLD`, number 30).
〔Decision〕**The old variant is not implemented**; only the three-parameter 34 is sent. Any server that still supports only the old variant
has an SSH implementation too old to fall within our support scope.

### 4.3 Session identifier `session_id`

The `H` computed by the **first** key exchange is the `session_id`, and it **never changes** thereafter
(even when rekeying produces a new `H`).

Uses of `session_id`:
- key derivation (§4.4);
- **the signature input of public key authentication** ([`04-authentication.md`](04-authentication.md) §4.3).

〔Implementation note〕During rekeying, "the new `H`" and "the unchanging `session_id`" must be stored separately.
If they are merged into a single field, the symptom is that public key authentication on a newly opened channel after rekeying fails ——
and that is an extremely rare path, likely to go unnoticed for a long time after release.

---

## 5 Host key verification

### 5.1 Format of `K_S`

| Algorithm | Blob content |
| --- | --- |
| `ssh-ed25519` | `string "ssh-ed25519"` ‖ `string key`(32 bytes) |
| `ecdsa-sha2-nistp256` | `string "ecdsa-sha2-nistp256"` ‖ `string "nistp256"` ‖ `string Q`(uncompressed point) |
| `ssh-rsa` / `rsa-sha2-*` | `string "ssh-rsa"` ‖ `mpint e` ‖ `mpint n` |
| `*-cert-v01@openssh.com` | Certificate structure, see OpenSSH `PROTOCOL.certkeys` |

〔Critical〕**The type string in an RSA blob is always `"ssh-rsa"`, even if `rsa-sha2-512` was negotiated.**
`rsa-sha2-256` / `rsa-sha2-512` are **signature algorithm** names, not key type names.
Comparing the negotiated algorithm name against the type string in the blob will fail —— this is an easy-to-trip asymmetry
introduced by RFC 8332.

### 5.2 Signature format

| Algorithm | Signature blob |
| --- | --- |
| `ssh-ed25519` | `string "ssh-ed25519"` ‖ `string sig`(64 bytes) |
| `ecdsa-sha2-nistp*` | `string alg` ‖ `string (mpint r ‖ mpint s)` —— **nested**; the inner part is a string made of two concatenated mpints |
| `rsa-sha2-256/512` | `string "rsa-sha2-256"` ‖ `string sig` —— PKCS#1 v1.5, **not PSS** |
| `ssh-rsa` | `string "ssh-rsa"` ‖ `string sig` —— SHA-1 + PKCS#1 v1.5 |

〔Note〕The **double string nesting** of ECDSA signatures is another classic pitfall:
the content of the outer string is the concatenation "`mpint r` followed by `mpint s`",
not r and s concatenated directly as fixed-length bytes. DER encoding is also wrong.

〔Decision〕**A signature blob must be exactly these two fields; a single extra byte after them makes it invalid** (likewise after the two inner mpints of ECDSA);
**the signature algorithm must be one this key can produce** (a P-256 key does not verify an `ecdsa-sha2-nistp384` signature, an RSA key does not verify an `ssh-ed25519` one).
〔History〕Early versions did not look at the end of the outer blob, and the binding held only indirectly through "does this key have the matching native object".

### 5.3 Verification order (the order itself is a security property)

```mermaid
flowchart TD
    A[KEX REPLY received] --> B{Signature algorithm name<br/>== negotiated<br/>host key algorithm?}
    B -->|No| X[ProtocolError, disconnect]
    B -->|Yes| C{K_S type string<br/>matches the algorithm?<br/>RSA: mind §5.1}
    C -->|No| X
    C -->|Yes| D{RSA and modulus<br/>< MinimumRsaKeyBits?}
    D -->|Yes| X2[HostKeyRejected, disconnect]
    D -->|No| E[Compute H]
    E --> F{Verify sig H with K_S}
    F -->|Failure| X3[HostKeyRejected, disconnect]
    F -->|Success| G[IHostKeyPolicy rules on K_S]
    G -->|Reject| X4[HostKeyRejected, disconnect<br/>with the reason given by the policy]
    G -->|Accept| H[Continue, send NEWKEYS]
```

**Three reasons for the order**:

1. **Verify the signature first, then consult the policy.** Asking the user "do you want to trust this key" before the signature has passed is absurd ——
   the key has not even proven that it holds the corresponding private key.
2. **The RSA length check comes before signature verification.** 〔Decision〕`MinimumRsaKeyBits` defaults to **2048**.
   It is placed before signature verification so as not to spend any computing resources on weak keys.
3. **Policy rulings are timed independently.** 〔Decision〕The time taken by `IHostKeyPolicy.EvaluateAsync`
   **is not counted against `ConnectTimeout`**; it is bounded by a separate `HostKeyDecisionTimeout` (infinite by default).
   A cancellation thrown by the policy itself (the decision timer did not fire and the caller did not cancel: the user closed the prompt) is not a timeout; it is reported as `Aborted` (`08-failures.md` §2.1).

   Rationale: this targets a real defect directly —— an interactive client pops up a dialog here to ask the user,
   and if the time the dialog sits there counted against the connect timeout, by the time the user clicks "Trust" this attempt has already been declared dead,
   and a reconnect has to be made on the spot. With the two timers separated, that reconnect logic disappears together with its explanatory comment.

   〔Decision〕In the implementation this comes down to three things:
   - the connection timer is **paused** during the ruling, and resumes from the remaining time after the ruling ends; every pause is deducted in turn, and the remaining time is never topped back up.
     〔Decision〕**If the budget is already used up at the moment of pausing, the timeout is declared on the spot and the policy is not asked.** The expiry callback runs only once the thread pool gets to it,
     which can be a long time when the thread pool is busy; freezing the timer at that point would let a connection that has already timed out take the fingerprint to the user,
     and right after the user clicks "Trust" it would time out anyway. So pausing settles the account by the time actually used, not by whether the callback has arrived;
     and right before the ruling the connection's token is checked once more — a connection that has expired, or that the caller has cancelled, is not taken to the user. Conversely, an expiry
     callback that only runs while the timer is paused does not count — the account was settled at the pause: a real expiry was declared then, and one that had not come yet is rescheduled from the remaining time on resume;
   - the ruling and the persistence of "trust permanently" honor only **the caller's cancellation token**, not the connection timer's ——
     when the user clicks "trust permanently", that write to known_hosts should not receive an already-cancelled token;
   - when connecting through a jump host, the entire connection setup of the inner hop happens within the dialing phase of the outer hop ——
     while the inner hop is ruling, **the outer timer is paused as well** (`09-dialing.md` §2.4).

### 5.4 The contract of `IHostKeyPolicy`

```
ValueTask<SshHostKeyVerdict> EvaluateAsync(SshHostKeyContext context, CancellationToken cancellationToken)
```

`SshHostKeyContext` **MUST** provide (all the material of the key itself is on `Key`, an `SshPublicKey`):

| Field | Purpose |
| --- | --- |
| `Host` / `Port` | The **logical** host being connected to (on a jump chain, the target of this hop, not the TCP peer) |
| `KeyBlob` / `KeyType` / `KeyBits` | Raw material |
| `Sha256Fingerprint` / `Md5Fingerprint` | For display. SHA-256 is base64 without padding, consistent with OpenSSH |
| `Key.IsCertificate` / `Key.Certificate` | Host certificate issued by a CA (§5.5). A certificate's fingerprint is the fingerprint of **the key inside it**, consistent with `ssh-keygen -l` |
| `Key.RandomArt` | 〔Decision〕Provide an OpenSSH-style ASCII fingerprint picture (algorithm below). It genuinely helps with visual comparison |

**How the fingerprint picture (`SshPublicKey.RandomArt`) is drawn**, byte-for-byte identical to `ssh-keygen -lv` (tests compare against real `ssh-keygen` output):

- The input is the 32-byte SHA-256 digest behind the fingerprint (the same one as `Sha256Fingerprint`: for a certificate, the key inside the certificate).
- The canvas is 17 columns × 9 rows with one counter per cell; the walk starts in the middle (column 8, row 4, counting from 0).
- Byte by byte, each byte yields four 2-bit groups starting from the least significant bits: bit 0 set moves right, clear moves left; bit 1 set moves down, clear moves up —
  every step is diagonal. At a wall that direction stays put (coordinates are clamped to 0–16 and 0–8). The cell reached has its counter incremented.
- Counts 0–14 are drawn as one character of ` .o+=*BOX@%&#/^` in order, larger counts also as `^`; the start cell is drawn `S` and the end cell `E` (`E` when they coincide).
- The top border is `+`, a centred `[TYPE BITS]` (`ED25519 256`, `ECDSA 384`, `RSA 3072`) padded with `-` to 17 characters, `+`;
  centring puts `(17 − length) / 2` rounded down on the left and the rest on the right. The bottom border centres `[SHA256]` the same way. The sides are `|`. Lines are joined with `\n`.

An `SshHostKeyVerdict` can only be obtained from four factory members: `Accept` / `AcceptAndPersist` / `Reject(message)` / `RejectChanged(message)`.
**A rejection MUST carry a reason text**, which goes verbatim into `SshConnectException.Message` ——
this directly targets "the user only sees a bare UntrustedPeer and doesn't know where to delete the record".
The reason code is determined by the kind of rejection (`SshHostKeyVerdict.Reason`): `Reject` is `HostKeyRejected`;
`RejectChanged` is `HostKeyChanged` —— the recorded key has changed, or only other types are recorded (the next decision), possibly a man-in-the-middle.
Callers use this to handle "not trusted" and "changed" separately: the latter should not be casually waved through by a "trust and remember" button.

〔Decision〕**`default(SshHostKeyVerdict)` is a rejection.** The zero value of the verdict enum is `Reject`, so a verdict someone forgot to assign does not turn into a pass;
a rejection without an explanation reports "host key rejected by policy".

〔Decision〕**Switching to another key type must not bypass "changed".** If a man-in-the-middle presents a key type not in the records and it is treated as "never seen",
the "host key changed" check is bypassed, and a policy that accepts new hosts will quietly record it. Both of the following are done:

1. A policy can (via the optional `IHostKeyTypePreference`) report which key types are already recorded for this host; at connect time the host key algorithms of those types
   are **moved to the front** — negotiation follows the client's order, so a legitimate server ends up with the recorded type. Rekeying uses the same list.
2. If a type that isn't recorded is still negotiated (the records only hold other types), that is a separate status, `OtherKeyTypesKnown`,
   handled exactly like "changed": reject, listing the recorded types and line numbers in the reason. It must **not** be treated as "never seen" and asked about or recorded.

Two more rules for `KnownHostsPolicy`: when a negated pattern (`!pattern`) matches, the **whole line** does not apply to this host
(`*.corp,!untrusted.corp` must not trust the key for `untrusted.corp` via `*.corp`);
before appending a record, check whether the file ends with a newline and add one if not — otherwise the new record is glued onto the last line and both break.
〔Decision〕A leading marker is recognized only if it is one of the two sshd(8) defines, `@revoked` and `@cert-authority` (case as written); **a line with an unrecognized marker is skipped entirely** —
when someone means to revoke a key and writes `@revoke` instead of `@revoked`, using the line as an ordinary trusted entry would make that key "known" for every host the pattern matches.
〔Decision〕Host names are **lower-cased** for lookups and when writing (as OpenSSH does: it lower-cases before writing, and a hashed line is the HMAC of the lower-case name).
Hashing the name as typed means a hashed line never matches when the user typed upper case — with a man in the middle, "key changed" degrades into "never seen, trust it?",
the key type preference stops protecting as well, and hashed lines this library writes cannot be read back by OpenSSH.
〔Decision〕**A host name containing characters that mean something else in `known_hosts` is not written** (`KnownHostsFile.IsRecordableHost`): `,` `*` `?` `!` `[` `]` `#`, whitespace,
control characters, and a leading `@` or `|`. The host field is itself a pattern list; with `x,*` written into it, the key becomes valid for every host, and host names can come from external launch links
or `HostName` in `ssh_config`. `FormatEntry` / `AppendAsync` throw `ArgumentException`; when `KnownHostsPolicy` meets such a name on "trust and remember",
**the connection is not allowed either** (`InvalidConfiguration`) — if it cannot be remembered, it must not silently become "trust just this once". Hashed lines are refused too: such a name is not a host anyway.
〔Decision〕**Failures to read or write `known_hosts` are reported as `HostKeyStoreFailed`** (`KnownHostsFile.LoadAsync` / `AppendAsync` throw `SshConnectException`, with the original exception in `InnerException`).
When the file cannot be read there is no way to tell whether this host is known, so the connection is not allowed — treating it as "never seen" and asking would, when a record really exists, hand the user a key of unknown origin to click "trust" on.
〔Decision〕**Append-only in normal operation, with a separate rewrite path for removing records** (Q4): records are removed in only two situations —— when the key "changed" and the user has confirmed a reinstall, a one-click removal of the old record
(`KnownHostsPolicy.RemoveHostKeysAsync`, the thing the error message tells people to do by hand; the library never removes on its own, and the verdict for "changed" is still a rejection),
and during host key rotation, removing old keys the server no longer presents ([spec/05 §6.4.1](05-connection.md)). Both go through `KnownHostsFile.RemoveHostKeysAsync`:
- **Only records that belong to this host alone are touched**: a hashed line (one line stands for one name) is removed whole when it matches; on a plain line this host's name is taken out —— when a line lists several names (`host,10.0.0.5`) the other names stay trusted, and the line is removed only once no names remain.
  `@revoked`, `@cert-authority`, and lines with wildcards or negation are left alone (they cover more than this host); all other lines are kept as they are, line endings included. When fingerprints are given, only those keys are removed.
- **Temporary file + atomic replace + retry on conflict**: the new content is first written to a temporary file in the same directory; before replacing, the original is read again, and if it differs from what the rewrite was based on (most likely another process just appended a record), the rewrite starts over from the new content,
  at most 5 times (on Windows, the file being held open by another process also counts as a conflict); only when it matches is the file replaced atomically, keeping its permissions on Unix. A failure part way leaves the original untouched; with nothing to remove, not a single byte of the file changes.
  A very short window remains between the comparison and the replacement, and a record appended in it is lost —— which is why the file is not rewritten in normal operation. 〔History〕It used to be append-only, never rewritten.

〔Decision〕**When "trust and remember" cannot write the record, this connection goes ahead** (only a warning, as in OpenSSH): the trust has been granted, it just was not recorded.
Among the exceptions thrown by `PersistAsync`, cancellation propagates as-is; any other library reason (the `InvalidConfiguration` of the previous rule) means the policy deliberately refuses, and also propagates as-is;
the rest — `HostKeyStoreFailed` and exceptions from the caller's own policy — are recorded in `SshConnection.HostKeyPersistFailure` (through a jump host, on that hop's own connection), and the next connection asks again.
This used to fail the whole connection, reported as "the peer closed the connection" and marked retryable.

### 5.5 Host certificates (`*-cert-v01@openssh.com`)

Sources: OpenSSH `PROTOCOL.certkeys` (certificate layout and what the signature covers), and the SSH_KNOWN_HOSTS section of sshd(8) (`@cert-authority` / `@revoked`).

**Algorithm list.** The default list appends the certificate variants **after** the plain host key algorithms:
`ssh-ed25519-cert-v01@openssh.com`, `ecdsa-sha2-nistp256/384/521-cert-v01@openssh.com`,
`rsa-sha2-512-cert-v01@openssh.com`, `rsa-sha2-256-cert-v01@openssh.com`.
`ssh-rsa-cert-v01@openssh.com` (SHA-1) is not included.

〔Decision〕**The certificate variants go last.** When no CA is configured for the host, negotiating a certificate buys no extra assurance (see item 4 below),
and putting them last guarantees such connections behave exactly as before. When `known_hosts` has an `@cert-authority` line matching the host,
`IHostKeyTypePreference` reports the certificate types, which moves the certificate algorithms forward (§5.4 item 1);
if the host's plain key is recorded too, the plain algorithms still come first in the list — that key is already explicitly trusted, and either path gives the same result.

**Handshake.** `K_S` is the whole certificate blob, and that is what goes into the exchange hash. The signature in the KEX reply is made by **the key inside the certificate**,
and the signature blob carries the **plain** algorithm name (`rsa-sha2-512-cert-v01@openssh.com` corresponds to `rsa-sha2-512`).
The verification order in §5.3 gains two rules:

- When a certificate algorithm is negotiated, `K_S` must be a certificate; when a plain algorithm is negotiated, it must not be — a mismatch is `HostKeyRejected`;
- the RSA minimum length applies to **the key inside the certificate** (its type string is `ssh-rsa-cert-v01@openssh.com`, so comparing the type string to `ssh-rsa` would skip the check).

〔Decision〕**An ask callback and "what to do with an unseen host" (`UnknownHost`) are either-or.** With an ask callback given (the constructor's `askUnknownHost`) and `UnknownHost`
set to `Reject` / `AcceptAndPersist`, the callback would never be called — setting it throws `ArgumentException` instead of silently ignoring the callback; an undefined value throws
`ArgumentOutOfRangeException`. Accordingly, the `ssh_config` path hands the caller's ask callback to the policy only when it asks (`spec/09` §7).

**How `KnownHostsPolicy` decides** (in order; once a rule applies, later ones are not consulted):

1. An `@revoked` line matching the host whose key is the key inside the certificate, the whole certificate, or the CA that signed it → `Revoked`.
2. The key inside the certificate is recorded as a plain key for this host → `Known`. An explicitly recorded key takes precedence and the certificate is not examined.
3. An `@cert-authority` line matches the host and its key is the certificate's signing CA → validate the certificate; it is `Known` only if **all** of these hold:
   - the certificate type is host (2);
   - the CA signature verifies: it covers every field from the type string up to and including the signing CA's public key;
     the signature algorithm is limited to `ssh-ed25519`, `ecdsa-sha2-nistp256/384/521`, `rsa-sha2-256`, `rsa-sha2-512` —
     〔Decision〕SHA-1 `ssh-rsa` signatures are not accepted; the CA key must not itself be a certificate; an RSA CA must be at least 2048 bits;
   - the current time is within `[valid_after, valid_before)` (both ends are compared as raw uint64 seconds. The fields may hold values past the year 9999;
     those are legal and must not make validation throw: when converted to a point in time for display, a `valid_before` past the end of 9999 is treated as unlimited,
     and a `valid_after` past it becomes the latest representable time);
   - `valid principals` is non-empty and contains the host name being connected to (exact comparison, case-insensitive, no wildcards);
   - there are no critical options (none are defined for host certificates, and an unrecognized critical option must be rejected).

   If any of these fails → `CertificateInvalid`: reject and say which one. Which one is in the `Kind` (`HostCertificateProblemKind`) of
   `KnownHostLookup.CertificateProblemDetail` (`HostCertificateProblem`), in order: `NotHostCertificate`, `AuthorityKeyUnreadable` /
   `AuthorityKeyTooShort`, `SignatureMalformed` / `SignatureAlgorithmRejected` / `SignatureInvalid`, `Expired` / `NotYetValid`,
   `NoPrincipals` / `HostNotListed` / `UnknownCriticalOptions` — the order is the order of verification, and the first failing check is the
   one reported; the parameters (Key ID, time, principals, host, critical options, algorithm, CA size) are raw values, not sanitized.
   `KnownHostLookup.CertificateProblem` is its Chinese text: the names in it that come from the peer's certificate (Key ID, principals,
   critical options, algorithm names) are already sanitized — control characters and bidirectional controls become `?`, and overlong values
   are cut (256 characters for Key IDs and names, 64 for algorithm names); the text for a normal certificate is unchanged. A UI words it
   from `Kind` and the parameters, without parsing the sentence. 〔Decision〕**Do not fall back to "never seen" and ask or record**:
   the host has a CA configured, so an invalid certificate means a misconfiguration or someone on the path; quietly switching to TOFU would hide that
   until the day the key is no longer on record.
   〔Decision〕**Host certificates with an empty `valid principals` are rejected.** `PROTOCOL.certkeys` defines an empty list as "valid for any principal";
   for a host certificate that means one certificate signed by the CA can impersonate any host within the scope of the `@cert-authority` line.
4. No CA vouches for it → treat the key inside the certificate as a plain key and apply the §5.4 rules to get `Changed` / `OtherKeyTypesKnown` / `Unknown`.
   When a new host is accepted, **the plain key is what gets recorded**, not the certificate: the blob changes every time the certificate is re-issued, so recording it would guarantee a "changed" report next time.

   〔Decision〕**An `@cert-authority` line matching the host also counts as "other types recorded".** If the host is managed by a CA but presents a key that CA doesn't vouch for
   (a plain key, or a certificate signed by another CA), and that key isn't recorded on its own → `OtherKeyTypesKnown`: reject, without asking or recording.
   The reason is the same as §5.4 item 2: otherwise a man-in-the-middle only has to present a plain key and `accept-new` records it quietly —
   and configuring a CA for a host is precisely about no longer relying on blind trust the first time. For a host that really has no certificate, verify the fingerprint and add its key to `known_hosts` on its own.

**The host side (2026-10-24).** The host's `VelaHostKeyPolicy` does not use `KnownHostsPolicy`, and does not read `~/.ssh/known_hosts` on every
connection: trusted CAs and revocation records live in the host's own trust store (SonnetDB `known_host_markers`), put there by the user
importing a known_hosts file in Settings or pasting a whole `@cert-authority` / `@revoked` line. To decide, it turns those records and the
trusted hosts into the library's `KnownHostEntry` and hands them to `KnownHostsFile.Lookup`, so negation, hashing and the certificate's type /
signature / validity / principals / critical options all follow the library, in the same order as above: a revocation beats everything → a
key recorded on its own comes first → a valid certificate signed by a matching CA is let through (not recorded among trusted hosts) → an
invalid one is rejected (the reason is worded in the UI language from `CertificateProblemDetail`, with the Key ID) → a CA-managed host presenting an unendorsed key is rejected, without asking or recording — whatever the host's
"confirm on first connection" and "block on change" switches say, and on automatic reconnects too. If the CA / revocation records cannot be
read it fails closed; while ordering host key algorithms an unreadable store is ignored. With a matching CA the host likewise reports the
certificate types, so certificate algorithms move to the front.

**Rekeying** pins the whole `K_S` from the first exchange (§8.4); a changed certificate is treated as a changed host key.
So on rekey the host key algorithm list keeps only algorithms of the pinned key's **type and certificate-ness** (certificate stays certificate, plain stays plain):
when a certificate is pinned, the plain algorithm also looks "supported" once the suffix is stripped, and negotiating it would make the server present its plain key instead of the certificate — the pin fails and the connection is dropped as a changed host key.

---

## 6 Strict KEX (Terrapin mitigation)

> Basis: `kex-strict-*-v00@openssh.com` in OpenSSH `PROTOCOL`; CVE-2023-48795.

**MUST be implemented, and cannot be turned off.**

The principle of the Terrapin attack: during the handshake a man-in-the-middle can **insert or delete** packets
(`SSH_MSG_IGNORE`, `SSH_MSG_DEBUG` etc. are allowed during the handshake),
thereby shifting the two sides' sequence numbers, and then, once encryption is established, delete the first few packets without being detected ——
including `SSH_MSG_EXT_INFO`, which allows the signature algorithm to be downgraded.

The mitigation has two parts, both required:

1. **Enabled when both sides announce support** (we send `kex-strict-c-v00@openssh.com`,
   and the peer's KEXINIT contains `kex-strict-s-v00@openssh.com`).
   **Only the first KEXINIT counts**: the markers are valid only there, and whether a later rekey KEXINIT carries them is ignored ——
   strict KEX is a property of the **whole connection**, fixed by the initial exchange.
2. Once enabled:
   - **Receiving any non-KEX-related packet during the first KEX (including `SSH_MSG_IGNORE`,
     `SSH_MSG_DEBUG`, `SSH_MSG_UNIMPLEMENTED`) always disconnects.**
     This applies to the first KEX only —— during a rekey these are ordinary, legal packets.
   - **The peer's first packet must be `KEXINIT`.** When it is read, whether strict KEX will be negotiated is not yet known, so any `IGNORE` / `DEBUG`
     before it can only be skipped per the RFC; once strict KEX is negotiated this is checked retroactively, and if anything was skipped the connection is dropped (`ProtocolError`).
   - **After every `SSH_MSG_NEWKEYS`, both sequence numbers are reset to zero** —— including every rekey.

〔Note〕Recomputing it from "does this KEXINIT carry the marker" each time is wrong: when the peer omits the marker on rekey,
the local side stops resetting while the peer keeps resetting, the first packet after the rekey fails integrity checking, and the long-lived connection drops.
chacha20-poly1305 (the nonce is the sequence number) and HMAC suites (the MAC covers the sequence number) expose it immediately;
AES-GCM's nonce ignores the sequence number and masks the error.

〔Decision〕**When the peer does not support strict KEX, log a warning-level entry and continue.**
The connection is not refused —— there are many old servers, and refusing would kill a large number of legitimate scenarios;
but the consumer must be able to see "this connection has no Terrapin mitigation" in the diagnostics panel.
`SshConnectionInfo.StrictKeyExchange` exposes this fact.

---

## 7 Key derivation (RFC 4253 §7.2)

Six keys, each using the same formula with a different constant letter:

```
K_x = HASH(K ‖ H ‖ "X" ‖ session_id)
```

| Letter | Purpose |
| :-: | --- |
| `A` | Initial IV, client→server |
| `B` | Initial IV, server→client |
| `C` | Encryption key, client→server |
| `D` | Encryption key, server→client |
| `E` | Integrity key, client→server |
| `F` | Integrity key, server→client |

**Key points**:

1. `K` is encoded according to the type for its method (the table in §4.1: `string` for the post-quantum hybrids, `mpint` for the rest); `H` and `session_id` are **raw bytes**, with no length prefix.
   **The letter `X` is a single raw byte, not a `string`.**
   〔History〕This item used to say "`H` and `session_id` as `string`", which contradicts RFC 4253 §7.2; the implementation switched to raw bytes long ago ([architecture.md §11.2.13](../design/architecture.md): the two extra length prefixes made the first connection to a real OpenSSH fail across the board).
2. **When the key is not long enough, it must be extended** (SHA-256 outputs 32 bytes and SHA-384 48 bytes, while ChaCha20 needs 64):
   ```
   K1 = HASH(K ‖ H ‖ "X" ‖ session_id)
   K2 = HASH(K ‖ H ‖ K1)
   K3 = HASH(K ‖ H ‖ K1 ‖ K2)
   key = K1 ‖ K2 ‖ K3 ‖ ... take the first N bytes
   ```
   Note that subsequent rounds **do not include** the letter or `session_id`, only `K ‖ H ‖ everything generated so far`.
3. **On the first KEX, `session_id == H`**; on rekeying, `H` changes while `session_id` does not.
4. Derived key material **MUST** be wiped with `CryptographicOperations.ZeroMemory` after use.

---

## 8 Rekeying

### 8.1 Trigger conditions

Either side may initiate rekeying at any time by sending `SSH_MSG_KEXINIT`.

> **Implementation status (2026-09-21)**: **fully landed** (see architecture document §11.2.11) ——
> handles rekeying initiated by the peer, initiated by us, and initiated by both sides simultaneously.
> The thresholds live in `SshRekeyPolicy`, enabled by default.

〔Decision〕**A rekey initiated by the peer during authentication is completed in place.** If the user takes a few minutes to find a one-time code, a time-based `RekeyLimit` on the server sends `KEXINIT` in the middle of authentication.
At that point the authenticator is the only reader and the only writer, so the exchange runs directly on the connection-setup transport (pinning the host key of the first exchange, §8.4), and then reading continues for the reply to the request in flight —
it arrives after the exchange, under the new keys; the delayed compression attached after authentication succeeds follows the latest negotiation result.
`KEXINIT` used to be treated as an unexpected message, and the connection failed with a protocol error.

〔Decision〕Thresholds at which we trigger rekeying ourselves:

| Condition | Default | Rationale |
| --- | --- | --- |
| Bytes sent/received | **1 GiB** (in either direction) | Recommendation of RFC 4253 §9 |
| Duration | 〔Decision〕**Not checked by default** (only when `maxInterval` is given explicitly, minimum 1 minute) | OpenSSH's client and server also rekey by data volume only by default (`ssh -G` reports `rekeylimit 0 0`; `sshd_config` defaults to `RekeyLimit default none`). On old devices that mishandle client-initiated rekeying, time-based rekeying means a scheduled disconnect: once our `KEXINIT` is out the gate is closed and cannot be taken back, until the time limit declares the exchange dead (Q1). 〔History〕It used to default to 1 hour |
| AES-GCM invocation counter | **Forced** when approaching 2⁶⁴ | Counter wraparound would reuse nonces, which is catastrophic |
| Packets in one direction under the same keys | **2³¹**, **independent of the policy and cannot be turned off** | The sequence number is 32 bits: chacha20-poly1305's nonce is the sequence number, so wrapping under the same keys reuses nonces and lets messages be forged; HMAC suites become open to replay (RFC 4344 §3.1) |

〔Decision〕**Thresholds are configurable but have lower bounds**: bytes no lower than 64 MiB, duration no lower than 1 minute.
Overly frequent rekeying is itself a denial-of-service surface (each one requires asymmetric operations).
The packet threshold also has an **upper bound** of 2³¹ (`SshRekeyPolicy.MaximumPackets`); larger values are rejected at construction.

〔Decision〕**The packet count is a hard constraint, not an item of the policy.** Whatever `SshRekeyPolicy` says (`Disabled` included),
the session rekeys as soon as either direction reaches 2³¹ packets under the same keys; the transport has a last line of defense as well: the 2³²-th packet under the same keys
(one more and the sequence number would wrap to a value these keys have already used) is refused in both directions and the connection is dropped. The packet count used to be just an item of the policy,
and `Disabled` or a threshold above 2³² could switch it off — a cryptographic hard constraint that the public API could turn off.

〔Decision〕**Every completed rekey is reported** (the `SshConnection.Rekeyed` event: cause, ordinal, duration, newly negotiated algorithms): peer-initiated, threshold-initiated and explicitly requested ones alike;
failed ones are not (the connection is declared dead). The duration runs from receiving the peer's `KEXINIT` to the new keys being installed — channel data is held back during that time, which is where "the terminal hiccups now and then" lines up;
the latest one also stays in `LastRekeyDuration`. The event is raised synchronously on the receive loop, so subscribers must not block; exceptions thrown by subscribers are swallowed.
〔Decision〕The event is raised **after another rekey can be started**: a subscriber that starts the next one on receiving it is not swallowed as a no-op because a rekey still seems "in progress". 〔History〕It used to be raised before that, and a subscriber that "starts another rekey after every rekey" stopped after the second one (§3.7.7).

### 8.2 Send gate

This is where this implementation differs most from common practice, and it is the core of [architecture.md §5.4](../design/architecture.md).

The literal wording of RFC 4253 §7.1: once `KEXINIT` has been sent,
**no packets other than transport-layer messages (1–49) may be sent before `NEWKEYS`**.

We implement this sentence directly as a gate:

```
While in state Rekeying:
  SendPump takes a frame from the queue
    → Is the frame's message number within 1..49?
        Yes → send normally
        No  → put it in the "pending stash", continue with the next frame
  NEWKEYS received/sent and KEX complete
    → open the gate → the stash drains in its original order
```

**Three MUSTs**:

1. **The stash preserves order** —— the order of channel data is part of its semantics.
2. **The stash has an upper limit** (〔Decision〕16 MiB by default). When the limit is exceeded, **the enqueuer is blocked** rather than anything being dropped,
   so backpressure propagates to the caller. Never drop packets here.
3. **The caller's `WriteAsync` is not blocked** —— enqueueing is non-blocking (unless it hits the limit);
   the gate acts only on `SendPump`. This is the most essential difference from "using semaphores to make two loops wait on each other":
   **no two paths hold each other's synchronization primitives, so deadlock is impossible**.

〔Decision〕**Only one exchange at a time.** "In progress" runs from the moment we send `KEXINIT` (or receive the peer's `KEXINIT`)
until that exchange finishes and the gate reopens. Any attempt to start another during that time (a caller, or the threshold monitor firing) is a no-op —
sending another `KEXINIT` mid-exchange is a protocol violation and the peer will disconnect.
The thresholds are reset only when the exchange completes, so checking only "we sent one and the peer hasn't answered yet" is not enough: that marker is gone as soon as the exchange starts,
while the monitor's next tick still sees counters past the threshold. Closing the gate and our `KEXINIT` are enqueued under the same lock,
so an exchange the peer starts at the same moment cannot put its first frame ahead of our `KEXINIT`.

〔Decision〕**Rekeying has a timeout** (2 minutes by default): if our `KEXINIT` never gets the peer's, or the exchange stalls midway,
the connection is dropped with `Timeout` (`Phase = Rekeying`). While the gate is closed, all channel data is stashed and keepalive probes cannot go out —
without a timeout the connection would simply stop, silently. Reaching the deadline **faults the connection directly** rather than only cancelling the exchange's token: the exchange's messages go through the send pump,
and when our sending is stuck (the peer does not read, the link is half-dead), "wait for this frame to go out" does not respond to cancellation; faulting stops the send pump, which is what releases the stuck write.
A rekey initiated by the peer used to only cancel the token, and once our sending got stuck it waited forever.

〔Decision〕**The gate opens only when the exchange succeeds.** When it fails (host key changed, signature check failed, timeout), the gate stays closed and the connection is torn down;
the stash is dropped by the send pump's teardown, which also releases senders waiting on backpressure with a connection-closed exception. It used to open the gate on failure too:
the send pump could write the stashed channel data before the connection was torn down — application data after `KEXINIT` and before `NEWKEYS` violates RFC 4253 §7.1,
and nothing more should go out right after deciding that "the host key changed".

### 8.3 Receiving side

```mermaid
stateDiagram-v2
    [*] --> Open
    Open --> Rekeying : Peer KEXINIT received<br/>or local threshold triggered
    Rekeying --> Rekeying : Only process packets in the 1..49 range
    Rekeying --> Open : NEWKEYS complete in both directions<br/>(sequence numbers reset under strict KEX)
    Open --> Closing : DISCONNECT / local close
    Closing --> [*]
```

〔Note〕**Channel data can still be received during rekeying.** The gate constrains only the **sending** direction;
the RFC imposes no such restriction on the receiving direction (the peer may already have put data on the wire before it sent its KEXINIT).
Blocking the receiving side as well would lose data.

### 8.4 What is **not** done during rekeying

| Not done | Rationale |
| --- | --- |
| `ext-info-c` is not renegotiated | Explicitly forbidden by RFC 8308 §2.2 (§2.3) |
| `session_id` is not reset | §4.3 |
| Existing channels are not interrupted | Channels sit above the transport layer and are unaware of rekeying |
| The host key fingerprint is not shown to the user again for re-verification | 〔Decision〕**But the signature is still verified**. If `K_S` differs from the first time, disconnect immediately and report `HostKeyChanged` —— there is no legitimate scenario for changing the host key mid-connection |

---

## 9 Boundaries and errors quick reference

| Situation | Failure reason | Retryable |
| --- | --- | :-: |
| Our list is empty or contains a name this library does not implement | Not a connection failure: `ArgumentException` before dialing (§2.2) | No (fix the configuration) |
| No intersection in any algorithm category | `NegotiationFailed` (with both sides' lists) | No (unless configuration is changed) |
| Wrong `Q_C`/`Q_S` length | `ProtocolError` | No |
| X25519 result is all zeros | `ProtocolError` | No |
| ECDH point not on the curve | `ProtocolError` | No |
| DH `e`/`f` out of range | `ProtocolError` | No |
| Wrong total length of a hybrid method's `S_REPLY` (§3.6 / §3.7) | `ProtocolError` | No |
| `Q_S` of a NIST-curve hybrid not uncompressed or not on the curve (§3.7) | `ProtocolError` | No |
| ML-KEM ciphertext modified (implicit rejection, shows up as signature verification failure, §3.7.3) | `HostKeyRejected` | No |
| GEX `p` smaller than 2048 bits or larger than 8192 bits | `NegotiationFailed` | No |
| GEX `p` not prime (even, has a small factor, or Miller-Rabin finds a witness of compositeness) | `ProtocolError` | No |
| GEX `g` not satisfying `1 < g < p-1` | `ProtocolError` | No |
| Signature algorithm name does not match the negotiation result | `ProtocolError` | No |
| Signature verification fails | `HostKeyRejected` | No |
| RSA modulus below the minimum | `HostKeyRejected` | No (can be relaxed by configuration) |
| A certificate algorithm is negotiated but `K_S` is not a certificate (or vice versa) | `HostKeyRejected` | No |
| A host certificate vouched for by a CA is invalid (§5.5 item 3) | `HostKeyRejected` | Yes (after the certificate is re-issued) |
| Rejected by policy | `HostKeyRejected` / `HostKeyChanged` | Yes (after the user changes trust) |
| IGNORE/DEBUG received during the first KEX under strict KEX | `ProtocolError` | No |
| Under strict KEX, the peer sent other packets before its KEXINIT | `ProtocolError` | No |
| `K_S` changed during rekeying | `HostKeyChanged` | No |
| KEX timeout | `Timeout` | Yes |

**Every `ProtocolError` SHOULD send `SSH_MSG_DISCONNECT` before disconnecting**,
on a best-effort basis —— failure to send it does not affect the disconnect itself. Reason code: a peer public value failing its checks during key exchange (in the table above: wrong `Q_C`/`Q_S` length, all-zero X25519,
the ECDH point, DH out of range, a non-prime GEX `p` or an out-of-range `g`, and the two hybrid rows) sends `SSH_DISCONNECT_KEY_EXCHANGE_FAILED = 3` (§3.7.4);
everything else sends `SSH_DISCONNECT_PROTOCOL_ERROR = 2`.
