//! The TLS 1.3 client handshake and the post-handshake stream.
//!
//! State machine per docs/specs/tls13-core.md §1: ServerHello in the clear,
//! then EncryptedExtensions → Certificate → CertificateVerify → Finished
//! under handshake keys (possibly straddling records), then exactly one
//! client Finished, then application data both ways.
//!
//! Tolerance rules that are load-bearing against real Xray REALITY servers
//! (docs/specs/REALITY-client.md §9): dummy ChangeCipherSpec records are
//! skipped, and after the handshake the server may send validly-encrypted
//! *empty* application-data records replicating the fallback site's ticket
//! flow — they must be consumed silently. Session tickets and KeyUpdate
//! arriving post-handshake are processed or ignored, never fatal.

use std::io;
use std::pin::Pin;
use std::task::{Context, Poll};

use bytes::{Buf, BufMut, BytesMut};
use ml_kem::Decapsulate;
use subtle::ConstantTimeEq;
use tokio::io::{AsyncRead, AsyncReadExt, AsyncWrite, AsyncWriteExt, ReadBuf};
use zero_core::{Confidence, Failure, FailureKind, Stage};
use zeroize::Zeroize;

use super::hello::{
    build as build_hello, offers_certificate_compression, ClientKeypair, HelloParams,
};
use super::kdf::{
    establish_application_secrets, establish_handshake_secrets, finished_verify_data,
    next_traffic_secret, Transcript,
};
use super::record::{
    check_cleartext_body, parse_header, record_header, RecordCrypter, CONTENT_ALERT,
    CONTENT_APPDATA, CONTENT_CCS, CONTENT_HANDSHAKE, DUMMY_CCS,
};
use super::{malformed, CipherSuite, MAX_PLAINTEXT};

/// Handshake message types we handle.
mod msg {
    pub const SERVER_HELLO: u8 = 2;
    pub const NEW_SESSION_TICKET: u8 = 4;
    pub const ENCRYPTED_EXTENSIONS: u8 = 8;
    pub const CERTIFICATE: u8 = 11;
    pub const CERTIFICATE_VERIFY: u8 = 15;
    pub const FINISHED: u8 = 20;
    pub const KEY_UPDATE: u8 = 24;
    pub const COMPRESSED_CERTIFICATE: u8 = 25;
}

/// The HelloRetryRequest sentinel random (RFC 8446 §4.1.3). We do not follow
/// retries; seeing it means the server refused our key share.
const HRR_RANDOM: [u8; 32] = [
    0xcf, 0x21, 0xad, 0x74, 0xe5, 0x9a, 0x61, 0x11, 0xbe, 0x1d, 0x8c, 0x02, 0x1e, 0x65, 0xb8, 0x91,
    0xc2, 0xa2, 0x11, 0x16, 0x7a, 0xbb, 0x8c, 0x5e, 0x07, 0x9e, 0x09, 0xe2, 0xc8, 0xa8, 0x33, 0x9c,
];

/// Certificate authentication policy.
///
/// The minimal stack does no X.509 chain validation; the policy owns the
/// decision. REALITY replaces it entirely with the temporary-certificate
/// HMAC (see `crate::reality`), which also returns the leaf's Ed25519 public
/// key so the CertificateVerify signature can be checked.
pub trait ServerAuth: Send + Sync {
    /// Inspect the leaf certificate DER. Returns the raw public key bytes
    /// from its SubjectPublicKeyInfo (32 bytes for Ed25519).
    fn verify_certificate(&self, cert_der: &[u8]) -> Result<Vec<u8>, Failure>;

    /// Verify a certificate with the handshake bytes available. REALITY's
    /// optional ML-DSA-65 binding signs an HMAC over both hellos; ordinary
    /// certificate policies can use the default implementation.
    fn verify_certificate_with_context(
        &self,
        cert_der: &[u8],
        _client_hello: &[u8],
        _server_hello: &[u8],
    ) -> Result<Vec<u8>, Failure> {
        self.verify_certificate(cert_der)
    }
}

/// A hello prepared for sending. `msg` is public so REALITY can patch its
/// sealed tag into bytes 39..71 before the record goes on the wire.
pub struct PendingHello {
    pub msg: Vec<u8>,
    keypair: ClientKeypair,
    /// The hello offered `compress_certificate`, so a `CompressedCertificate`
    /// from the server is legitimate (RFC 8879 §4: the server may send one
    /// only when asked).
    compression_offered: bool,
}

impl PendingHello {
    /// Build with `params`; `params.session_id` lands verbatim at msg[39..71].
    pub fn new(params: &HelloParams) -> Self {
        let (msg, keypair) = build_hello(params);
        Self {
            msg,
            keypair,
            compression_offered: offers_certificate_compression(params.fingerprint),
        }
    }

    /// The 32-byte session-id field as currently in the message.
    pub fn session_id(&self) -> &[u8] {
        &self.msg[39..71]
    }

    /// The ephemeral keypair behind the key share. REALITY derives its auth
    /// key from this secret without consuming it; the handshake later uses
    /// the same secret for the TLS ECDHE.
    pub fn keypair(&self) -> &ClientKeypair {
        &self.keypair
    }

    /// The hello random (salt and nonce source for the REALITY seal).
    pub fn random(&self) -> &[u8] {
        &self.msg[6..38]
    }
}

/// Everything a completed handshake hands to the caller.
pub struct HandshakeResult<S> {
    pub stream: Tls13Stream<S>,
    pub suite: CipherSuite,
}

/// Run the full handshake over `io` and return a usable stream.
pub async fn handshake<S>(
    mut io: S,
    hello: PendingHello,
    auth: &dyn ServerAuth,
) -> Result<HandshakeResult<S>, Failure>
where
    S: AsyncRead + AsyncWrite + Unpin,
{
    let stage = Stage::TlsStarted;

    // ── ClientHello ──────────────────────────────────────────────────────
    let mut record = Vec::with_capacity(5 + hello.msg.len());
    // TLS 1.3 keeps the legacy ClientHello record version at 0x0301 for
    // middlebox compatibility. Subsequent protected records use 0x0303.
    let mut hello_header = record_header(CONTENT_HANDSHAKE, hello.msg.len());
    hello_header[2] = 0x01;
    record.extend_from_slice(&hello_header);
    record.extend_from_slice(&hello.msg);
    io.write_all(&record)
        .await
        .map_err(|e| Failure::from_io(&e, stage))?;
    io.flush().await.map_err(|e| Failure::from_io(&e, stage))?;

    // ── ServerHello ──────────────────────────────────────────────────────
    let sh = read_server_hello(&mut io).await?;
    let suite = parse_server_hello(&sh, hello.session_id())?;
    let server_share = extract_server_key_share(&sh)?;

    let mut transcript = Transcript::new(suite.hash);
    transcript.update(&hello.msg);
    transcript.update(&sh);

    // ── Key schedule, phase one ──────────────────────────────────────────
    let mut shared = match server_share.group {
        0x001d if server_share.data.len() == 32 => x25519_dalek::x25519(
            hello.keypair.secret,
            server_share.data[..].try_into().unwrap(),
        )
        .to_vec(),
        0x11ec if server_share.data.len() == 1088 + 32 => {
            // X25519MLKEM768 puts the ML-KEM ciphertext first and the
            // X25519 server share last. Go's TLS implementation concatenates
            // the KEM secret before the ECDH secret for this group.
            let decapsulation_key = hello.keypair.mlkem.as_ref().ok_or_else(|| {
                malformed("server selected X25519MLKEM768, which the hello did not offer")
            })?;
            let mlkem = decapsulation_key
                .decapsulate_slice(&server_share.data[..1088])
                .map_err(|_| malformed("invalid ML-KEM-768 server ciphertext"))?;
            let x25519 = x25519_dalek::x25519(
                hello.keypair.secret,
                server_share.data[1088..].try_into().unwrap(),
            );
            let mut shared = Vec::with_capacity(64);
            shared.extend_from_slice(mlkem.as_ref());
            shared.extend_from_slice(&x25519);
            shared
        }
        _ => return Err(malformed("unsupported or malformed server key share")),
    };
    if shared.iter().all(|b| *b == 0) {
        return Err(malformed("ECDH produced a degenerate shared secret"));
    }
    let ch_sh_hash = transcript.snapshot();
    let schedule = establish_handshake_secrets(suite, &shared, &ch_sh_hash);
    shared.zeroize();

    let mut read_crypter = RecordCrypter::new(suite, &schedule.server_hs_traffic);

    // ── Encrypted flight: EE, Certificate, CertificateVerify, Finished ──
    let mut acc: Vec<u8> = Vec::new();
    let mut got_ee = false;
    // The public key the certificate policy authenticated; CertificateVerify
    // must be checked against exactly this key.
    let mut leaf_key: Option<Vec<u8>> = None;
    let mut got_cv = false;
    let mut got_finished = false;

    while !got_finished {
        let (inner_type, payload) = read_encrypted_record(&mut io, &mut read_crypter).await?;
        if inner_type != CONTENT_HANDSHAKE {
            return Err(malformed(format!(
                "expected handshake content inside encrypted records, got {inner_type:#04x}"
            )));
        }
        acc.extend_from_slice(&payload);
        if acc.len() > 4 * MAX_PLAINTEXT {
            return Err(malformed(
                "encrypted handshake flight exceeds the size limit",
            ));
        }

        // Parse every complete message currently buffered.
        let mut at = 0usize;
        while !got_finished && at + 4 <= acc.len() {
            let mtype = acc[at];
            let mlen = read_u24(&acc, at + 1)?;
            let total = 4 + mlen;
            if at + total > acc.len() {
                break; // message straddles records; wait for the next one
            }
            let body = &acc[at + 4..at + total];

            match mtype {
                msg::ENCRYPTED_EXTENSIONS if !got_ee && leaf_key.is_none() => got_ee = true,
                msg::CERTIFICATE if leaf_key.is_none() => {
                    let leaf = certificate_leaf_der(body)?;
                    leaf_key = Some(auth.verify_certificate_with_context(leaf, &hello.msg, &sh)?);
                }
                msg::COMPRESSED_CERTIFICATE if leaf_key.is_none() && hello.compression_offered => {
                    let certificate = inflate_certificate(body)?;
                    let leaf = certificate_leaf_der(&certificate)?;
                    leaf_key = Some(auth.verify_certificate_with_context(leaf, &hello.msg, &sh)?);
                }
                msg::CERTIFICATE_VERIFY if !got_cv => {
                    let Some(key) = leaf_key.as_deref() else {
                        return Err(malformed("CertificateVerify before Certificate"));
                    };
                    verify_certificate_verify(body, key, &transcript)?;
                    got_cv = true;
                }
                msg::FINISHED if got_cv => {
                    // verify_data covers CH..CertificateVerify, i.e. the
                    // transcript as it stands before this message.
                    let th = transcript.snapshot();
                    let expect = finished_verify_data(suite.hash, &schedule.server_hs_traffic, &th);
                    if !bool::from(body.ct_eq(expect.as_slice())) {
                        return Err(malformed("server Finished verify_data mismatch"));
                    }
                    got_finished = true;
                }
                msg::NEW_SESSION_TICKET => { /* tickets never join the transcript */ }
                other => {
                    return Err(malformed(format!(
                        "unexpected handshake message type {other} in the encrypted flight"
                    )))
                }
            }
            if mtype != msg::NEW_SESSION_TICKET {
                transcript.update(&acc[at..at + total]);
            }
            at += total;
        }
        acc.drain(..at);
    }

    // ── Key schedule, phase two ──────────────────────────────────────────
    let full_hash = transcript.snapshot();
    let (client_app, server_app) = establish_application_secrets(&schedule, &full_hash);

    // ── Client Finished ──────────────────────────────────────────────────
    let vd = finished_verify_data(suite.hash, &schedule.client_hs_traffic, &full_hash);
    let mut finished_msg = Vec::with_capacity(4 + vd.len());
    finished_msg.push(msg::FINISHED);
    finished_msg.extend_from_slice(&(vd.len() as u32).to_be_bytes()[1..]);
    finished_msg.extend_from_slice(&vd);

    let mut write_hs = RecordCrypter::new(suite, &schedule.client_hs_traffic);
    let sealed = write_hs.seal(&finished_msg, CONTENT_HANDSHAKE)?;
    // One write, as a browser sends them: the dummy CCS, then the Finished.
    let mut flight = Vec::with_capacity(DUMMY_CCS.len() + sealed.bytes.len());
    flight.extend_from_slice(&DUMMY_CCS);
    flight.extend_from_slice(&sealed.bytes);
    io.write_all(&flight)
        .await
        .map_err(|e| Failure::from_io(&e, stage))?;
    io.flush().await.map_err(|e| Failure::from_io(&e, stage))?;

    Ok(HandshakeResult {
        stream: Tls13Stream::new(io, suite, server_app, client_app),
        suite,
    })
}

/// CertificateVerify: parse, and verify against the authenticated leaf key
/// over `Hash(CH .. Certificate)` with the RFC 8446 §4.4.3 framing.
///
/// `leaf_key` is the key the `ServerAuth` policy returned. When it is an
/// Ed25519 key (every REALITY certificate) the signature *must* be Ed25519
/// and must verify: the certificate HMAC alone is replayable by an on-path
/// attacker who relays our hello to the real server, and CertificateVerify is
/// the proof that the peer we derived keys with owns the certificate.
fn verify_certificate_verify(
    cv_body: &[u8],
    leaf_key: &[u8],
    transcript: &Transcript,
) -> Result<(), Failure> {
    if cv_body.len() < 4 {
        return Err(super::truncated("CertificateVerify"));
    }
    let alg = u16::from_be_bytes([cv_body[0], cv_body[1]]);
    let sig_len = u16::from_be_bytes([cv_body[2], cv_body[3]]) as usize;
    if cv_body.len() != 4 + sig_len {
        return Err(malformed("CertificateVerify length mismatch"));
    }
    let Ok(pubkey) = <[u8; 32]>::try_from(leaf_key) else {
        // Only Ed25519 is verifiable here; that is what REALITY servers use.
        // A policy authenticating some other key type owns that decision.
        return Ok(());
    };
    if alg != 0x0807 {
        return Err(malformed(format!(
            "CertificateVerify algorithm {alg:#06x} does not match the Ed25519 leaf key"
        )));
    }
    if sig_len != 64 {
        return Err(malformed("Ed25519 CertificateVerify is not 64 bytes"));
    }

    let th = transcript.snapshot();
    let mut signed = Vec::with_capacity(64 + 34 + th.len());
    signed.extend_from_slice(&[0x20u8; 64]);
    signed.extend_from_slice(b"TLS 1.3, server CertificateVerify");
    signed.push(0x00);
    signed.extend_from_slice(&th);

    use ed25519_dalek::{Signature, Verifier, VerifyingKey};
    let key = VerifyingKey::from_bytes(&pubkey)
        .map_err(|e| malformed(format!("bad Ed25519 leaf key: {e}")))?;
    let sig_arr: [u8; 64] = cv_body[4..4 + 64]
        .try_into()
        .map_err(|_| malformed("CertificateVerify signature is not 64 bytes"))?;
    let sig = Signature::from_bytes(&sig_arr);
    key.verify(&signed, &sig)
        .map_err(|_| malformed("CertificateVerify signature did not verify"))?;
    Ok(())
}

/// Read the ServerHello handshake message from cleartext records, skipping
/// dummy CCS/mimicry records.
///
/// Returns exactly the one handshake message (4-byte header included), which
/// is what the transcript must hash. A server may legally fragment the
/// ServerHello across several records; nothing may follow it in cleartext,
/// because every later handshake message is encrypted.
async fn read_server_hello<S>(io: &mut S) -> Result<Vec<u8>, Failure>
where
    S: AsyncRead + AsyncWrite + Unpin,
{
    let mut message: Vec<u8> = Vec::new();
    // One record buffer for the whole call: before the ServerHello every
    // record is cleartext and at most one plaintext long, so the buffer grows
    // to that once and is reused. Allocating per record would put a
    // peer-sized allocation on the read path for nothing.
    let mut body: Vec<u8> = Vec::new();
    let mut guard = 0u64;
    loop {
        let mut header = [0u8; 5];
        io.read_exact(&mut header)
            .await
            .map_err(|e| classify_eof(e, "waiting for ServerHello"))?;
        let (ctype, len) = parse_header(&header)?;
        // Nothing here is protected yet: the body is plaintext, and Go fails
        // one longer than a plaintext (`RL/conn.go:725-727`).
        check_cleartext_body(len)?;

        body.resize(len, 0);
        match ctype {
            CONTENT_HANDSHAKE => {
                io.read_exact(&mut body)
                    .await
                    .map_err(|e| classify_eof(e, "reading ServerHello"))?;
                if body.is_empty() {
                    // RFC 8446 §5.1: zero-length handshake fragments are illegal.
                    return Err(malformed("empty handshake record before ServerHello"));
                }
                message.extend_from_slice(&body);
                if message.len() >= 4 {
                    let need = 4 + read_u24(&message, 1)?;
                    if need > MAX_PLAINTEXT {
                        return Err(malformed("ServerHello exceeds the size limit"));
                    }
                    match message.len().cmp(&need) {
                        std::cmp::Ordering::Equal => return Ok(message),
                        std::cmp::Ordering::Greater => {
                            return Err(malformed(
                                "unexpected cleartext handshake data after ServerHello",
                            ))
                        }
                        std::cmp::Ordering::Less => {} // fragmented; keep reading
                    }
                }
            }
            CONTENT_CCS | CONTENT_APPDATA if message.is_empty() => {
                io.read_exact(&mut body)
                    .await
                    .map_err(|e| classify_eof(e, "reading pre-handshake record"))?;
                // dummy CCS or mimicry: skip
            }
            CONTENT_ALERT => {
                io.read_exact(&mut body)
                    .await
                    .map_err(|e| classify_eof(e, "reading alert"))?;
                return Err(alert_failure(&body));
            }
            _ if !message.is_empty() => {
                return Err(malformed(format!(
                    "record type {ctype:#04x} interleaved with a fragmented ServerHello"
                )))
            }
            _ => return Err(malformed(format!("unexpected record type {ctype:#04x}"))),
        }
        guard += 1;
        if guard > 64 {
            return Err(malformed(
                "too many non-handshake records before ServerHello",
            ));
        }
    }
}

/// Read and decrypt one protected record after the ServerHello.
async fn read_encrypted_record<S>(
    io: &mut S,
    crypter: &mut RecordCrypter,
) -> Result<(u8, Vec<u8>), Failure>
where
    S: AsyncRead + AsyncWrite + Unpin,
{
    let mut guard = 0u64;
    // One buffer for the whole call, reused per record: the record a peer
    // declares can be thousands of bytes, and a read path that allocates one
    // per record hands it that memory each time.
    let mut body: Vec<u8> = Vec::new();
    loop {
        let mut header = [0u8; 5];
        io.read_exact(&mut header)
            .await
            .map_err(|e| classify_eof(e, "waiting for encrypted flight"))?;
        let (ctype, len) = parse_header(&header)?;
        if ctype != CONTENT_APPDATA {
            // Not protected, so the body is plaintext and Go's narrower bound
            // applies (`RL/conn.go:725-727`). The protected case is checked
            // inside `open_in_place`, at the TLS 1.3 ciphertext bound.
            check_cleartext_body(len)?;
        }

        body.resize(len, 0);
        io.read_exact(&mut body)
            .await
            .map_err(|e| classify_eof(e, "reading encrypted flight"))?;

        match ctype {
            CONTENT_APPDATA => {
                let (inner_type, len) = crypter.open_in_place(&header, &mut body)?;
                body.truncate(len);
                return Ok((inner_type, body));
            }
            CONTENT_CCS => { /* middlebox-compat dummy */ }
            CONTENT_ALERT => return Err(alert_failure(&body)),
            CONTENT_HANDSHAKE => {
                return Err(malformed(
                    "cleartext handshake record inside the encrypted flight",
                ))
            }
            _ => return Err(malformed(format!("unexpected record type {ctype:#04x}"))),
        }
        guard += 1;
        if guard > 64 {
            return Err(malformed(
                "too many useless records in the encrypted flight",
            ));
        }
    }
}

fn classify_eof(e: std::io::Error, ctx: &'static str) -> Failure {
    let mut f = Failure::from_io(&e, Stage::TlsStarted);
    f.detail = Some(format!("{ctx}: {e}"));
    f
}

fn alert_failure(body: &[u8]) -> Failure {
    let desc = body.get(1).copied().unwrap_or(0xff);
    let kind = if desc == 0 {
        FailureKind::Cancelled // close_notify
    } else {
        FailureKind::TlsAlert
    };
    Failure::new(kind, Stage::TlsStarted)
        .with_confidence(Confidence::Confirmed)
        .with_detail(format!("alert description {desc}"))
}

/// Validate a ServerHello against what we sent. Returns the negotiated suite.
fn parse_server_hello(sh: &[u8], our_session_id: &[u8]) -> Result<CipherSuite, Failure> {
    if sh.first() != Some(&msg::SERVER_HELLO) {
        return Err(malformed(
            "first server handshake message is not ServerHello",
        ));
    }
    let mut at = 4usize;

    at += 2; // legacy_version

    let random = super::take(sh, at, 32, "server random")?;
    if random == HRR_RANDOM {
        return Err(malformed(
            "server sent HelloRetryRequest; the hello's key share was not acceptable",
        ));
    }
    at += 32;

    let sid_len = byte_at(sh, at, "session id length")? as usize;
    at += 1;
    let sid = super::take(sh, at, sid_len, "session id")?;
    if sid != our_session_id {
        return Err(malformed("server did not echo our session id"));
    }
    at += sid_len;

    let suite_id = u16::from_be_bytes(super::take(sh, at, 2, "cipher suite")?.try_into().unwrap());
    at += 2;
    let suite = CipherSuite::by_id(suite_id)
        .ok_or_else(|| malformed(format!("server selected unknown suite {suite_id:#06x}")))?;

    let compression = byte_at(sh, at, "compression")?;
    at += 1;
    if compression != 0 {
        return Err(malformed("server selected non-null compression"));
    }

    // Extensions: supported_versions must confirm 1.3.
    let ext_total = u16::from_be_bytes(
        super::take(sh, at, 2, "extensions length")?
            .try_into()
            .unwrap(),
    ) as usize;
    at += 2;
    let end = at + ext_total;
    if end > sh.len() {
        return Err(super::truncated("server extensions"));
    }

    let mut saw_tls13 = false;
    while at + 4 <= end {
        let etype = u16::from_be_bytes(sh[at..at + 2].try_into().unwrap());
        let elen = u16::from_be_bytes(sh[at + 2..at + 4].try_into().unwrap()) as usize;
        at += 4;
        let body = super::take(sh, at, elen, "extension body")?;
        at += elen;
        // ClientHello carries a length-prefixed list here, but ServerHello
        // carries the single selected version directly (RFC 8446 §4.2.1).
        if etype == 43 && body == [0x03, 0x04] {
            saw_tls13 = true;
        }
    }
    if !saw_tls13 {
        // A fallback target on TLS 1.2 shows up exactly here.
        return Err(malformed("server did not negotiate TLS 1.3"));
    }
    Ok(suite)
}

struct ServerKeyShare {
    group: u16,
    data: Vec<u8>,
}

/// Extract the selected X25519 or X25519MLKEM768 share from ServerHello.
fn extract_server_key_share(sh: &[u8]) -> Result<ServerKeyShare, Failure> {
    let mut at = 4 + 2 + 32;
    let sid_len = byte_at(sh, at, "session id length")? as usize;
    at += 1 + sid_len + 2 + 1;
    let ext_total = u16::from_be_bytes(
        super::take(sh, at, 2, "extensions length")?
            .try_into()
            .unwrap(),
    ) as usize;
    at += 2;
    let end = at + ext_total;
    if end > sh.len() {
        return Err(super::truncated("server extensions"));
    }

    while at + 4 <= end {
        let etype = u16::from_be_bytes(sh[at..at + 2].try_into().unwrap());
        let elen = u16::from_be_bytes(sh[at + 2..at + 4].try_into().unwrap()) as usize;
        at += 4;
        let body = super::take(sh, at, elen, "key_share body")?;
        at += elen;
        if etype == 51 {
            // ServerHello carries one selected share directly; the
            // two-byte vector length exists only in ClientHello.
            if body.len() < 4 {
                return Err(super::truncated("server key_share"));
            }
            let group = u16::from_be_bytes(body[..2].try_into().unwrap());
            let klen = u16::from_be_bytes(body[2..4].try_into().unwrap()) as usize;
            let data = super::take(body, 4, klen, "server key_share entry")?;
            if body.len() != 4 + klen {
                return Err(malformed("trailing bytes in server key_share"));
            }
            if (group == 0x001d && klen == 32) || (group == 0x11ec && klen == 1088 + 32) {
                return Ok(ServerKeyShare {
                    group,
                    data: data.to_vec(),
                });
            }
        }
    }
    Err(malformed("no X25519 key share in ServerHello"))
}

/// Pull the leaf certificate DER out of a Certificate handshake message.
fn certificate_leaf_der(body: &[u8]) -> Result<&[u8], Failure> {
    let ctx_len = byte_at(body, 0, "cert request context length")? as usize;
    let mut at = 1 + ctx_len;
    let list_len = read_u24(body, at)?;
    at += 3;
    if list_len == 0 {
        return Err(malformed("empty certificate list"));
    }
    let cert_len = read_u24(body, at)?;
    at += 3;
    super::take(body, at, cert_len, "certificate DER")
}

/// The largest Certificate message a `CompressedCertificate` may inflate to.
/// RFC 8879 §4 asks for a cap so a small message cannot claim a huge one;
/// real chains are a few kilobytes.
const MAX_INFLATED_CERTIFICATE: usize = 1 << 16;

/// Inflate a `CompressedCertificate` body (RFC 8879 §4) into the body of the
/// Certificate message it stands for.
///
/// Layout: algorithm (2), uncompressed length (3), compressed length (3),
/// data. Only brotli is accepted because only brotli was offered. The output
/// must be exactly the length the server declared: a bomb that expands past
/// it, or a message that stops short, fails the handshake. The transcript
/// still hashes the message as it came off the wire (the caller does that),
/// not this inflated form.
fn inflate_certificate(body: &[u8]) -> Result<Vec<u8>, Failure> {
    use std::io::Read;
    let algorithm = u16::from_be_bytes([
        byte_at(body, 0, "algorithm")?,
        byte_at(body, 1, "algorithm")?,
    ]);
    if algorithm != 0x0002 {
        return Err(malformed(format!(
            "CompressedCertificate uses algorithm {algorithm:#06x}, only brotli was offered"
        )));
    }
    let declared = read_u24(body, 2)?;
    let compressed = read_u24(body, 5)?;
    let data = super::take(body, 8, compressed, "compressed certificate")?;
    if 8 + compressed != body.len() {
        return Err(malformed("CompressedCertificate has trailing bytes"));
    }
    if declared == 0 || declared > MAX_INFLATED_CERTIFICATE {
        return Err(malformed("CompressedCertificate declares an unusable size"));
    }
    let mut out = vec![0u8; declared];
    let mut reader = brotli_decompressor::Decompressor::new(data, 4096);
    reader
        .read_exact(&mut out)
        .map_err(|_| malformed("CompressedCertificate is shorter than it declared"))?;
    let mut extra = [0u8; 1];
    match reader.read(&mut extra) {
        Ok(0) => Ok(out),
        _ => Err(malformed(
            "CompressedCertificate is longer than it declared",
        )),
    }
}

fn byte_at(buf: &[u8], at: usize, what: &'static str) -> Result<u8, Failure> {
    Ok(super::take(buf, at, 1, what)?[0])
}

fn read_u24(buf: &[u8], at: usize) -> Result<usize, Failure> {
    let b = super::take(buf, at, 3, "u24 length")?;
    Ok(((b[0] as usize) << 16) | ((b[1] as usize) << 8) | b[2] as usize)
}

// ── The post-handshake stream ────────────────────────────────────────────

/// Sealed-but-unsent ciphertext at which `poll_write` stops accepting new
/// plaintext until the socket drains: four full records.
const OUTGOING_HIGH_WATER: usize = 4 * (MAX_PLAINTEXT + 5 + 1 + 16);

/// How many consecutive records that advance nothing a peer may send before
/// the connection is dead: Go's `maxUselessRecords` (`RL/common.go:70`),
/// enforced by `retryReadRecord` (`RL/conn.go:827-839`), which closes with
/// `alertUnexpectedMessage` and "tls: too many ignored records" on the
/// thirty-third. The run is *consecutive*: `readRecordOrCCS` resets the count
/// as soon as a record carries data (`RL/conn.go:734-737`), which is what
/// makes this a shape a real peer can rely on — a session that keeps making
/// progress may idle as long as it likes, while one that only emits
/// placeholders is bounded.
///
/// Go learns the number from the camouflage site and applies it to the
/// connections it accepts (`RL/tls.go:425-427`); the port learns it the same
/// way (see [`super::ccs_probe`]) and applies it through
/// [`Tls13Stream::set_max_useless_records`]. This is the value to use when
/// the site could not be asked, and the one every real site with Go's TLS
/// stack answers with.
pub const MAX_USELESS_RECORDS: u64 = 32;

/// The failure that trips the useless-record limit, as a caller can name
/// rather than one more `malformed`.
///
/// The limit is the stream's own, since Go's is (`RL/conn.go:831-833`:
/// `MaxUselessRecords`), so the message names it rather than the default.
fn too_many_useless_records(limit: u64) -> Failure {
    Failure::new(FailureKind::TlsAlert, Stage::TlsStarted)
        .with_confidence(Confidence::Confirmed)
        .with_detail(format!(
            "peer sent more than {limit} consecutive non-advancing records \
             (Go: alertUnexpectedMessage, \"tls: too many ignored records\")"
        ))
}

/// Plaintext of the record at the head of `wire`, as offsets into it.
/// `frame_len == 0` means no record is pending.
#[derive(Debug, Clone, Copy, Default)]
struct PlainFrame {
    pos: usize,
    end: usize,
    frame_len: usize,
}

/// A completed TLS 1.3 connection: decrypts inbound records, encrypts
/// outbound ones, and tolerates everything a REALITY server emits around
/// the data plane.
pub struct Tls13Stream<S> {
    inner: S,
    suite: CipherSuite,
    read: RecordCrypter,
    write: RecordCrypter,
    read_secret: Vec<u8>,
    write_secret: Vec<u8>,
    /// Raw bytes off the socket, not yet reassembled into records.
    wire: BytesMut,
    /// A record is decrypted in place inside `wire`, so its plaintext is
    /// already in place; `wire` holds the record until it has all been taken.
    plain: PlainFrame,
    /// Sealed records awaiting transmission.
    outgoing: BytesMut,
    eof: bool,
    close_sent: bool,
    /// XTLS Vision transitions are directional. A peer's authenticated
    /// `PaddingDirect` response authorizes raw bytes on the read path, but
    /// this client emits `PaddingEnd`, so its write path must remain inside
    /// the outer TLS carrier. Keeping the states separate prevents a fast
    /// response from exposing request bytes that are still being written.
    direct_read: bool,
    direct_write: bool,
    /// Consecutive records that advanced nothing: warning alerts, empty
    /// application data, change_cipher_spec. Reset by any record that does
    /// advance the stream; fatal past [`MAX_USELESS_RECORDS`].
    useless_records: u64,
    /// How many records that advance nothing this stream tolerates.
    ///
    /// Go's is the same field (`RL/conn.go:32`, `:831-833`), and Go's server
    /// sets it from what the camouflage site was found to answer with
    /// (`RL/tls.go:425-427`), so that a REALITY server puts up with exactly
    /// as many of them as the site it borrows its name from.
    max_useless_records: u64,
    /// Whether this end is the client.
    ///
    /// Go refuses a session ticket that arrives *from* a client
    /// (`RL/handshake_client_tls13.go:855-858`) and accepts one from a
    /// server, so the two ends answer the same message differently.
    is_client: bool,
}

impl<S> Tls13Stream<S> {
    /// Wrap a stream whose traffic keys the caller already derived.
    ///
    /// `pub` for the REALITY server in the `reality` crate, which terminates
    /// the handshake itself and then hands the record layer on; the client is
    /// the only caller inside this crate.
    pub fn new(inner: S, suite: CipherSuite, server_app: Vec<u8>, client_app: Vec<u8>) -> Self {
        Self {
            inner,
            suite,
            read: RecordCrypter::new(suite, &server_app),
            write: RecordCrypter::new(suite, &client_app),
            read_secret: server_app,
            write_secret: client_app,
            wire: BytesMut::with_capacity(16 * 1024),
            plain: PlainFrame::default(),
            outgoing: BytesMut::new(),
            eof: false,
            close_sent: false,
            direct_read: false,
            direct_write: false,
            useless_records: 0,
            max_useless_records: MAX_USELESS_RECORDS,
            is_client: true,
        }
    }

    /// Say that this end is the *server*, so a session ticket arriving from
    /// the peer is refused rather than ignored.
    ///
    /// The REALITY server in the `reality` crate terminates the handshake
    /// itself and then hands the record layer on, so it has to say so.
    pub fn set_server_side(&mut self) {
        self.is_client = false;
    }

    pub fn suite(&self) -> CipherSuite {
        self.suite
    }

    /// Queue empty application-data records of these wire sizes behind
    /// anything already waiting to be sent. They leave on the next flush.
    pub fn queue_empty_records(&mut self, wire_lens: &[u16]) -> Result<(), super::Failure> {
        for &wire_len in wire_lens {
            self.write
                .seal_empty_into(wire_len as usize, &mut self.outgoing)?;
        }
        Ok(())
    }

    /// Set how many records that advance nothing this stream tolerates.
    ///
    /// The value a camouflage site was found to answer with is the value a
    /// REALITY server answers with, so that the two cannot be told apart by
    /// how long they put up with a run of them (`RL/tls.go:425-427`).
    pub fn set_max_useless_records(&mut self, limit: u64) {
        self.max_useless_records = limit;
    }

    /// Enter Vision's authenticated direct-read mode. The protocol layer
    /// calls this only after consuming a valid `PaddingDirect` frame; an
    /// unauthenticated record-shaped prefix must never bypass the outer
    /// record authenticator.
    pub fn enter_direct_mode(&mut self) {
        self.direct_read = true;
    }
}

impl<S> Drop for Tls13Stream<S> {
    fn drop(&mut self) {
        self.read_secret.zeroize();
        self.write_secret.zeroize();
    }
}

impl<S: AsyncRead + AsyncWrite + Unpin> Tls13Stream<S> {
    /// Turn buffered wire bytes into plaintext. Ok(false) means clean EOF.
    fn pump_records(&mut self) -> Result<bool, Failure> {
        loop {
            if self.wire.len() < 5 {
                return Ok(true);
            }
            let (ctype, len) = {
                let hdr = [
                    self.wire[0],
                    self.wire[1],
                    self.wire[2],
                    self.wire[3],
                    self.wire[4],
                ];
                parse_header(&hdr)?
            };
            if self.wire.len() < 5 + len {
                return Ok(true);
            }
            if ctype != CONTENT_APPDATA {
                // After the handshake the only protected type is
                // application_data; a change_cipher_spec or a cleartext alert
                // is plaintext on the wire, so Go's `maxPlaintext` bound
                // applies to its body (`RL/conn.go:725-727`).
                check_cleartext_body(len)?;
            }
            let mut header = [0u8; 5];
            header.copy_from_slice(&self.wire[..5]);

            match ctype {
                CONTENT_CCS => {
                    // A compatibility change_cipher_spec is legal but useless;
                    // Go counts one that arrives during a TLS 1.3 handshake
                    // against `MaxUselessRecords` (`RL/conn.go:793-795`) and
                    // refuses one after the handshake outright
                    // (`:796-798`). This stream stays tolerant of a stray CCS
                    // — REALITY's own peers can emit them — but a run of them
                    // is exactly the shape the counter exists to bound.
                    self.count_useless_record()?;
                    self.wire.advance(5 + len);
                }
                CONTENT_ALERT => {
                    let close_notify = self.wire.get(5 + 1) == Some(&0) && len >= 2;
                    if close_notify {
                        self.wire.advance(5 + len);
                        self.eof = true;
                        return Ok(false);
                    }
                    return Err(alert_failure(&self.wire[5..5 + len]));
                }
                CONTENT_HANDSHAKE => {
                    return Err(malformed(
                        "cleartext handshake record after the handshake completed",
                    ));
                }
                CONTENT_APPDATA => {
                    // Decrypt inside the wire buffer: no allocation, no copy.
                    let (inner_type, pt_len) = self
                        .read
                        .open_in_place(&header, &mut self.wire[5..5 + len])?;
                    let payload_range = 5..5 + pt_len;
                    match inner_type {
                        CONTENT_APPDATA => {
                            if pt_len == 0 {
                                // REALITY ticket-mimicry: validly encrypted
                                // empty records. Go counts these against
                                // `MaxUselessRecords` too (`RL/conn.go:803-811`),
                                // so the count *is* the old "ticket mimicry"
                                // bound: 32 consecutive ones is fewer than the
                                // 256 the port used to allow, and any run long
                                // enough for the old bound to matter trips this
                                // one first.
                                self.count_useless_record()?;
                            } else {
                                // The record advanced the stream; the run a
                                // peer may spend on placeholders starts over.
                                self.useless_records = 0;
                                self.plain = PlainFrame {
                                    pos: payload_range.start,
                                    end: payload_range.end,
                                    frame_len: 5 + len,
                                };
                            }
                        }
                        CONTENT_ALERT => {
                            let payload = &self.wire[payload_range];
                            if payload.get(1) == Some(&0) {
                                self.wire.advance(5 + len);
                                self.eof = true;
                                return Ok(false);
                            }
                            return Err(alert_failure(payload));
                        }
                        CONTENT_HANDSHAKE => {
                            // A post-handshake message carries data, so Go's
                            // `readRecordOrCCS` resets the count on the record
                            // before `handlePostHandshakeMessage` even looks
                            // at what it is (`RL/conn.go:734-737`).
                            self.useless_records = 0;
                            let payload = self.wire[payload_range].to_vec();
                            self.handle_post_handshake_messages(&payload)?;
                        }
                        _ => unreachable!("open validated the inner type"),
                    }
                    if self.plain.frame_len == 0 {
                        // Nothing to hand out, so the record can go now.
                        self.wire.advance(5 + len);
                    }

                    // Return after one authenticated plaintext record. Vision
                    // may need to inspect that record and authorize a direct
                    // carrier transition before the next raw bytes already
                    // buffered in `wire` are parsed. Draining the whole wire
                    // buffer here races that protocol-level state change and
                    // can mistake raw inner TLS for a failed outer record.
                    if self.plain.frame_len != 0 {
                        return Ok(true);
                    }
                }
                _ => return Err(malformed(format!("unexpected record type {ctype:#04x}"))),
            }
        }
    }

    /// One more record that advanced nothing, and the connection dies on the
    /// thirty-third consecutive one. Go's `retryReadRecord` (`RL/conn.go:827-839`):
    /// `retryCount++`, then `alertUnexpectedMessage` and "tls: too many
    /// ignored records" once the count passes `MaxUselessRecords`. The alert
    /// itself is not sendable here — the record layer has no way to report a
    /// warning without ending the stream — so the closure is the failure.
    fn count_useless_record(&mut self) -> Result<(), Failure> {
        self.useless_records += 1;
        if self.useless_records > self.max_useless_records {
            return Err(too_many_useless_records(self.max_useless_records));
        }
        Ok(())
    }

    /// Post-handshake handshake messages: session tickets are ignored,
    /// KeyUpdate rolls the traffic secrets (RFC 8446 §4.6.3).
    fn handle_post_handshake_messages(&mut self, payload: &[u8]) -> Result<(), Failure> {
        let mut at = 0usize;
        while at + 4 <= payload.len() {
            let mtype = payload[at];
            let mlen = match read_u24(payload, at + 1) {
                Ok(n) => n,
                Err(_) => return Ok(()), // fragment/mimicry: stop here
            };
            let body_at = at + 4;
            if body_at + mlen > payload.len() {
                return Ok(()); // incomplete trailing message: mimicry, not an error
            }
            if mtype == msg::KEY_UPDATE {
                // Go's `keyUpdateMsg` unmarshal reads one byte and requires
                // the body to be *empty* afterwards
                // (`RL/handshake_messages.go:1141-1151`), so a body of any
                // other length is refused rather than accepted. It also
                // accepts only 0 and 1 (`updateRequested`). A refused message
                // is an alert in Go (`RL/conn.go:1248-1250`:
                // `alertDecodeError`).
                if mlen != 1 || payload[body_at] > 1 {
                    return Err(alert_failure(&[0x15, 0x32]));
                }
                let next = next_traffic_secret(self.suite.hash, &self.read_secret);
                self.read_secret.zeroize();
                self.read_secret = next;
                self.read = RecordCrypter::new(self.suite, &self.read_secret);
                if payload[body_at] == 1 && !self.close_sent {
                    // Peer requests our update: answer with a not-requesting
                    // KeyUpdate, then roll the write side. RFC 8446 §4.6.3:
                    // the KeyUpdate itself is protected under the *old* key,
                    // and only the records after it use the new one — the
                    // peer switches its read key when it processes it.
                    let reply = [msg::KEY_UPDATE, 0, 0, 1, 0];
                    self.write
                        .seal_into(&reply, CONTENT_HANDSHAKE, &mut self.outgoing)?;
                    let next = next_traffic_secret(self.suite.hash, &self.write_secret);
                    self.write_secret.zeroize();
                    self.write_secret = next;
                    self.write = RecordCrypter::new(self.suite, &self.write_secret);
                }
            }
            if mtype == msg::NEW_SESSION_TICKET {
                // A ticket from a *client* is refused: the client is the one
                // that receives tickets (`RL/handshake_client_tls13.go:855-858`).
                // A ticket from a server is ordinary, and this end does no
                // resumption, so it is ignored.
                if !self.is_client {
                    return Err(alert_failure(&[0x15, 0x10]));
                }
            } else if mtype != msg::KEY_UPDATE {
                // An unexpected type is an alert in Go
                // (`RL/conn.go:1394-1398`: `alertUnexpectedMessage`).
                return Err(alert_failure(&[0x15, 0x10]));
            }
            at = body_at + mlen;
        }
        Ok(())
    }

    fn poll_flush_outgoing(&mut self, cx: &mut Context<'_>) -> Poll<io::Result<()>> {
        while !self.outgoing.is_empty() {
            match Pin::new(&mut self.inner).poll_write(cx, &self.outgoing) {
                Poll::Ready(Ok(0)) => {
                    return Poll::Ready(Err(io::Error::new(
                        io::ErrorKind::WriteZero,
                        "tls13 write returned 0",
                    )))
                }
                Poll::Ready(Ok(n)) => self.outgoing.advance(n),
                Poll::Ready(Err(e)) => return Poll::Ready(Err(e)),
                Poll::Pending => return Poll::Pending,
            }
        }
        Poll::Ready(Ok(()))
    }
}

/// A zero-length application-data record is the one no-op TLS 1.3 actually
/// permits: RFC 8446 §5.1 forbids empty fragments of handshake and alert
/// types, but explicitly allows them for application data. Servers in this
/// ecosystem already emit them as session-ticket mimicry, and this stream's
/// own read path already tolerates and bounds them — so a keepalive here is
/// indistinguishable from traffic the peer was going to send anyway.
///
/// Owning the TLS stack is what makes this possible at all: a stock TLS
/// library gives no way to emit a record with no payload, which is why
/// keepalive shaping is absent from proxies built on one.
impl<S: AsyncRead + AsyncWrite + Unpin> zero_evasion::KeepaliveCarrier for Tls13Stream<S> {
    fn poll_keepalive(self: Pin<&mut Self>, cx: &mut Context<'_>) -> Poll<io::Result<bool>> {
        let this = self.get_mut();
        // After a Vision direct-write transition there is no record layer left
        // to put a no-op into; the bytes would land in the peer's payload.
        if this.close_sent || this.direct_write {
            return Poll::Ready(Ok(false));
        }
        match this
            .write
            .seal_into(&[], CONTENT_APPDATA, &mut this.outgoing)
        {
            Ok(()) => {}
            Err(failure) => {
                return Poll::Ready(Err(io::Error::new(
                    io::ErrorKind::InvalidData,
                    failure.to_string(),
                )))
            }
        }
        match this.poll_flush_outgoing(cx) {
            // The record is buffered either way, so it is on its way out even
            // if the socket did not take it all this poll.
            Poll::Ready(Ok(())) | Poll::Pending => Poll::Ready(Ok(true)),
            Poll::Ready(Err(e)) => Poll::Ready(Err(e)),
        }
    }

    /// The server is Go's TLS stack (REALITY forks `crypto/tls`), which
    /// closes the connection with "too many ignored records" after a run of
    /// records that carry nothing: 16 in Go, 32 in current REALITY. Only
    /// application data from us ends the run. Half of the smaller limit
    /// leaves room for the peer to count something else we did not foresee.
    fn max_probes_between_writes(&self) -> Option<u32> {
        Some(8)
    }
}

impl<S: AsyncRead + AsyncWrite + Unpin> AsyncRead for Tls13Stream<S> {
    fn poll_read(
        self: Pin<&mut Self>,
        cx: &mut Context<'_>,
        buf: &mut ReadBuf<'_>,
    ) -> Poll<io::Result<()>> {
        let this = self.get_mut();

        loop {
            if this.plain.frame_len != 0 {
                let left = this.plain.end - this.plain.pos;
                let n = left.min(buf.remaining());
                buf.put_slice(&this.wire[this.plain.pos..this.plain.pos + n]);
                this.plain.pos += n;
                if this.plain.pos == this.plain.end {
                    // Fully delivered: the header, ciphertext and tag can go.
                    let frame_len = this.plain.frame_len;
                    this.plain = PlainFrame::default();
                    this.wire.advance(frame_len);
                }
                return Poll::Ready(Ok(()));
            }
            if this.eof {
                return Poll::Ready(Ok(())); // clean EOF: zero-byte read
            }
            if this.direct_read {
                if !this.wire.is_empty() {
                    let n = this.wire.len().min(buf.remaining());
                    let data = this.wire.split_to(n);
                    buf.put_slice(&data);
                    return Poll::Ready(Ok(()));
                }
                return Pin::new(&mut this.inner).poll_read(cx, buf);
            }

            match this.pump_records() {
                Ok(true) => {}
                Ok(false) => {
                    // A peer may put application data and close_notify in
                    // the same socket read. `pump_records` has already
                    // queued that plaintext before reporting EOF; drain it
                    // before exposing the clean end of stream.
                    if this.plain.frame_len != 0 {
                        continue;
                    }
                    return Poll::Ready(Ok(()));
                }
                Err(f) => {
                    return Poll::Ready(Err(io::Error::new(
                        io::ErrorKind::InvalidData,
                        f.to_string(),
                    )))
                }
            }
            if this.plain.frame_len != 0 || this.eof {
                continue; // something to deliver or EOF was reached
            }

            // Need more wire bytes.
            this.wire.reserve(16 * 1024);
            let (ptr, len) = {
                let chunk = this.wire.chunk_mut();
                (chunk.as_mut_ptr().cast(), chunk.len())
            };
            // SAFETY: `chunk_mut` just handed out this spare capacity.
            let mut sub = unsafe { ReadBuf::uninit(std::slice::from_raw_parts_mut(ptr, len)) };
            match Pin::new(&mut this.inner).poll_read(cx, &mut sub) {
                Poll::Ready(Ok(())) => {
                    let n = sub.filled().len();
                    if n == 0 {
                        // TCP EOF without a goodbye.
                        this.eof = true;
                        return Poll::Ready(Ok(()));
                    }
                    // SAFETY: n bytes were just filled into the spare
                    // capacity of wire.
                    unsafe { this.wire.advance_mut(n) };
                }
                Poll::Ready(Err(e)) => return Poll::Ready(Err(e)),
                Poll::Pending => return Poll::Pending,
            }
        }
    }
}

impl<S: AsyncRead + AsyncWrite + Unpin> AsyncWrite for Tls13Stream<S> {
    fn poll_write(
        self: Pin<&mut Self>,
        cx: &mut Context<'_>,
        buf: &[u8],
    ) -> Poll<io::Result<usize>> {
        let this = self.get_mut();

        if this.close_sent {
            return Poll::Ready(Err(io::Error::new(
                io::ErrorKind::BrokenPipe,
                "tls13 stream already closed",
            )));
        }

        if this.direct_write {
            return Pin::new(&mut this.inner).poll_write(cx, buf);
        }
        if buf.is_empty() {
            // An empty write must not put an (empty) record on the wire.
            return Poll::Ready(Ok(0));
        }

        // Backpressure: sealed-but-unsent bytes are bounded. Without this a
        // fast producer on a slow socket would have every write accepted and
        // queued, growing `outgoing` without limit.
        while this.outgoing.len() >= OUTGOING_HIGH_WATER {
            match Pin::new(&mut this.inner).poll_write(cx, &this.outgoing) {
                Poll::Ready(Ok(0)) => {
                    return Poll::Ready(Err(io::Error::new(
                        io::ErrorKind::WriteZero,
                        "tls13 write returned 0",
                    )))
                }
                Poll::Ready(Ok(n)) => this.outgoing.advance(n),
                Poll::Ready(Err(e)) => return Poll::Ready(Err(e)),
                Poll::Pending => return Poll::Pending,
            }
        }

        // Seal one record's worth; the rest is delivered by further
        // poll_write calls from `write_all`. Buffering the sealed bytes
        // here means we own them even if the flush below pends.
        let take = buf.len().min(MAX_PLAINTEXT);
        match this
            .write
            .seal_into(&buf[..take], CONTENT_APPDATA, &mut this.outgoing)
        {
            Ok(()) => {}
            Err(f) => {
                return Poll::Ready(Err(io::Error::new(
                    io::ErrorKind::InvalidData,
                    f.to_string(),
                )))
            }
        }

        // Flush as far as the socket accepts. A pending flush is fine: the
        // bytes are already buffered above, so report them as written.
        match this.poll_flush_outgoing(cx) {
            Poll::Ready(Ok(())) => Poll::Ready(Ok(take)),
            Poll::Ready(Err(e)) => Poll::Ready(Err(e)),
            Poll::Pending => Poll::Ready(Ok(take)),
        }
    }

    fn poll_flush(self: Pin<&mut Self>, cx: &mut Context<'_>) -> Poll<io::Result<()>> {
        let this = self.get_mut();
        if this.direct_write {
            return Pin::new(&mut this.inner).poll_flush(cx);
        }
        this.poll_flush_outgoing(cx)
    }

    fn poll_shutdown(self: Pin<&mut Self>, cx: &mut Context<'_>) -> Poll<io::Result<()>> {
        let this = self.get_mut();
        if this.direct_write {
            return Pin::new(&mut this.inner).poll_shutdown(cx);
        }
        if !this.close_sent {
            this.close_sent = true;
            // close_notify: warning level 1, description 0.
            match this
                .write
                .seal_into(&[0x01, 0x00], CONTENT_ALERT, &mut this.outgoing)
            {
                Ok(()) => {}
                Err(f) => {
                    return Poll::Ready(Err(io::Error::new(
                        io::ErrorKind::InvalidData,
                        f.to_string(),
                    )))
                }
            }
        }
        match this.poll_flush_outgoing(cx) {
            Poll::Ready(Ok(())) => Pin::new(&mut this.inner).poll_shutdown(cx),
            Poll::Ready(Err(e)) => Poll::Ready(Err(e)),
            Poll::Pending => Poll::Pending,
        }
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use std::time::Duration;
    use tokio::io::{AsyncReadExt, AsyncWriteExt};

    fn brotli(data: &[u8]) -> Vec<u8> {
        let mut out = Vec::new();
        let params = brotli::enc::BrotliEncoderParams::default();
        brotli::BrotliCompress(&mut &data[..], &mut out, &params).unwrap();
        out
    }

    /// A CompressedCertificate body: algorithm, declared length, data.
    fn compressed_body(algorithm: u16, declared: usize, data: &[u8]) -> Vec<u8> {
        let mut body = algorithm.to_be_bytes().to_vec();
        body.extend_from_slice(&(declared as u32).to_be_bytes()[1..]);
        body.extend_from_slice(&(data.len() as u32).to_be_bytes()[1..]);
        body.extend_from_slice(data);
        body
    }

    /// The Certificate body a server would have sent: an empty request
    /// context, then a one-entry list.
    fn certificate_body() -> Vec<u8> {
        let der = [0x30u8, 0x03, 0x02, 0x01, 0x07];
        let mut entry = (der.len() as u32).to_be_bytes()[1..].to_vec();
        entry.extend_from_slice(&der);
        entry.extend_from_slice(&[0, 0]); // no extensions
        let mut body = vec![0u8];
        body.extend_from_slice(&(entry.len() as u32).to_be_bytes()[1..]);
        body.extend_from_slice(&entry);
        body
    }

    #[test]
    fn a_brotli_certificate_inflates_to_the_message_it_stood_for() {
        let original = certificate_body();
        let body = compressed_body(2, original.len(), &brotli(&original));
        let inflated = inflate_certificate(&body).unwrap();
        assert_eq!(inflated, original);
        assert_eq!(certificate_leaf_der(&inflated).unwrap(), [0x30, 3, 2, 1, 7]);
    }

    #[test]
    fn a_compressed_certificate_that_lies_or_is_not_brotli_is_refused() {
        let original = certificate_body();
        let data = brotli(&original);
        // Declares more than it holds, and less.
        assert!(inflate_certificate(&compressed_body(2, original.len() + 1, &data)).is_err());
        assert!(inflate_certificate(&compressed_body(2, original.len() - 1, &data)).is_err());
        // zlib and zstd were never offered.
        assert!(inflate_certificate(&compressed_body(1, original.len(), &data)).is_err());
        assert!(inflate_certificate(&compressed_body(3, original.len(), &data)).is_err());
        // A claim past the cap is refused before anything is allocated.
        let huge = compressed_body(2, MAX_INFLATED_CERTIFICATE + 1, &data);
        assert!(inflate_certificate(&huge).is_err());
        // Trailing bytes after the data, garbage data, and a truncated head.
        let mut trailing = compressed_body(2, original.len(), &data);
        trailing.push(0);
        assert!(inflate_certificate(&trailing).is_err());
        assert!(inflate_certificate(&compressed_body(2, 40, &[0xff; 20])).is_err());
        assert!(inflate_certificate(&[0, 2, 0]).is_err());
    }

    #[test]
    fn only_the_chrome_hello_invites_a_compressed_certificate() {
        use crate::FingerprintProfile;
        for (fingerprint, offered) in [
            (FingerprintProfile::Chrome, true),
            (FingerprintProfile::Firefox, false),
            (FingerprintProfile::Safari, false),
        ] {
            let mut params = HelloParams::new("example.com");
            params.fingerprint = fingerprint;
            assert_eq!(PendingHello::new(&params).compression_offered, offered);
        }
    }

    #[tokio::test]
    async fn unauthenticated_record_shaped_bytes_fail_closed() {
        let (mut peer, io) = tokio::io::duplex(4096);
        let mut stream = Tls13Stream::new(
            io,
            CipherSuite::TLS_AES_128_GCM_SHA256,
            vec![1; 32],
            vec![2; 32],
        );
        let raw = {
            let mut record = vec![CONTENT_APPDATA, 0x03, 0x03, 0, 17];
            record.extend_from_slice(&[0xa5; 17]);
            record
        };
        peer.write_all(&raw).await.unwrap();

        let mut received = vec![0u8; raw.len()];
        let error = stream.read_exact(&mut received).await.unwrap_err();
        assert_eq!(error.kind(), std::io::ErrorKind::InvalidData);
    }

    async fn read_record<R: AsyncRead + Unpin>(
        peer: &mut R,
        crypter: &mut RecordCrypter,
    ) -> (u8, Vec<u8>) {
        let mut header = [0u8; 5];
        peer.read_exact(&mut header).await.unwrap();
        let mut body = vec![0u8; u16::from_be_bytes([header[3], header[4]]) as usize];
        peer.read_exact(&mut body).await.unwrap();
        crypter.open(&header, &body).unwrap()
    }

    /// A KeyUpdate whose body is not exactly one byte is refused, as Go
    /// refuses it.
    ///
    /// Go's `keyUpdateMsg` unmarshal reads one byte and requires the body to
    /// be empty afterwards (`RL/handshake_messages.go:1141-1151`), and a
    /// refused message is an alert (`RL/conn.go:1248-1250`). The port used to
    /// accept a body of any length, which a peer could use to say anything
    /// about itself.
    #[tokio::test]
    async fn a_key_update_with_the_wrong_body_length_is_refused() {
        let suite = CipherSuite::TLS_AES_128_GCM_SHA256;
        let (server_app, client_app) = (vec![1u8; 32], vec![2u8; 32]);
        for body in [
            vec![msg::KEY_UPDATE, 0, 0, 0],       // empty
            vec![msg::KEY_UPDATE, 0, 0, 2, 0, 0], // two bytes
            vec![msg::KEY_UPDATE, 0, 0, 1, 2],    // a value Go does not have
        ] {
            let (mut peer, io) = tokio::io::duplex(64 * 1024);
            let mut stream = Tls13Stream::new(io, suite, server_app.clone(), client_app.clone());
            let mut peer_write = RecordCrypter::new(suite, &server_app);
            let wire = peer_write.seal(&body, CONTENT_HANDSHAKE).unwrap().bytes;
            peer.write_all(&wire).await.unwrap();

            let error = stream.read(&mut [0u8; 4]).await.unwrap_err();
            assert!(
                error.to_string().contains("alert"),
                "a KeyUpdate of {body:?} was answered with {error}"
            );
        }
    }

    /// A session ticket from a *client* is refused, and one from a server is
    /// ignored.
    ///
    /// Go refuses a ticket arriving from a client
    /// (`RL/handshake_client_tls13.go:855-858`) and accepts one from a
    /// server, so the two ends answer the same message differently. The port
    /// used to ignore both, which is wrong on the server side: a client that
    /// offers a ticket is talking a protocol the server does not accept.
    #[tokio::test]
    async fn a_session_ticket_is_refused_from_a_client_and_ignored_from_a_server() {
        let suite = CipherSuite::TLS_AES_128_GCM_SHA256;
        let (server_app, client_app) = (vec![1u8; 32], vec![2u8; 32]);

        // From a client: refused.
        let (mut peer, io) = tokio::io::duplex(64 * 1024);
        let mut stream = Tls13Stream::new(io, suite, server_app.clone(), client_app.clone());
        stream.set_server_side();
        let mut peer_write = RecordCrypter::new(suite, &server_app);
        let ticket: [u8; 8] = [msg::NEW_SESSION_TICKET, 0, 0, 4, 0, 0, 0, 0];
        let wire = peer_write.seal(&ticket, CONTENT_HANDSHAKE).unwrap().bytes;
        peer.write_all(&wire).await.unwrap();
        // The read is bounded: a ticket that is *ignored* rather than
        // refused would leave it waiting for a record that never comes, and
        // the test would hang instead of failing.
        let error = tokio::time::timeout(Duration::from_secs(5), stream.read(&mut [0u8; 4]))
            .await
            .expect("a ticket from a client must be refused, not left waiting")
            .unwrap_err();
        assert!(
            error.to_string().contains("alert"),
            "a ticket from a client was answered with {error}"
        );

        // From a server: ignored, so the session carries on.
        let (mut peer, io) = tokio::io::duplex(64 * 1024);
        let mut stream = Tls13Stream::new(io, suite, server_app.clone(), client_app.clone());
        let mut peer_write = RecordCrypter::new(suite, &server_app);
        let mut wire = peer_write.seal(&ticket, CONTENT_HANDSHAKE).unwrap().bytes;
        // A ticket does not roll the read secret, so the record after it is
        // still under the old key.
        wire.extend_from_slice(&peer_write.seal(b"hi", CONTENT_APPDATA).unwrap().bytes);
        peer.write_all(&wire).await.unwrap();
        let mut got = [0u8; 2];
        stream.read_exact(&mut got).await.unwrap();
        assert_eq!(&got, b"hi", "a ticket from a server is ignored");
    }

    /// RFC 8446 §4.6.3: the KeyUpdate answer is sealed under the old write
    /// key and only the records after it use the new one. Sealing it under
    /// the new key makes the peer fail authentication on the answer itself.
    #[tokio::test]
    async fn requested_key_update_is_answered_under_the_old_key() {
        let suite = CipherSuite::TLS_AES_128_GCM_SHA256;
        let (server_app, client_app) = (vec![1u8; 32], vec![2u8; 32]);
        let (mut peer, io) = tokio::io::duplex(64 * 1024);
        let mut stream = Tls13Stream::new(io, suite, server_app.clone(), client_app.clone());

        let mut peer_write = RecordCrypter::new(suite, &server_app);
        let mut wire = peer_write
            .seal(&[msg::KEY_UPDATE, 0, 0, 1, 1], CONTENT_HANDSHAKE)
            .unwrap()
            .bytes;
        let mut peer_write =
            RecordCrypter::new(suite, &next_traffic_secret(suite.hash, &server_app));
        wire.extend_from_slice(&peer_write.seal(b"hi", CONTENT_APPDATA).unwrap().bytes);
        peer.write_all(&wire).await.unwrap();

        let mut got = [0u8; 2];
        stream.read_exact(&mut got).await.unwrap();
        assert_eq!(&got, b"hi");
        stream.write_all(b"x").await.unwrap();
        stream.flush().await.unwrap();

        let mut old_read = RecordCrypter::new(suite, &client_app);
        let (kind, answer) = read_record(&mut peer, &mut old_read).await;
        assert_eq!(
            (kind, answer.as_slice()),
            (CONTENT_HANDSHAKE, &[24, 0, 0, 1, 0][..])
        );
        let mut new_read = RecordCrypter::new(suite, &next_traffic_secret(suite.hash, &client_app));
        let (kind, data) = read_record(&mut peer, &mut new_read).await;
        assert_eq!((kind, data.as_slice()), (CONTENT_APPDATA, &b"x"[..]));
    }

    /// Writes must apply backpressure. Previously every `poll_write` sealed
    /// and queued its record and reported success even when the socket was
    /// full, so a stalled peer let `outgoing` grow without bound.
    #[tokio::test]
    async fn writes_block_instead_of_buffering_without_bound() {
        let (_peer, io) = tokio::io::duplex(4096);
        let mut stream = Tls13Stream::new(
            io,
            CipherSuite::TLS_AES_128_GCM_SHA256,
            vec![1; 32],
            vec![2; 32],
        );
        let payload = vec![0x5a; 4 * 1024 * 1024];
        let result = tokio::time::timeout(
            std::time::Duration::from_millis(200),
            stream.write_all(&payload),
        )
        .await;
        assert!(result.is_err(), "write_all finished against a stalled peer");
        assert!(stream.outgoing.len() < OUTGOING_HIGH_WATER + MAX_PLAINTEXT + 64);
    }

    #[tokio::test]
    async fn empty_writes_put_nothing_on_the_wire() {
        let (mut peer, io) = tokio::io::duplex(4096);
        let mut stream = Tls13Stream::new(
            io,
            CipherSuite::TLS_AES_128_GCM_SHA256,
            vec![1; 32],
            vec![2; 32],
        );
        assert_eq!(stream.write(&[]).await.unwrap(), 0);
        stream.write_all(b"a").await.unwrap();
        stream.flush().await.unwrap();
        let mut read = RecordCrypter::new(CipherSuite::TLS_AES_128_GCM_SHA256, &[2; 32]);
        let (_, data) = read_record(&mut peer, &mut read).await;
        assert_eq!(data, b"a", "the first record must carry the first byte");
    }

    /// An on-path relay can forward the genuine REALITY certificate (its HMAC
    /// is valid for our hello) but cannot sign with its key. Skipping the
    /// CertificateVerify check for a non-Ed25519 algorithm let exactly that
    /// relay complete the handshake.
    #[test]
    fn certificate_verify_must_use_the_ed25519_leaf_key() {
        let transcript = Transcript::new(super::super::HashAlg::Sha256);
        let mut body = vec![0x04, 0x03, 0x00, 0x40];
        body.extend_from_slice(&[0u8; 64]);
        assert!(verify_certificate_verify(&body, &[9u8; 32], &transcript).is_err());

        let mut ed = vec![0x08, 0x07, 0x00, 0x40];
        ed.extend_from_slice(&[0u8; 64]);
        assert!(
            verify_certificate_verify(&ed, &[9u8; 32], &transcript).is_err(),
            "a forged Ed25519 signature must not verify"
        );
    }

    #[tokio::test]
    async fn fragmented_server_hello_is_reassembled_exactly() {
        let message: Vec<u8> = {
            let mut m = vec![msg::SERVER_HELLO, 0, 0, 6];
            m.extend_from_slice(b"abcdef");
            m
        };
        let (mut peer, mut io) = tokio::io::duplex(4096);
        let mut wire = Vec::new();
        wire.extend_from_slice(&[CONTENT_CCS, 3, 3, 0, 1, 1]);
        wire.extend_from_slice(&record_header(CONTENT_HANDSHAKE, 3));
        wire.extend_from_slice(&message[..3]);
        wire.extend_from_slice(&record_header(CONTENT_HANDSHAKE, 7));
        wire.extend_from_slice(&message[3..]);
        peer.write_all(&wire).await.unwrap();
        assert_eq!(read_server_hello(&mut io).await.unwrap(), message);

        // Trailing cleartext after a complete ServerHello is a violation.
        let mut extra = record_header(CONTENT_HANDSHAKE, message.len() + 1).to_vec();
        extra.extend_from_slice(&message);
        extra.push(0);
        peer.write_all(&extra).await.unwrap();
        assert!(read_server_hello(&mut io).await.is_err());
    }

    #[tokio::test]
    async fn direct_read_transition_does_not_bypass_outer_tls_writes() {
        let (mut peer, io) = tokio::io::duplex(4096);
        let mut stream = Tls13Stream::new(
            io,
            CipherSuite::TLS_AES_128_GCM_SHA256,
            vec![1; 32],
            vec![2; 32],
        );
        stream.enter_direct_mode();
        stream.write_all(b"request-tail").await.unwrap();

        let mut header = [0u8; 5];
        peer.read_exact(&mut header).await.unwrap();
        assert_eq!(&header[..3], &[CONTENT_APPDATA, 0x03, 0x03]);
    }

    /// One side of a stream whose peer seals with `peer_secrets`, and the wire
    /// the peer writes. Both ends are the same key material, so the stream
    /// opens what the tests seal.
    fn stream_and_sealer(
        suite: CipherSuite,
    ) -> (
        tokio::io::DuplexStream,
        Tls13Stream<tokio::io::DuplexStream>,
        RecordCrypter,
    ) {
        let (peer, io) = tokio::io::duplex(64 * 1024);
        let stream = Tls13Stream::new(io, suite, vec![1; 32], vec![2; 32]);
        // The stream reads with the *server* application secret.
        (peer, stream, RecordCrypter::new(suite, &[1; 32]))
    }

    /// Go's `maxUselessRecords` is 32 consecutive non-advancing records, and
    /// the thirty-third closes the connection (`RL/common.go:70`,
    /// `RL/conn.go:827-839`). The port tolerated 256 consecutive empty records
    /// and counted a change_cipher_spec at all, so a peer could keep a
    /// connection alive for an unbounded number of records that advanced
    /// nothing — the shape a censor measures against the site the server
    /// claims to be, since Go's REALITY copies its decoy's own tolerance.
    #[tokio::test]
    async fn thirty_two_consecutive_useless_records_are_the_limit() {
        let suite = CipherSuite::TLS_AES_128_GCM_SHA256;
        // The bound is Go's number and nothing else, so the counts below are
        // written out rather than taken from the constant they check.
        assert_eq!(MAX_USELESS_RECORDS, 32);

        // Exactly Go's allowance, then real data: tolerated.
        let (mut peer, mut stream, mut seal) = stream_and_sealer(suite);
        let mut wire = Vec::new();
        for _ in 0..32 {
            seal.seal_empty_into(69, &mut wire).unwrap();
        }
        seal.seal_into(b"live", CONTENT_APPDATA, &mut wire).unwrap();
        peer.write_all(&wire).await.unwrap();
        let mut got = [0u8; 4];
        stream.read_exact(&mut got).await.unwrap();
        assert_eq!(&got, b"live");

        // One more than the allowance is fatal, and it is a failure the caller
        // can name rather than a dropped connection.
        let (mut peer, mut stream, mut seal) = stream_and_sealer(suite);
        let mut wire = Vec::new();
        for _ in 0..33 {
            seal.seal_empty_into(69, &mut wire).unwrap();
        }
        seal.seal_into(b"live", CONTENT_APPDATA, &mut wire).unwrap();
        peer.write_all(&wire).await.unwrap();
        let error = stream.read(&mut [0u8; 4]).await.unwrap_err();
        assert_eq!(
            error.to_string(),
            too_many_useless_records(MAX_USELESS_RECORDS).to_string()
        );

        // A change_cipher_spec advances nothing either, so a run of them is
        // the same failure — the port ignored them without counting at all.
        let (mut peer, mut stream, _) = stream_and_sealer(suite);
        let mut wire = Vec::new();
        for _ in 0..33 {
            wire.extend_from_slice(&DUMMY_CCS);
        }
        let mut trailing = RecordCrypter::new(suite, &[1; 32]);
        trailing
            .seal_into(b"live", CONTENT_APPDATA, &mut wire)
            .unwrap();
        peer.write_all(&wire).await.unwrap();
        let error = stream.read(&mut [0u8; 4]).await.unwrap_err();
        assert_eq!(
            error.to_string(),
            too_many_useless_records(MAX_USELESS_RECORDS).to_string()
        );
    }

    /// The bound is on a *consecutive* run: Go resets `retryCount` on any
    /// record that carries data (`RL/conn.go:734-737`), so a long-lived flow
    /// that keeps making progress is never closed, however many keepalive
    /// probes it spends in between. A total counter would fail here.
    #[tokio::test]
    async fn a_record_that_advances_the_stream_resets_the_run() {
        let suite = CipherSuite::TLS_AES_128_GCM_SHA256;
        let (mut peer, mut stream, mut seal) = stream_and_sealer(suite);
        let mut wire = Vec::new();
        for round in 0..4u8 {
            for _ in 0..32 {
                seal.seal_empty_into(69, &mut wire).unwrap();
            }
            seal.seal_into(&[round], CONTENT_APPDATA, &mut wire)
                .unwrap();
        }
        peer.write_all(&wire).await.unwrap();
        let mut got = [0u8; 1];
        for round in 0..4u8 {
            stream.read_exact(&mut got).await.unwrap();
            assert_eq!(got[0], round, "128 useless records between four writes");
        }
    }

    /// The limit is the stream's own, because the camouflage site's is.
    ///
    /// Go's server sets `MaxUselessRecords` from what the site was found to
    /// answer with (`RL/tls.go:425-427`), so a REALITY server puts up with
    /// exactly as many records that advance nothing as the site it borrows
    /// its name from. A stream that always answered with 32 would be a
    /// stream that could be told apart from a site that answers with a
    /// different number.
    #[tokio::test]
    async fn the_limit_is_the_streams_own() {
        let suite = CipherSuite::TLS_AES_128_GCM_SHA256;
        let (mut peer, mut stream, mut seal) = stream_and_sealer(suite);
        stream.set_max_useless_records(4);

        // Four are tolerated, and the fifth is not.
        let mut wire = Vec::new();
        for _ in 0..4 {
            seal.seal_empty_into(69, &mut wire).unwrap();
        }
        seal.seal_into(b"live", CONTENT_APPDATA, &mut wire).unwrap();
        peer.write_all(&wire).await.unwrap();
        let mut got = [0u8; 4];
        stream.read_exact(&mut got).await.unwrap();
        assert_eq!(&got, b"live", "the run the limit allows is answered");

        let (mut peer, mut stream, mut seal) = stream_and_sealer(suite);
        stream.set_max_useless_records(4);
        let mut wire = Vec::new();
        for _ in 0..5 {
            seal.seal_empty_into(69, &mut wire).unwrap();
        }
        seal.seal_into(b"live", CONTENT_APPDATA, &mut wire).unwrap();
        peer.write_all(&wire).await.unwrap();
        let error = stream.read(&mut [0u8; 4]).await.unwrap_err();
        assert_eq!(
            error.to_string(),
            too_many_useless_records(4).to_string(),
            "the run past the limit is fatal, and the message names the limit"
        );
    }
}
