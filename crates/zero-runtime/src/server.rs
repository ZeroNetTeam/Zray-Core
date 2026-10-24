//! Inbound listeners and dispatch.

use std::collections::{HashMap, HashSet};
use std::net::SocketAddr;
use std::sync::atomic::{AtomicU64, AtomicU8, Ordering};
use std::sync::{Arc, Mutex as StdMutex};

use futures::{SinkExt, StreamExt};
use tokio::io::{AsyncReadExt, AsyncWriteExt};
use tokio::net::{TcpListener, UdpSocket};
use tokio::sync::Mutex;
use tokio::time::{timeout, Duration};
use tracing::{debug, error, info, warn};
use zero_config::{
    InboundProtocol, NoiseConfig, NoiseKind, OutboundProtocol, RuntimeConfig, Sniffing,
    VlessInboundConfig,
};
use zero_core::{boxed, Address, Destination, GenerationId, InboundId, Network, SessionContext};
use zero_protocol::socks::{self, Accepted, InboundKind};
use zero_router::{Decision, Router};

use crate::outbound;
use crate::relay::{relay, Transferred};

#[derive(Debug, Default)]
pub struct Stats {
    pub accepted: AtomicU64,
    pub succeeded: AtomicU64,
    pub failed: AtomicU64,
    pub blocked: AtomicU64,
    pub uploaded: AtomicU64,
    pub downloaded: AtomicU64,
    /// What works for Cloudflare CDN outbounds here ([`crate::cdn_check`]).
    pub cdn: AtomicU8,
    /// TCP sessions currently being served. A graceful drain waits for this to
    /// reach zero before the process exits.
    pub active: AtomicU64,
    /// Per-tag byte counters keyed by the Xray stat name
    /// (`inbound>>>{tag}>>>traffic>>>uplink`, etc.). Populated only for tags
    /// that have carried traffic, matching Xray, which reports absent counters
    /// as zero. A session end is not a hot path, so a mutex-guarded map is
    /// cheaper than an atomic per possible tag.
    pub traffic: StdMutex<HashMap<String, u64>>,
    /// Whether the TUN device is still being served: [`TUN_NONE`] when this
    /// runtime has none, [`TUN_UP`] while its packet bridge runs and
    /// [`TUN_LOST`] once the bridge has ended. The device can vanish under us
    /// (the platform closed the interface, another VPN took over) and nothing
    /// else on this side would notice, so the host reads this to know that
    /// "connected" has stopped being true.
    pub tun: AtomicU8,
    /// Who is connected, as counts only ([`crate::usage`]).
    pub usage: Arc<crate::usage::UsageTracker>,
    /// Per-account bytes and sessions, by `email` ([`crate::accounts`]).
    pub accounts: Arc<crate::accounts::Accounts>,
}

/// [`Stats::tun`]: this runtime has no TUN device.
pub const TUN_NONE: u8 = 0;
/// [`Stats::tun`]: the packet bridge is running.
pub const TUN_UP: u8 = 1;
/// [`Stats::tun`]: the packet bridge ended; nothing more will flow.
pub const TUN_LOST: u8 = 2;

impl Stats {
    /// True once a TUN device that was being served is gone.
    pub fn tun_lost(&self) -> bool {
        self.tun.load(Ordering::Relaxed) == TUN_LOST
    }

    pub fn snapshot(&self) -> StatsSnapshot {
        StatsSnapshot {
            accepted: self.accepted.load(Ordering::Relaxed),
            succeeded: self.succeeded.load(Ordering::Relaxed),
            failed: self.failed.load(Ordering::Relaxed),
            blocked: self.blocked.load(Ordering::Relaxed),
            uploaded: self.uploaded.load(Ordering::Relaxed),
            downloaded: self.downloaded.load(Ordering::Relaxed),
            cdn: self.cdn_condition(),
            cdn_notice: self.cdn_condition().notice(),
        }
    }

    pub fn cdn_condition(&self) -> crate::cdn_check::CdnCondition {
        crate::cdn_check::CdnCondition::from_u8(self.cdn.load(Ordering::Relaxed))
    }

    /// The server's live events ([`crate::events`]).
    pub fn events(&self) -> &crate::events::Events {
        self.accounts.events()
    }

    /// Tell event subscribers that a session on `inbound` failed.
    pub fn report_failure(&self, inbound: &str, error: &str) {
        self.events().emit(|| crate::events::Event::SessionFailed {
            inbound: inbound.to_string(),
            error: error.to_string(),
        });
    }

    /// Accumulate one relay's bytes against its inbound tag and, when the
    /// session used a named proxy outbound, that outbound tag too. Xray's
    /// convention is uplink = client→destination and downlink = the reverse,
    /// which is exactly the relay's `uploaded`/`downloaded`.
    pub fn record_tag_traffic(
        &self,
        inbound_tag: &str,
        outbound_tag: Option<&str>,
        transferred: &Transferred,
    ) {
        if transferred.uploaded == 0 && transferred.downloaded == 0 {
            return;
        }
        let mut traffic = self
            .traffic
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        if !inbound_tag.is_empty() {
            *traffic
                .entry(format!("inbound>>>{inbound_tag}>>>traffic>>>uplink"))
                .or_insert(0) += transferred.uploaded;
            *traffic
                .entry(format!("inbound>>>{inbound_tag}>>>traffic>>>downlink"))
                .or_insert(0) += transferred.downloaded;
        }
        if let Some(outbound_tag) = outbound_tag.filter(|tag| !tag.is_empty()) {
            *traffic
                .entry(format!("outbound>>>{outbound_tag}>>>traffic>>>uplink"))
                .or_insert(0) += transferred.uploaded;
            *traffic
                .entry(format!("outbound>>>{outbound_tag}>>>traffic>>>downlink"))
                .or_insert(0) += transferred.downloaded;
        }
    }

    /// Xray-style `{name, value}` counters, sorted by name for stable output:
    /// per tag, and per account (`user>>>{email}>>>traffic>>>uplink`).
    /// `reset` zeroes each counter as it is read, matching the semantics of
    /// Xray's `QueryStats reset=true`.
    pub fn traffic_counters(&self, reset: bool) -> Vec<(String, u64)> {
        let mut traffic = self
            .traffic
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        let mut counters: Vec<(String, u64)> = traffic
            .iter()
            .map(|(name, value)| (name.clone(), *value))
            .collect();
        if reset {
            for value in traffic.values_mut() {
                *value = 0;
            }
        }
        drop(traffic);
        for account in self.accounts.traffic(reset) {
            let email = &account.email;
            counters.push((format!("user>>>{email}>>>traffic>>>uplink"), account.uplink));
            counters.push((
                format!("user>>>{email}>>>traffic>>>downlink"),
                account.downlink,
            ));
        }
        counters.sort_by(|a, b| a.0.cmp(&b.0));
        counters
    }
}

/// Increments the active-session gauge on creation and decrements it on drop,
/// so the count is correct no matter which path a handler returns or panics on.
pub struct ActiveGuard(Arc<Stats>);

impl ActiveGuard {
    pub fn new(stats: Arc<Stats>) -> Self {
        stats.active.fetch_add(1, Ordering::Relaxed);
        Self(stats)
    }
}

impl Drop for ActiveGuard {
    fn drop(&mut self) {
        self.0.active.fetch_sub(1, Ordering::Relaxed);
    }
}

#[derive(Debug, Clone, Copy, PartialEq, Eq, serde::Serialize)]
pub struct StatsSnapshot {
    pub accepted: u64,
    pub succeeded: u64,
    pub failed: u64,
    pub blocked: u64,
    pub uploaded: u64,
    pub downloaded: u64,
    /// What works for Cloudflare CDN outbounds on this network.
    pub cdn: crate::cdn_check::CdnCondition,
    /// One sentence for the user about it, when there is something to say.
    pub cdn_notice: Option<&'static str>,
}

pub struct ServerConfig {
    pub config: Arc<RuntimeConfig>,
    pub generation: GenerationId,
}

/// Upper bound on everything a client does before its first proxied byte:
/// the TLS/REALITY handshake, the transport upgrade, and the protocol request
/// header. Matches Xray's default `handshake` policy. Without it a client that
/// connects and then says nothing -- a slow-loris, or a censor's half-open
/// probe -- pins a task and a descriptor for as long as it cares to.
const DEFAULT_HANDSHAKE_TIMEOUT: Duration = Duration::from_secs(60);

static HANDSHAKE_MS: AtomicU64 = AtomicU64::new(DEFAULT_HANDSHAKE_TIMEOUT.as_millis() as u64);

/// The handshake limit in force: the default, or the configured
/// `policy.levels.0.handshake`.
fn handshake_timeout() -> Duration {
    Duration::from_millis(HANDSHAKE_MS.load(Ordering::Relaxed))
}

/// A connection to `chain[0]`'s server, carried through every later hop of
/// `chain` (innermost dialled directly). `chain` has at least two entries.
async fn carry_to_exit(
    chain: &[zero_config::Outbound],
    resolver: &zero_dns::Resolver,
) -> Result<zero_core::BoxStream, zero_core::Failure> {
    carry_through(Arc::from(chain), 1, resolver.clone()).await
}

/// The server of `hop`, as a destination to connect to.
fn hop_server(hop: &zero_config::Outbound) -> Result<Destination, zero_core::Failure> {
    hop.endpoint()
        .map(|(address, port)| Destination::tcp(address, port))
        .ok_or_else(|| {
            zero_core::Failure::new(
                zero_core::FailureKind::LocalPolicy,
                zero_core::Stage::SocketConnected,
            )
            .with_detail(format!("outbound {} has no endpoint", hop.tag))
        })
}

/// A connection to the server of `chain[at - 1]`, opened through `chain[at]`
/// and the hops after it, with the response header of each hop taken off.
///
/// The last hop dials directly. A hop before it runs over a connection to its
/// own server that the hops after it carry. A Tide hop cannot run over one
/// connection (it keeps several and replaces them), so it is given a way to
/// open a new one whenever it wants one.
fn carry_through(
    chain: Arc<[zero_config::Outbound]>,
    at: usize,
    resolver: zero_dns::Resolver,
) -> std::pin::Pin<
    Box<dyn std::future::Future<Output = Result<zero_core::BoxStream, zero_core::Failure>> + Send>,
> {
    Box::pin(async move {
        let hop = &chain[at];
        let destination = hop_server(&chain[at - 1])?;
        if at + 1 == chain.len() {
            let stream = outbound::connect_with_resolver(hop, &destination, &resolver).await?;
            return Ok(outbound::strip_response(hop, stream));
        }
        if matches!(hop.protocol, OutboundProtocol::Tide(_)) {
            let (route, carrier) = tide_carrier(&chain, at, &resolver);
            return outbound::connect_tide_via(hop, &destination, &route, carrier).await;
        }
        let carried = carry_through(chain.clone(), at + 1, resolver.clone()).await?;
        let stream = outbound::connect_over(hop, carried, &destination).await?;
        Ok(outbound::strip_response(hop, stream))
    })
}

/// What a Tide client at `chain[at]` needs to reach its server: a name for
/// the route (the hops behind it) and a way to open one more connection to
/// the server through them.
fn tide_carrier(
    chain: &Arc<[zero_config::Outbound]>,
    at: usize,
    resolver: &zero_dns::Resolver,
) -> (String, outbound::TideCarrier) {
    let route = format!("{:?}", &chain[at + 1..]);
    let (chain, resolver) = (chain.clone(), resolver.clone());
    let carrier: outbound::TideCarrier =
        Arc::new(move || carry_through(chain.clone(), at + 1, resolver.clone()));
    (route, carrier)
}

/// Give `dialed` the TCP fragmentation of the direct outbound `dialer`, unless
/// `dialed` has shaping of its own or cannot carry it (see
/// `GatewayServer::resolve_chain`).
fn lend_direct_dial(dialed: &mut zero_config::Outbound, dialer: &zero_config::Outbound) {
    use zero_config::Security;
    let fits = match &dialed.stream.security {
        Security::None => true,
        Security::Tls(tls) => tls.ech.is_none(),
        Security::Reality(_) | Security::ShadowTls(_) => false,
    };
    let evasion = &mut dialed.stream.evasion;
    if fits && evasion.tcp_fragment.is_none() && evasion.sni_desync.is_none() {
        evasion.tcp_fragment = dialer.stream.evasion.tcp_fragment.clone();
        evasion.tcp_fragment_under = dialer.stream.evasion.tcp_fragment_under.clone();
    }
}

/// Most outbounds one `dialerProxy` chain may pass through, the exit
/// included. Each hop adds a round trip to every connection.
const MAX_CHAIN: usize = 4;

/// How long a balancer member gets to connect before the next best is tried
/// beside it (`Server::connect_balanced`). Above the handshake of a healthy
/// server over a slow international path, well below the connect timeout.
const HEDGE_AFTER: Duration = Duration::from_millis(3000);

/// How many datagrams one UDP ingress may have in flight at once. Each one
/// waits up to the exchange deadline for its answer, so the ingress must not
/// wait for them one at a time -- a single unanswered query would stall every
/// other flow behind it -- yet a flood must not turn into unbounded tasks and
/// sockets either. Datagrams beyond the limit are dropped, which is what UDP
/// promises anyway.
const UDP_INFLIGHT_LIMIT: usize = 512;

/// Hard deadline on one proxied UDP exchange, including dialing the outbound.
/// Several carriers read their answer without a timeout of their own, and a
/// server that never answers must not leak the task and its connection.
const UDP_EXCHANGE_DEADLINE: Duration = Duration::from_secs(15);

async fn within_handshake<F: std::future::Future>(future: F) -> Result<F::Output, String> {
    timeout(handshake_timeout(), future).await.map_err(|_| {
        format!(
            "client handshake timed out after {}s",
            handshake_timeout().as_secs()
        )
    })
}

struct ServerState {
    config: Arc<RuntimeConfig>,
    router: Arc<Router>,
    /// The resolver as configured, FakeDNS included: it answers the
    /// applications' own queries (`dns-out`) and maps synthetic addresses
    /// back to names.
    client_resolver: Arc<zero_dns::Resolver>,
    /// The same resolver without FakeDNS, for every lookup the runtime makes
    /// to connect somewhere (see [`zero_dns::Resolver::without_fake`]).
    resolver: Arc<zero_dns::Resolver>,
    generation: GenerationId,
    /// Per-inbound material derived from configuration once per generation
    /// instead of once per accepted connection, indexed like
    /// `config.inbounds`.
    inbounds: Arc<[InboundRuntime]>,
}

/// Inbound settings compiled once per configuration generation.
///
/// Building a rustls `ServerConfig` parses the certificate chain and private
/// key and allocates a fresh session cache and ticketer. Doing that per
/// connection cost CPU on every accept and, worse, made TLS session resumption
/// impossible, since no two connections ever shared a cache.
#[derive(Default, Clone)]
struct InboundRuntime {
    tls: Option<Result<Arc<rustls::ServerConfig>, String>>,
    reality: Option<reality::RealityServerParams>,
    transport: Option<zero_transport::ws::WsConfig>,
    raw_http_header: Option<zero_transport::tcp_header::HttpHeaderConfig>,
    tide: Option<Arc<TideInbound>>,
    tide_relay: Option<Arc<zero_transport::tide_relay::Relay>>,
    /// The VLESS Encryption server of a VLESS inbound with `decryption` set,
    /// or why its setting is unusable. Made once per inbound, because its
    /// 0-RTT tickets must outlive any one connection.
    vless_encryption: Option<Result<Arc<zero_protocol::vless_encryption::Server>, String>>,
    /// The user table of a multi-user Shadowsocks 2022 inbound, or why its
    /// keys are unusable. Rebuilt when its accounts change at run time.
    shadowsocks_users: Option<Result<Arc<zero_protocol::shadowsocks2022::ServerUsers>, String>>,
}

/// A Tide inbound's server. It outlives any one connection: a session's
/// requests arrive on several connections, some of them after the one that
/// opened it has gone.
struct TideInbound {
    server: Arc<zero_transport::tide::Server>,
    /// Its users, shared with the server, which checks them at each
    /// handshake: id to name.
    users: crate::tide_users::Users,
    /// The ids that came from the configuration rather than the users file,
    /// so an account removed from the configuration leaves the table.
    from_config: StdMutex<HashSet<zero_protocol::tide::UserId>>,
    /// Streams clients open, until the first connection starts the task that
    /// routes them.
    streams: StdMutex<Option<tokio::sync::mpsc::Receiver<zero_transport::tide::Incoming>>>,
}

impl TideInbound {
    fn new(config: &zero_config::TideInboundConfig) -> Arc<Self> {
        let users = crate::tide_users::load(config);
        let shared = Arc::clone(&users);
        let (server, streams) =
            zero_transport::tide::Server::new(zero_transport::tide::ServerConfig {
                path: config.path.to_string(),
                secret: config.secret,
                admin: crate::tide_users::admin(config, &users),
                users,
                decoy: Default::default(),
                shape: match config.shape {
                    zero_config::TideShape::Off => zero_protocol::tide::ShapeLevel::Off,
                    zero_config::TideShape::Light => zero_protocol::tide::ShapeLevel::Light,
                    zero_config::TideShape::Full => zero_protocol::tide::ShapeLevel::Full,
                },
            });
        Arc::new(Self {
            server,
            users: shared,
            from_config: StdMutex::new(config.users.iter().map(|user| user.id).collect()),
            streams: StdMutex::new(Some(streams)),
        })
    }

    /// Bring the user table in line with `config`'s users, keeping those the
    /// users file added.
    fn sync_users(&self, config: &zero_config::TideInboundConfig) {
        let mut from_config = self
            .from_config
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        let mut users = self
            .users
            .write()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        for id in from_config.iter() {
            if !config.users.iter().any(|user| user.id == *id) {
                users.remove(id);
            }
        }
        for user in config.users.iter() {
            users.insert(user.id, user.name.to_string());
        }
        *from_config = config.users.iter().map(|user| user.id).collect();
    }

    /// The name `user` is metered under: none for a user without one, and
    /// `Err` for one that is no longer a user (removed while its session
    /// still had streams to open).
    fn account_of(&self, user: &zero_protocol::tide::UserId) -> Result<Option<Arc<str>>, ()> {
        let users = self
            .users
            .read()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        let name = users.get(user).ok_or(())?;
        Ok((!name.is_empty()).then(|| Arc::from(name.as_str())))
    }
}

impl InboundRuntime {
    fn compile(inbound: &zero_config::Inbound, resolver: &Arc<zero_dns::Resolver>) -> Self {
        let tls = match &inbound.security {
            zero_config::InboundSecurity::Tls(tls)
                if tls.extra_identities.is_empty() && !tls.reject_unknown_sni =>
            {
                Some(zero_security::server::server_config(
                    &tls.certificate,
                    &tls.private_key,
                    &tls.alpn,
                ))
            }
            zero_config::InboundSecurity::Tls(tls) => {
                let identities: Vec<(&[u8], &[u8])> =
                    std::iter::once((&*tls.certificate, &*tls.private_key))
                        .chain(
                            tls.extra_identities
                                .iter()
                                .map(|(cert, key)| (&**cert, &**key)),
                        )
                        .collect();
                Some(zero_security::server::server_config_multi(
                    &identities,
                    &tls.alpn,
                    tls.reject_unknown_sni,
                ))
            }
            _ => None,
        };
        let reality = match &inbound.security {
            zero_config::InboundSecurity::Reality(reality) => Some(reality::RealityServerParams {
                private_key: reality.private_key,
                server_names: reality.server_names.clone(),
                short_ids: reality.short_ids.clone(),
                mldsa65_seed: reality.mldsa65_seed.as_ref().map(|seed| seed.0),
                site_writes: None,
                max_time_diff: Duration::from_millis(reality.max_time_diff_ms),
                min_client_ver: reality.min_client_ver,
                max_client_ver: reality.max_client_ver,
                post_handshake: Default::default(),
                show: reality.show,
                // The key log is opened once here, so that every handshake
                // appends to the same file. A path that cannot be opened is
                // reported and the listener runs without one: Xray does the
                // same (`XC/transport/internet/reality/config.go:66-71`), and
                // a debugging aid is not a reason for a listener to be down.
                key_log: match &reality.master_key_log {
                    None => None,
                    Some(path) => match reality::keys::KeyLog::open(path) {
                        Ok(log) => Some(Arc::new(log)),
                        Err(error) => {
                            warn!(%error, %path, "REALITY key log could not be opened");
                            None
                        }
                    },
                },
                // Go dials the camouflage site for every connection and reads
                // the site's own flight off that connection
                // (`RL/tls.go:168`, `:293-330`), so the flight a client sees
                // is the site's, read live. The dial lives here, because the
                // resolver and its deadline are this runtime's.
                decoy: reality.target.as_ref().map(|target| {
                    Arc::new(RuntimeDecoy {
                        target: target.clone(),
                        resolver: Arc::clone(resolver),
                    }) as Arc<dyn reality::DecoyDialer>
                }),
            }),
            _ => None,
        };
        let transport = match &inbound.transport {
            zero_config::Transport::Raw => None,
            zero_config::Transport::WebSocket(w)
            | zero_config::Transport::HttpUpgrade(w)
            | zero_config::Transport::Grpc(w)
            | zero_config::Transport::Xhttp(w) => Some(zero_transport::ws::WsConfig {
                path: w.path.to_string(),
                host: w.host.as_deref().unwrap_or("").to_string(),
                headers: w
                    .headers
                    .iter()
                    .map(|(k, v)| (k.to_string(), v.to_string()))
                    .collect(),
                early_data_len: 0,
                xhttp: Default::default(),
                secure: false,
                grpc_multi_path: w.grpc_multi_path.as_deref().map(str::to_string),
                grpc_multi: false,
            }),
        };
        let vless_encryption = match &inbound.protocol {
            InboundProtocol::Vless(config) => config.decryption.as_deref().map(|setting| {
                zero_protocol::vless_encryption::ServerConfig::parse(setting)
                    .map(zero_protocol::vless_encryption::Server::new)
            }),
            _ => None,
        };
        Self {
            tls,
            reality,
            transport,
            vless_encryption,
            shadowsocks_users: shadowsocks_users(&inbound.protocol),
            tide: match &inbound.protocol {
                InboundProtocol::Tide(config) => Some(TideInbound::new(config)),
                _ => None,
            },
            tide_relay: match &inbound.protocol {
                InboundProtocol::TideRelay(config) => match outbound::tide_relay_dialer(config) {
                    Ok(dial) => Some(zero_transport::tide_relay::Relay::new(
                        zero_transport::tide_relay::RelayConfig {
                            path: config.path.to_string(),
                            host: config.upstream_name.as_deref().map_or_else(
                                || config.upstream_address.host_string(),
                                str::to_string,
                            ),
                            decoy: Default::default(),
                        },
                        dial,
                    )),
                    Err(error) => {
                        warn!(%error, "the Tide relay's upstream could not be set up");
                        None
                    }
                },
                _ => None,
            },
            raw_http_header: inbound
                .raw_http_header
                .as_ref()
                .map(outbound::raw_http_header_config),
        }
    }
}

/// Which named WireGuard peer owns an address, by its `allowedIPs`, for
/// metering a peer's packets under its `email`.
struct WireGuardOwners(Vec<(zero_config::routing::ipnet_lite::Cidr, Arc<str>)>);

impl WireGuardOwners {
    /// The owners among `peers`; empty when no peer has an `email`.
    fn of(peers: &[zero_config::WireGuardPeer]) -> Self {
        let mut owned: Vec<_> = peers
            .iter()
            .filter_map(|peer| Some((peer, peer.email.clone()?)))
            .flat_map(|(peer, email)| {
                peer.allowed_ips
                    .iter()
                    .map(move |cidr| (*cidr, Arc::clone(&email)))
            })
            .collect();
        // Longest prefix first, so the most specific owner wins.
        owned.sort_by_key(|(cidr, _)| std::cmp::Reverse(cidr.prefix));
        Self(owned)
    }

    fn owner(&self, ip: std::net::IpAddr) -> Option<&Arc<str>> {
        self.0
            .iter()
            .find(|(cidr, _)| cidr.contains(ip))
            .map(|(_, email)| email)
    }

    fn of_source(&self, packet: &[u8]) -> Option<&Arc<str>> {
        self.owner(packet_address(packet, true)?)
    }

    fn of_destination(&self, packet: &[u8]) -> Option<&Arc<str>> {
        self.owner(packet_address(packet, false)?)
    }
}

/// What the WireGuard server needs of each of `peers`.
fn peer_specs(peers: &[zero_config::WireGuardPeer]) -> Vec<zero_protocol::wg_server::PeerSpec> {
    peers
        .iter()
        .map(|peer| zero_protocol::wg_server::PeerSpec {
            public_key: peer.public_key,
            preshared_key: peer.preshared_key,
            allowed: peer
                .allowed_ips
                .iter()
                .map(|cidr| (cidr.addr, cidr.prefix))
                .collect(),
            keepalive: peer.keepalive,
        })
        .collect()
}

/// How long a WireGuard peer that sent nothing still counts as connected. A
/// connected client talks at least every two minutes, when its keys rotate.
const WIREGUARD_IDLE: Duration = Duration::from_secs(180);

/// The named WireGuard peers seen lately, each held online as a session of
/// its account ([`crate::accounts::Accounts::open_session`]) while it talks.
#[derive(Default)]
struct WireGuardSessions(
    StdMutex<HashMap<Arc<str>, (crate::accounts::SessionGuard, tokio::time::Instant)>>,
);

impl WireGuardSessions {
    /// Whether a packet of `email`'s peer from `from` may pass: it opens or
    /// refreshes the peer's session, which may have been ended.
    fn heard_from(
        &self,
        accounts: &crate::accounts::Accounts,
        email: &Arc<str>,
        tag: &Arc<str>,
        from: SocketAddr,
    ) -> bool {
        let mut sessions = self
            .0
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        let now = tokio::time::Instant::now();
        let (guard, seen) = sessions
            .entry(Arc::clone(email))
            .or_insert_with(|| (accounts.open_session(email, tag, Some(from.ip())), now));
        *seen = now;
        !guard.is_ended()
    }

    /// Whether a packet to `email`'s peer may pass: not once its session was
    /// ended.
    fn to_peer(&self, email: &Arc<str>) -> bool {
        let sessions = self
            .0
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        sessions
            .get(email)
            .is_none_or(|(guard, _)| !guard.is_ended())
    }

    /// Forget the peers that have been quiet for [`WIREGUARD_IDLE`].
    fn sweep(&self) {
        let mut sessions = self
            .0
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        sessions.retain(|_, (_, seen)| seen.elapsed() < WIREGUARD_IDLE);
    }
}

/// The source (or destination) address of an IPv4 or IPv6 packet.
fn packet_address(packet: &[u8], source: bool) -> Option<std::net::IpAddr> {
    match packet.first()? >> 4 {
        4 => {
            let at = if source { 12 } else { 16 };
            let bytes: [u8; 4] = packet.get(at..at + 4)?.try_into().ok()?;
            Some(std::net::IpAddr::from(bytes))
        }
        6 => {
            let at = if source { 8 } else { 24 };
            let bytes: [u8; 16] = packet.get(at..at + 16)?.try_into().ok()?;
            Some(std::net::IpAddr::from(bytes))
        }
        _ => None,
    }
}

/// The SIP023 user table of a multi-user Shadowsocks 2022 inbound.
fn shadowsocks_users(
    protocol: &InboundProtocol,
) -> Option<Result<Arc<zero_protocol::shadowsocks2022::ServerUsers>, String>> {
    let InboundProtocol::Shadowsocks(config) = protocol else {
        return None;
    };
    if !config.method.is_2022() || !config.multi_user {
        return None;
    }
    let keys: Vec<&str> = config.users.iter().map(|user| &*user.password).collect();
    Some(
        zero_protocol::shadowsocks2022::ServerUsers::new(
            ss2022_method(config.method),
            &config.password,
            &keys,
        )
        .map(Arc::new)
        .map_err(|error| format!("Shadowsocks 2022 users: {error}")),
    )
}

/// A Hysteria2 inbound's masquerade, in the form the transport serves.
fn hysteria_masquerade(
    masquerade: &zero_config::Hysteria2Masquerade,
) -> zero_transport::masquerade::Masquerade {
    use zero_config::Hysteria2Masquerade as Config;
    use zero_transport::masquerade::Masquerade;
    match masquerade {
        Config::Text {
            status,
            headers,
            content,
        } => Masquerade::Text {
            status: *status,
            headers: headers
                .iter()
                .map(|(name, value)| (name.to_string(), value.to_string()))
                .collect(),
            content: content.as_bytes().to_vec(),
        },
        Config::Files { dir } => Masquerade::Files {
            dir: std::path::PathBuf::from(&**dir),
        },
        Config::Proxy { url } => {
            let base: Arc<str> = Arc::from(url.trim_end_matches('/'));
            Masquerade::Proxy(Arc::new(move |path: String, head: bool| {
                let url = format!("{base}{path}");
                Box::pin(async move { fetch_page(&url, head).await })
            }))
        }
    }
}

/// One page of the site a masquerade proxies. Only a 200 comes back with its
/// body (the fetch client keeps nothing else); any other status is passed on
/// as itself with no body, and a failure to reach the site is a 502.
async fn fetch_page(url: &str, head: bool) -> zero_transport::masquerade::Page {
    let limits = zero_net::fetch::FetchLimits {
        max_bytes: 16 * 1024 * 1024,
        timeout: Duration::from_secs(10),
        max_redirects: 3,
    };
    match zero_net::fetch::fetch(url, &limits, &Default::default()).await {
        Ok(zero_net::fetch::Fetched::Body { body, .. }) => {
            let kind = match url
                .split(['?', '#'])
                .next()
                .unwrap_or("")
                .rsplit('.')
                .next()
            {
                Some("css") => "text/css; charset=utf-8",
                Some("js") => "text/javascript; charset=utf-8",
                Some("json") => "application/json",
                Some("png") => "image/png",
                Some("jpg" | "jpeg") => "image/jpeg",
                Some("svg") => "image/svg+xml",
                Some("ico") => "image/x-icon",
                _ => "text/html; charset=utf-8",
            };
            let body = if head { Vec::new() } else { body };
            (
                200,
                vec![("content-type".to_string(), kind.to_string())],
                body,
            )
        }
        Ok(zero_net::fetch::Fetched::NotModified) => (304, Vec::new(), Vec::new()),
        Err(zero_net::fetch::FetchError::Status(status)) => (status, Vec::new(), Vec::new()),
        Err(_) => (502, Vec::new(), Vec::new()),
    }
}

/// An accepted TCP connection as the inbound security layer reads it.
type InboundTcp = zero_evasion::ReadPastMark<tokio::net::TcpStream>;

/// How a dokodemo inbound learns the real destination of what it accepts:
/// the `sockopt.tproxy` it names, or `followRedirect` alone, which means the
/// REDIRECT lookup (what most setups with that flag use). `Off` means only
/// the fixed `address`/`port`.
fn dokodemo_follow(inbound: &zero_config::Inbound) -> zero_config::Tproxy {
    match (&inbound.protocol, inbound.sockopt.tproxy) {
        (
            InboundProtocol::Dokodemo {
                follow_redirect: true,
                ..
            },
            zero_config::Tproxy::Off,
        ) => zero_config::Tproxy::Redirect,
        (InboundProtocol::Dokodemo { .. }, mode) => mode,
        _ => zero_config::Tproxy::Off,
    }
}

/// Read the PROXY protocol header at the start of `stream` and consume
/// exactly its bytes, leaving the rest of the connection untouched. A
/// connection that does not start with one is refused: with the option on, a
/// plain client would be reading its own address from nowhere.
async fn read_proxy_header(
    stream: &tokio::net::TcpStream,
) -> Result<zero_protocol::proxy_protocol::Header, String> {
    use zero_protocol::proxy_protocol::{parse, Parsed};
    let mut buffer = [0u8; 536];
    let mut last = 0;
    loop {
        let seen = stream.peek(&mut buffer).await.map_err(|e| e.to_string())?;
        if seen == 0 {
            return Err("the connection closed before a PROXY header".into());
        }
        match parse(&buffer[..seen]) {
            Parsed::Header(header, consumed) => {
                let mut taken = vec![0u8; consumed];
                let mut read = 0;
                while read < consumed {
                    stream.readable().await.map_err(|e| e.to_string())?;
                    match stream.try_read(&mut taken[read..]) {
                        Ok(0) => return Err("the connection closed inside the header".into()),
                        Ok(n) => read += n,
                        Err(e) if e.kind() == std::io::ErrorKind::WouldBlock => {}
                        Err(e) => return Err(e.to_string()),
                    }
                }
                return Ok(header);
            }
            Parsed::NotProxy => return Err("not a PROXY protocol header".into()),
            Parsed::Incomplete => {
                // Peek returns what has arrived without waiting for more;
                // wait for new bytes before looking again.
                if seen == last {
                    tokio::time::sleep(Duration::from_millis(5)).await;
                }
                last = seen;
            }
        }
    }
}

/// Dials the camouflage site, for the REALITY server to read the site's own
/// flight off.
///
/// The site is dialled with this runtime's resolver, so the site's name is
/// resolved the way every other destination is, and the dial carries the
/// same deadline.
struct RuntimeDecoy {
    target: zero_config::RealityTarget,
    resolver: Arc<zero_dns::Resolver>,
}

impl reality::DecoyDialer for RuntimeDecoy {
    fn dial(
        &self,
    ) -> std::pin::Pin<
        Box<dyn std::future::Future<Output = Result<zero_core::BoxStream, String>> + Send>,
    > {
        let target = self.target.clone();
        let resolver = Arc::clone(&self.resolver);
        Box::pin(async move {
            match &target {
                zero_config::RealityTarget::Host(address, port) => {
                    let destination = Destination::tcp(address.clone(), *port);
                    outbound::connect_direct_with_resolver(
                        &destination,
                        &zero_config::StreamSettings::default(),
                        &resolver,
                    )
                    .await
                    .map_err(|error| error.to_string())
                }
                zero_config::RealityTarget::Unix(path) => connect_unix(path).await,
            }
        })
    }
}

/// What terminating an inbound's security layer produced.
enum Secured {
    Stream(zero_core::BoxStream, ConnInfo),
    /// An unauthenticated REALITY client, to be handed to the camouflage
    /// target with the ClientHello it already sent.
    Fallback {
        stream: InboundTcp,
        client_hello: Vec<u8>,
        failure: String,
    },
}

/// Aborts the tasks it owns when dropped, so cancelling [`Server::run`] also
/// closes the listeners it spawned instead of leaving them accepting.
struct AbortOnDrop(Vec<tokio::task::JoinHandle<()>>);

impl Drop for AbortOnDrop {
    fn drop(&mut self) {
        for handle in &self.0 {
            handle.abort();
        }
    }
}

pub struct Server {
    state: arc_swap::ArcSwap<ServerState>,
    /// Routing rule-set data, held outside `ServerState` because it has its
    /// own lifecycle: a refresh replaces it without a configuration reload,
    /// and a reload must not discard data that is already current.
    geodata: Arc<arc_swap::ArcSwap<zero_router::GeoData>>,
    asset_status: Arc<StdMutex<Vec<AssetStatus>>>,
    planner: Arc<Mutex<zero_observatory::ConnectionPlanner>>,
    health: Arc<StdMutex<zero_observatory::HealthTable>>,
    clean_ip_results: Arc<StdMutex<Vec<zero_net::clean_ip::CleanIpResult>>>,
    xhttp_hub: zero_transport::xhttp::SharedSplitHub,
    xhttp_packet_hub: zero_transport::xhttp::SharedPacketHub,
    /// Shared ticket source for balancer selection. Keeping this outside the
    /// immutable config graph means reloads do not reset a live rotation back
    /// to the first member.
    selection_counter: AtomicU64,
    /// Flipped once every inbound listener is bound and accepting.
    ///
    /// Callers otherwise have no way to tell "starting up" from "started" but
    /// to poll the ports, and probing a port is not a safe way to ask: a UDP
    /// bind probe competes with the listener for the very port it is asking
    /// about, and can take it away. A host application embedding the runtime
    /// needs this for the same reason a test does.
    listening: tokio::sync::watch::Sender<bool>,
    /// Bumped on every configuration reload with the generation that was just
    /// installed. Its only job is to let the idle background tasks wait for a
    /// change instead of polling: while no observatory or asset block is
    /// configured, `run_observatory` and `run_asset_refresh` sleep on this
    /// signal rather than waking several times a minute to re-read a config
    /// that cannot have changed without a reload.
    ///
    /// Invariant: [`Server::reload`] stores the new state *before* it sends
    /// here, so a receiver woken by the signal always re-reads `config()` and
    /// sees the generation that triggered it. The value carried is only for
    /// clarity; a receiver reacts to the change, not to the number.
    config_changed: tokio::sync::watch::Sender<GenerationId>,
    /// Lock-free mirror of the planner rung used when materialising an
    /// outbound for a new session.
    planner_strategy: AtomicU8,
    /// The anti-sanction resolver measured best on this network, once the
    /// first measurement is in ([`crate::sanction_dns`]).
    sanction: StdMutex<Option<crate::sanction_dns::SanctionState>>,
    /// Names whose anti-sanction verdict has been logged, so each is said once
    /// (bounded; see [`Server::announce_sanction`]).
    announced: StdMutex<HashSet<String>>,
    /// Connections prepared ahead of need ([`crate::warm`]).
    warm: Arc<crate::warm::WarmPool>,
    /// The bridges that have dialled in to each reverse-proxy portal, by the
    /// portal's outbound tag. Kept here, outside the configuration, so a
    /// reload does not disconnect them.
    portals: StdMutex<HashMap<Arc<str>, Arc<crate::reverse::Portal>>>,
    /// Lock-free mirror of the shortest time-triggered reset the planner has
    /// measured, in milliseconds; `0` means no such evidence exists.
    ///
    /// Keepalive shaping needs the *number*, not just the rung: a carrier has
    /// to be retired before whatever deadline was actually observed, and a
    /// fixed guess would be useless on a short timeout and wasteful on a long
    /// one. Mirrored here for the same reason the rung is — materialising an
    /// outbound must not take the planner lock on every new session.
    planner_flow_lifetime_ms: AtomicU64,
    /// The running WireGuard inbounds by tag, for changing their peers.
    wireguard: StdMutex<HashMap<Arc<str>, RunningWireGuard>>,
    pub stats: Arc<Stats>,
}

/// What a running WireGuard inbound takes changes through: its list of
/// peers, and who owns which address for metering.
struct RunningWireGuard {
    peers: tokio::sync::mpsc::UnboundedSender<Vec<zero_protocol::wg_server::PeerSpec>>,
    owners: Arc<arc_swap::ArcSwap<WireGuardOwners>>,
}

/// A transport's first stream, and for multiplexing transports the channel
/// its later streams arrive on.
type AcceptedTransport = (
    zero_core::BoxStream,
    Option<tokio::sync::mpsc::Receiver<zero_core::BoxStream>>,
);

/// The configuration generation a session was accepted under. Handlers
/// borrow their inbound settings from it rather than cloning user lists,
/// credentials and sniffing rules for every connection.
struct InboundSession {
    state: Arc<ServerState>,
    /// What the connection's TLS layer learned, for fallbacks that choose by
    /// server name or ALPN.
    conn: ConnInfo,
}

/// The server name and ALPN protocol a TLS client asked for and got.
#[derive(Debug, Clone, Default)]
struct ConnInfo {
    server_name: Option<Arc<str>>,
    alpn: Option<Arc<[u8]>>,
    /// Where a transparently proxied connection was really going.
    original: Option<SocketAddr>,
    /// The inbound's own address, the destination of a PROXY header.
    local: Option<SocketAddr>,
    /// Set by Vision when a client goes direct under VLESS Encryption, so the
    /// encryption layer, which Vision cannot reach by type, stops decrypting.
    direct: Option<Arc<std::sync::atomic::AtomicBool>>,
}

struct Hysteria2UdpSession {
    connection: h3_quinn::quinn::Connection,
    session_id: u32,
    packet_id: u16,
    peer: SocketAddr,
    destination: Destination,
    payload: Vec<u8>,
}

/// Last refresh result per rule-set file, for the management API.
#[derive(Debug, Clone)]
struct AssetStatus {
    name: String,
    outcome: String,
    detail: Option<String>,
    entries: Option<usize>,
    at: std::time::SystemTime,
}

/// The password and name lists without the accounts `named` picks, and how
/// many those were.
#[allow(clippy::type_complexity)]
fn remove_passwords(
    passwords: &[Box<str>],
    emails: &[Option<Arc<str>>],
    named: impl Fn(Option<&Arc<str>>) -> bool,
) -> (Box<[Box<str>]>, Box<[Option<Arc<str>>]>, usize) {
    let (kept, names): (Vec<_>, Vec<_>) = passwords
        .iter()
        .cloned()
        .zip(emails.iter().cloned().chain(std::iter::repeat(None)))
        .filter(|(_, email)| !named(email.as_ref()))
        .unzip();
    let removed = passwords.len() - kept.len();
    (kept.into_boxed_slice(), names.into_boxed_slice(), removed)
}

fn accounts_unsupported(tag: &str) -> String {
    format!(
        "inbound {tag:?} does not take accounts at run time; only vless, vmess, trojan, shadowsocks, hysteria2, tuic, anytls, zerov1 and wireguard do"
    )
}

/// [`add_account`] for the parallel password and name lists of a Hysteria2 or
/// AnyTLS inbound: the new lists, and the name of a replaced account whose
/// password changed.
#[allow(clippy::type_complexity)]
fn place_password(
    passwords: &[Box<str>],
    emails: &[Option<Arc<str>>],
    password: &str,
    email: &Option<Arc<str>>,
) -> Result<((Box<[Box<str>]>, Option<Arc<str>>), Box<[Option<Arc<str>>]>), String> {
    let mut accounts: Vec<(Box<str>, Option<Arc<str>>)> = passwords
        .iter()
        .cloned()
        .zip(emails.iter().cloned().chain(std::iter::repeat(None)))
        .collect();
    let existing = email
        .as_ref()
        .and_then(|name| accounts.iter().position(|(_, e)| e.as_ref() == Some(name)));
    if accounts
        .iter()
        .enumerate()
        .any(|(index, (other, _))| Some(index) != existing && &**other == password)
    {
        return Err(format!(
            "the credential of {} is already used by another account",
            email.as_deref().unwrap_or("this account")
        ));
    }
    let replaced = match existing {
        Some(index) => {
            let changed = &*accounts[index].0 != password;
            accounts[index] = (password.into(), email.clone());
            changed.then(|| email.clone()).flatten()
        }
        None => {
            accounts.push((password.into(), email.clone()));
            None
        }
    };
    let (passwords, emails): (Vec<_>, Vec<_>) = accounts.into_iter().unzip();
    Ok((
        (passwords.into_boxed_slice(), replaced),
        emails.into_boxed_slice(),
    ))
}

/// Put `client` on `protocol`, replacing the account with the same `email`.
/// Returns that `email` when an account was replaced with a different
/// credential, whose sessions must then end.
fn add_account(
    protocol: &mut InboundProtocol,
    client: &zero_config::InboundClient,
) -> Result<Option<Arc<str>>, String> {
    use zero_config::InboundClient;

    /// Where `new` goes in `list`: over the account with its email, or at
    /// the end. A credential held by another account is refused.
    fn place<U: PartialEq>(
        list: &mut Vec<U>,
        new: U,
        email: impl Fn(&U) -> Option<&Arc<str>>,
        same_credential: impl Fn(&U, &U) -> bool,
    ) -> Result<Option<Arc<str>>, String> {
        let name = email(&new).cloned();
        let existing = name
            .as_ref()
            .and_then(|name| list.iter().position(|u| email(u) == Some(name)));
        if list
            .iter()
            .enumerate()
            .any(|(index, user)| Some(index) != existing && same_credential(user, &new))
        {
            return Err(format!(
                "the credential of {} is already used by another account",
                name.as_deref().unwrap_or("this account")
            ));
        }
        match existing {
            Some(index) => {
                let changed = !same_credential(&list[index], &new);
                list[index] = new;
                Ok(changed.then_some(name).flatten())
            }
            None => {
                list.push(new);
                Ok(None)
            }
        }
    }

    match (protocol, client) {
        (InboundProtocol::Vless(vless), InboundClient::Vless(user)) => {
            let mut users = vless.users.to_vec();
            let replaced = place(
                &mut users,
                user.clone(),
                |u| u.email.as_ref(),
                |a, b| a.uuid == b.uuid,
            )?;
            vless.users = users.into_boxed_slice();
            Ok(replaced)
        }
        (InboundProtocol::Vmess(vmess), InboundClient::Vmess(user)) => {
            let mut users = vmess.users.to_vec();
            let replaced = place(
                &mut users,
                user.clone(),
                |u| u.email.as_ref(),
                |a, b| a.uuid == b.uuid,
            )?;
            vmess.users = users.into_boxed_slice();
            Ok(replaced)
        }
        (
            InboundProtocol::Trojan(trojan),
            InboundClient::Trojan {
                password_hash,
                email,
            },
        ) => {
            let mut users: Vec<([u8; 56], Option<Arc<str>>)> = trojan
                .password_hashes
                .iter()
                .copied()
                .zip(trojan.emails.iter().cloned())
                .collect();
            let replaced = place(
                &mut users,
                (*password_hash, email.clone()),
                |(_, email)| email.as_ref(),
                |a, b| a.0 == b.0,
            )?;
            let (hashes, emails): (Vec<_>, Vec<_>) = users.into_iter().unzip();
            trojan.password_hashes = hashes.into_boxed_slice();
            trojan.emails = emails.into_boxed_slice();
            Ok(replaced)
        }
        (InboundProtocol::Shadowsocks(ss), InboundClient::Shadowsocks(user)) => {
            if !ss.multi_user && !ss.method.is_2022() {
                return Err(
                    "a single-password Shadowsocks inbound takes no accounts; give it settings.clients"
                        .into(),
                );
            }
            if ss.method == zero_config::ShadowsocksMethod::Blake3Chacha20Poly1305 {
                return Err("2022-blake3-chacha20-poly1305 has no multi-user form".into());
            }
            let mut users = ss.users.to_vec();
            let replaced = place(&mut users, user.clone(), |u| u.email.as_ref(), |a, b| {
                a.password == b.password
            })?;
            ss.users = users.into_boxed_slice();
            // A 2022 inbound given its first account serves accounts from now
            // on; its key becomes the identity key they all send.
            ss.multi_user = true;
            Ok(replaced)
        }
        (InboundProtocol::Hysteria2(hy), InboundClient::Password { password, email }) => {
            let (passwords, emails) =
                place_password(&hy.passwords, &hy.emails, password, email)?;
            (hy.passwords, hy.emails) = (passwords.0, emails);
            Ok(passwords.1)
        }
        (InboundProtocol::AnyTls(any), InboundClient::Password { password, email }) => {
            let (passwords, emails) =
                place_password(&any.passwords, &any.emails, password, email)?;
            (any.passwords, any.emails) = (passwords.0, emails);
            Ok(passwords.1)
        }
        (InboundProtocol::Tuic(tuic), InboundClient::Tuic(user)) => {
            let mut users = tuic.users.to_vec();
            let replaced = place(&mut users, user.clone(), |u| u.email.as_ref(), |a, b| {
                a.uuid == b.uuid
            })?;
            // A changed password under the same uuid is a changed credential.
            let replaced = replaced.or_else(|| {
                let email = user.email.as_ref()?;
                tuic.users
                    .iter()
                    .find(|old| old.email.as_ref() == Some(email))
                    .filter(|old| old.password != user.password)
                    .map(|_| Arc::clone(email))
            });
            tuic.users = users.into_boxed_slice();
            Ok(replaced)
        }
        (InboundProtocol::Tide(tide), InboundClient::Tide { id, name }) => {
            // A Tide user's name is a plain string, not an optional one, so
            // `place` does not fit it; the rules are the same.
            if tide
                .users
                .iter()
                .any(|user| user.id == *id && *user.name != **name)
            {
                return Err(format!(
                    "the credential of {name} is already used by another account"
                ));
            }
            let mut users = tide.users.to_vec();
            let replaced = match users.iter().position(|user| *user.name == **name) {
                Some(index) => {
                    let changed = users[index].id != *id;
                    users[index].id = *id;
                    changed.then(|| Arc::clone(name))
                }
                None => {
                    users.push(zero_config::TideUser {
                        id: *id,
                        name: Box::from(&**name),
                    });
                    None
                }
            };
            tide.users = users.into_boxed_slice();
            Ok(replaced)
        }
        (InboundProtocol::WireGuard(wireguard), InboundClient::WireGuard(peer)) => {
            let mut peers = wireguard.peers.to_vec();
            let replaced = place(
                &mut peers,
                peer.clone(),
                |p| p.email.as_ref(),
                |a, b| a.public_key == b.public_key,
            )?;
            wireguard.peers = peers.into_boxed_slice();
            Ok(replaced)
        }
        (
            InboundProtocol::Vless(_)
            | InboundProtocol::Vmess(_)
            | InboundProtocol::Trojan(_)
            | InboundProtocol::Shadowsocks(_)
            | InboundProtocol::Hysteria2(_)
            | InboundProtocol::AnyTls(_)
            | InboundProtocol::Tuic(_)
            | InboundProtocol::Tide(_)
            | InboundProtocol::WireGuard(_),
            _,
        ) => {
            Err("the account is for a different protocol than the inbound".into())
        }
        _ => Err(
            "this inbound does not take accounts at run time; only vless, vmess, trojan, shadowsocks, hysteria2, tuic, anytls, zerov1 and wireguard do"
                .into(),
        ),
    }
}

/// Every `(inbound tag, email)` pair that `config` meters.
pub(crate) fn metered_accounts(config: &RuntimeConfig) -> HashSet<(Arc<str>, Arc<str>)> {
    let mut accounts = HashSet::new();
    for inbound in config.inbounds.iter() {
        let emails: Vec<&Arc<str>> = match &inbound.protocol {
            InboundProtocol::Vless(vless) => vless
                .users
                .iter()
                .filter_map(|u| u.email.as_ref())
                .collect(),
            InboundProtocol::Vmess(vmess) => vmess
                .users
                .iter()
                .filter_map(|u| u.email.as_ref())
                .collect(),
            InboundProtocol::Trojan(trojan) => trojan.emails.iter().flatten().collect(),
            InboundProtocol::Shadowsocks(ss) => ss
                .users
                .iter()
                .filter_map(|u| u.email.as_ref())
                .chain(ss.email.as_ref())
                .collect(),
            InboundProtocol::Hysteria2(hy) => hy.emails.iter().flatten().collect(),
            InboundProtocol::AnyTls(any) => any.emails.iter().flatten().collect(),
            InboundProtocol::Tuic(tuic) => {
                tuic.users.iter().filter_map(|u| u.email.as_ref()).collect()
            }
            InboundProtocol::WireGuard(wireguard) => wireguard
                .peers
                .iter()
                .filter_map(|p| p.email.as_ref())
                .collect(),
            InboundProtocol::Tide(tide) => {
                for user in tide.users.iter().filter(|user| !user.name.is_empty()) {
                    accounts.insert((Arc::clone(&inbound.tag), Arc::from(&*user.name)));
                }
                Vec::new()
            }
            _ => Vec::new(),
        };
        for email in emails {
            accounts.insert((Arc::clone(&inbound.tag), Arc::clone(email)));
        }
    }
    accounts
}

impl Server {
    pub fn new(cfg: ServerConfig) -> Self {
        Self::with_stats(cfg, Arc::new(Stats::default()))
    }

    /// A server that carries on `stats` (the figures, accounts, speed limits
    /// and event subscribers) of the one it replaces ([`crate::host`]).
    pub fn with_stats(cfg: ServerConfig, stats: Arc<Stats>) -> Self {
        let geodata = Arc::new(arc_swap::ArcSwap::from_pointee(Self::initial_geodata(
            &cfg.config,
        )));
        let state = Self::build_state(cfg.config, cfg.generation, &geodata.load_full());
        Server {
            state: arc_swap::ArcSwap::from_pointee(state),
            geodata,
            asset_status: Arc::new(StdMutex::new(Vec::new())),
            planner: Arc::new(Mutex::new({
                let mut planner =
                    zero_observatory::ConnectionPlanner::new(b"zray-local-network-profile");
                planner.set_decoy_available(zero_evasion::decoy::any_available());
                planner
            })),
            health: Arc::new(StdMutex::new(zero_observatory::HealthTable::default())),
            clean_ip_results: Arc::new(StdMutex::new(Vec::new())),
            xhttp_hub: Arc::new(zero_transport::xhttp::SplitHub::new()),
            xhttp_packet_hub: Arc::new(zero_transport::xhttp::PacketHub::new()),
            selection_counter: AtomicU64::new(0),
            listening: tokio::sync::watch::channel(false).0,
            config_changed: tokio::sync::watch::channel(cfg.generation).0,
            planner_strategy: AtomicU8::new(zero_observatory::PathStrategy::DirectReality.as_u8()),
            sanction: StdMutex::new(None),
            announced: StdMutex::new(HashSet::new()),
            warm: Arc::default(),
            portals: StdMutex::new(HashMap::new()),
            planner_flow_lifetime_ms: AtomicU64::new(0),
            wireguard: StdMutex::new(HashMap::new()),
            stats,
        }
    }

    /// Return bounded, local-only outbound health evidence for the management
    /// API. It contains endpoint tags and timing counters, never destinations
    /// or payload data.
    pub fn health_snapshot(&self) -> serde_json::Value {
        let health = self
            .health
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        let entries = self
            .config()
            .outbounds
            .iter()
            .map(|outbound| {
                let sample = health.sample(&outbound.tag);
                serde_json::json!({
                    "tag": outbound.tag.as_ref(),
                    "successes": sample.successes,
                    "failures": sample.failures,
                    "consecutiveFailures": sample.consecutive_failures,
                    "latencyMs": sample.latency.map(|value| value.as_secs_f64() * 1000.0),
                })
            })
            .collect::<Vec<_>>();
        serde_json::Value::Array(entries)
    }

    /// Return the latest bounded clean-IP application probes. Only the
    /// operator-supplied edge address and response progress are retained.
    pub fn clean_ip_snapshot(&self) -> serde_json::Value {
        let results = self
            .clean_ip_results
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        serde_json::Value::Array(
            results
                .iter()
                .map(|result| {
                    serde_json::json!({
                        "address": result.address.to_string(),
                        "elapsedMs": result.elapsed.as_secs_f64() * 1000.0,
                        "status": result.status,
                        "responseBytes": result.response_bytes,
                        "success": result.success,
                    })
                })
                .collect(),
        )
    }

    /// Assemble the startup dataset: whatever the host supplied through the
    /// environment, overlaid with any validated cached rule sets. A cache that
    /// fails validation is reported and skipped, never merged.
    fn initial_geodata(config: &RuntimeConfig) -> zero_router::GeoData {
        let mut geodata = zero_router::GeoData::from_environment();
        let Some(assets) = config.assets.as_ref() else {
            return geodata;
        };
        let store = asset_store(assets);
        let specs = asset_specs(assets);
        if specs.is_empty() {
            return geodata;
        }
        let (cached, problems) = store.load_geodata(&specs);
        for problem in &problems {
            warn!(%problem, "cached rule set is unusable and was not loaded");
        }
        geodata.merge(cached);
        geodata
    }

    fn build_router(config: &RuntimeConfig, geodata: &zero_router::GeoData) -> Arc<Router> {
        let router = Arc::new(Router::build_with_geodata(config, geodata));
        if !router.unresolved.is_empty() {
            warn!(
                count = router.unresolved.len(),
                tags = %router.unresolved.iter().take(8).map(|t| t.to_string()).collect::<Vec<_>>().join(", "),
                "geosite/geoip rules are skipped: no geodata loaded"
            );
        }
        router
    }

    fn build_state(
        config: Arc<RuntimeConfig>,
        generation: GenerationId,
        geodata: &zero_router::GeoData,
    ) -> ServerState {
        // The policy is process-wide, so the generation just built decides
        // for every connection from here on.
        HANDSHAKE_MS.store(
            config.policy.handshake.as_millis() as u64,
            Ordering::Relaxed,
        );
        crate::relay::set_policy(config.policy.conn_idle, config.policy.half_close);
        let router = Self::build_router(&config, geodata);
        let client_resolver = Arc::new(zero_dns::Resolver::new(config.dns.clone()));
        let resolver = Arc::new(client_resolver.without_fake());
        let inbounds: Vec<_> = config
            .inbounds
            .iter()
            .map(|inbound| InboundRuntime::compile(inbound, &resolver))
            .collect();
        learn_post_handshake(&config, &inbounds, &resolver);
        ServerState {
            resolver,
            client_resolver,
            inbounds: inbounds.into(),
            config,
            router,
            generation,
        }
    }

    /// Atomically replace the routing, DNS, outbound and authentication graph.
    ///
    /// Existing sessions retain the old `Arc` state until they finish. The
    /// listener topology is deliberately kept stable: changing a bound port
    /// or protocol during reload would create a partial generation and can
    /// strand clients. Callers must restart for that topology change.
    pub fn reload(
        &self,
        config: Arc<RuntimeConfig>,
        generation: GenerationId,
    ) -> Result<(), String> {
        let current = self.state.load();
        if current.config.inbounds.len() != config.inbounds.len() {
            return Err("reload cannot change the inbound listener topology".into());
        }
        for (old, new) in current.config.inbounds.iter().zip(config.inbounds.iter()) {
            if old.listen != new.listen
                || old.port != new.port
                || std::mem::discriminant(&old.protocol) != std::mem::discriminant(&new.protocol)
            {
                return Err(format!(
                    "reload cannot change inbound {} listener topology",
                    old.tag
                ));
            }
        }
        config.validate()?;
        // Balancer health is keyed by outbound tag. A host that re-orders its
        // servers on reload (the mobile app lists them best first) points a
        // tag at a different server, which must not inherit the latency and
        // failures measured for the one it replaced.
        {
            let mut health = self
                .health
                .lock()
                .unwrap_or_else(|poisoned| poisoned.into_inner());
            for old in current.config.outbounds.iter() {
                let unchanged = config
                    .outbound_by_tag(&old.tag)
                    .is_some_and(|new| format!("{new:?}") == format!("{old:?}"));
                if !unchanged {
                    health.forget(&old.tag);
                    // A Psiphon outbound that changed keeps a tunnel it no
                    // longer needs: the old configuration's client is dropped
                    // so its SSH session and its memory go with it. One that
                    // did not change keeps its tunnel, which is the point of
                    // sharing a client per configuration.
                    forget_psiphon(old);
                }
            }
        }
        let mut next = Self::build_state(config, generation, &self.geodata.load_full());
        // A reload builds a fresh resolver on purpose: a network change is a
        // reload too (`zray_network_changed`), and pooled DoH/DoT connections
        // bound to the old interface must go. The FakeDNS mappings the
        // applications already hold must survive it, though, or every
        // address they cached would lead nowhere.
        if next.client_resolver.has_fake() {
            let adopted = (*next.client_resolver)
                .clone()
                .adopt_fake_state(&current.client_resolver);
            next.resolver = Arc::new(adopted.without_fake());
            next.client_resolver = Arc::new(adopted);
        }
        let accounts = metered_accounts(&next.config);
        self.state.store(Arc::new(next));
        // An account the new configuration no longer lists on an inbound has
        // no business keeping the sessions it opened there.
        let ended = self.stats.accounts.end_where(|email, inbound| {
            !accounts.contains(&(Arc::<str>::from(inbound), Arc::<str>::from(email)))
        });
        if ended > 0 {
            info!(ended, "reload ended the sessions of removed accounts");
        }
        self.stats.events().emit(|| crate::events::Event::Reloaded {
            generation: generation.0,
            ended,
        });
        // Wake the idle background tasks now that the new state is visible.
        // The store above happens first on purpose: a task woken here re-reads
        // `config()` and must see the generation that triggered the wake, not
        // the one it replaced. A send only fails when no task is listening,
        // which is fine — there is nothing to wake.
        let _ = self.config_changed.send(generation);
        Ok(())
    }

    /// Recompile the router against newly installed rule-set data, keeping the
    /// current configuration generation. Sessions in flight keep the old
    /// `Arc`; new sessions see the new rules.
    ///
    /// Only the router changes. The resolver in particular is kept: a fresh
    /// one would forget every FakeDNS mapping it handed out, so each session
    /// opened afterwards to an address an application had already resolved
    /// would be routed by a meaningless synthetic IP. It would also discard
    /// the DNS cache and the compiled inbound TLS state for no reason.
    ///
    /// `rcu` rather than load-then-store: a reload landing in between must
    /// not be overwritten by a router compiled for the configuration it
    /// replaced.
    /// Add accounts to the inbound tagged `tag` of the running server.
    ///
    /// Unlike [`Server::reload`], nothing else is rebuilt: routing, the DNS
    /// caches, the TLS session caches and every open session are left as they
    /// are, and the next handshake on the inbound sees the new list. An
    /// account whose `email` is already on the inbound is replaced; if its
    /// credential changed, its open sessions there are ended, since they were
    /// opened with a credential that no longer exists. A credential another
    /// account already holds is refused: the handshake could not tell the two
    /// apart.
    pub fn add_accounts(
        &self,
        tag: &str,
        clients: &[zero_config::InboundClient],
    ) -> Result<(), String> {
        let replaced = self.edit_inbound_accounts(tag, |protocol| {
            let mut replaced = Vec::new();
            for client in clients {
                if let Some(email) = add_account(protocol, client)? {
                    replaced.push(email);
                }
            }
            Ok(replaced)
        })?;
        self.sync_running_accounts(tag);
        if !replaced.is_empty() {
            self.stats.accounts.end_where(|email, inbound| {
                inbound == tag && replaced.iter().any(|r| &**r == email)
            });
        }
        self.stats
            .events()
            .emit(|| crate::events::Event::AccountsAdded {
                inbound: tag.to_string(),
                emails: clients
                    .iter()
                    .filter_map(|client| client.email().map(|email| email.to_string()))
                    .collect(),
            });
        Ok(())
    }

    /// Remove the accounts named `emails` from the inbound tagged `tag` of the
    /// running server, without a reload (see [`Server::add_accounts`]), and
    /// end their open sessions there. Returns how many accounts were removed;
    /// a name that is not on the inbound is not an error.
    pub fn remove_accounts(&self, tag: &str, emails: &[&str]) -> Result<usize, String> {
        let removed = self.edit_inbound_accounts(tag, |protocol| {
            let named = |email: Option<&Arc<str>>| email.is_some_and(|e| emails.contains(&&**e));
            Ok(match protocol {
                InboundProtocol::Vless(vless) => {
                    let mut users = vless.users.to_vec();
                    let before = users.len();
                    users.retain(|user| !named(user.email.as_ref()));
                    vless.users = users.into_boxed_slice();
                    before - vless.users.len()
                }
                InboundProtocol::Vmess(vmess) => {
                    let mut users = vmess.users.to_vec();
                    let before = users.len();
                    users.retain(|user| !named(user.email.as_ref()));
                    vmess.users = users.into_boxed_slice();
                    before - vmess.users.len()
                }
                InboundProtocol::Trojan(trojan) => {
                    let (hashes, kept): (Vec<_>, Vec<_>) = trojan
                        .password_hashes
                        .iter()
                        .zip(trojan.emails.iter())
                        .filter(|(_, email)| !named(email.as_ref()))
                        .map(|(hash, email)| (*hash, email.clone()))
                        .unzip();
                    let removed = trojan.password_hashes.len() - hashes.len();
                    trojan.password_hashes = hashes.into_boxed_slice();
                    trojan.emails = kept.into_boxed_slice();
                    removed
                }
                InboundProtocol::Shadowsocks(ss) => {
                    let mut users = ss.users.to_vec();
                    let before = users.len();
                    users.retain(|user| !named(user.email.as_ref()));
                    ss.users = users.into_boxed_slice();
                    before - ss.users.len()
                }
                InboundProtocol::Tuic(tuic) => {
                    let mut users = tuic.users.to_vec();
                    let before = users.len();
                    users.retain(|user| !named(user.email.as_ref()));
                    tuic.users = users.into_boxed_slice();
                    before - tuic.users.len()
                }
                InboundProtocol::Hysteria2(hy) => {
                    let removed;
                    (hy.passwords, hy.emails, removed) =
                        remove_passwords(&hy.passwords, &hy.emails, named);
                    removed
                }
                InboundProtocol::AnyTls(any) => {
                    let removed;
                    (any.passwords, any.emails, removed) =
                        remove_passwords(&any.passwords, &any.emails, named);
                    removed
                }
                InboundProtocol::Tide(tide) => {
                    let mut users = tide.users.to_vec();
                    let before = users.len();
                    users.retain(|user| !emails.contains(&&*user.name));
                    tide.users = users.into_boxed_slice();
                    before - tide.users.len()
                }
                InboundProtocol::WireGuard(wireguard) => {
                    let mut peers = wireguard.peers.to_vec();
                    let before = peers.len();
                    peers.retain(|peer| !named(peer.email.as_ref()));
                    wireguard.peers = peers.into_boxed_slice();
                    before - wireguard.peers.len()
                }
                _ => return Err(accounts_unsupported(tag)),
            })
        })?;
        self.sync_running_accounts(tag);
        self.stats
            .accounts
            .end_where(|email, inbound| inbound == tag && emails.contains(&email));
        self.stats
            .events()
            .emit(|| crate::events::Event::AccountsRemoved {
                inbound: tag.to_string(),
                emails: emails.iter().map(|email| email.to_string()).collect(),
            });
        Ok(removed)
    }

    /// Hand the accounts of the inbound tagged `tag`, as the current state
    /// has them, to the parts of it that run apart from the state: a Tide
    /// server's user table and a WireGuard server's peers. Every other
    /// protocol reads its accounts from the state at each handshake.
    fn sync_running_accounts(&self, tag: &str) {
        let state = self.state.load();
        let Some((index, inbound)) = state
            .config
            .inbounds
            .iter()
            .enumerate()
            .find(|(_, inbound)| &*inbound.tag == tag)
        else {
            return;
        };
        match &inbound.protocol {
            InboundProtocol::Tide(tide) => {
                if let Some(running) = state.inbounds.get(index).and_then(|c| c.tide.as_ref()) {
                    running.sync_users(tide);
                }
            }
            InboundProtocol::WireGuard(wireguard) => {
                let running = self
                    .wireguard
                    .lock()
                    .unwrap_or_else(|poisoned| poisoned.into_inner());
                if let Some(running) = running.get(tag) {
                    running
                        .owners
                        .store(Arc::new(WireGuardOwners::of(&wireguard.peers)));
                    let _ = running.peers.send(peer_specs(&wireguard.peers));
                }
            }
            _ => {}
        }
    }

    /// Apply `edit` to the protocol settings of the inbound tagged `tag` and
    /// install the result, keeping everything else of the current state. Runs
    /// as a read-copy-update, so an edit racing a reload or another edit is
    /// redone on whichever state won rather than overwriting it.
    fn edit_inbound_accounts<T>(
        &self,
        tag: &str,
        mut edit: impl FnMut(&mut InboundProtocol) -> Result<T, String>,
    ) -> Result<T, String> {
        let mut outcome = None;
        self.state.rcu(|current| {
            let mut config = (*current.config).clone();
            let mut inbounds = std::mem::take(&mut config.inbounds).into_vec();
            let index = inbounds.iter().position(|inbound| &*inbound.tag == tag);
            let edited = match index {
                Some(index) => edit(&mut inbounds[index].protocol),
                None => Err(format!("there is no inbound tagged {tag:?}")),
            };
            // What is compiled from the accounts (a Shadowsocks 2022 user
            // table) is rebuilt for the edited inbound; nothing else is.
            let compiled = match (&edited, index) {
                (Ok(_), Some(index)) => {
                    let users = shadowsocks_users(&inbounds[index].protocol);
                    if users.is_some() || current.inbounds[index].shadowsocks_users.is_some() {
                        let mut compiled = current.inbounds.to_vec();
                        compiled[index].shadowsocks_users = users;
                        Arc::from(compiled)
                    } else {
                        Arc::clone(&current.inbounds)
                    }
                }
                _ => Arc::clone(&current.inbounds),
            };
            config.inbounds = inbounds.into_boxed_slice();
            match edited.and_then(|value| config.validate().map(|()| value)) {
                Ok(value) => {
                    outcome = Some(Ok(value));
                    Arc::new(ServerState {
                        config: Arc::new(config),
                        router: Arc::clone(&current.router),
                        client_resolver: Arc::clone(&current.client_resolver),
                        resolver: Arc::clone(&current.resolver),
                        generation: current.generation,
                        inbounds: compiled,
                    })
                }
                Err(error) => {
                    outcome = Some(Err(error));
                    Arc::clone(current)
                }
            }
        });
        outcome.expect("rcu runs its closure at least once")
    }

    fn rebuild_router_for_new_geodata(&self) {
        let geodata = self.geodata.load_full();
        self.state.rcu(|current| ServerState {
            config: Arc::clone(&current.config),
            router: Self::build_router(&current.config, &geodata),
            client_resolver: Arc::clone(&current.client_resolver),
            resolver: Arc::clone(&current.resolver),
            generation: current.generation,
            inbounds: Arc::clone(&current.inbounds),
        });
    }

    /// Bind every supported inbound and serve until cancelled.
    ///
    /// Every listener and background task is owned by this future: dropping
    /// it (a shutdown signal winning a `select!`, or an aborted task) closes
    /// the listeners, so a drain that follows sees no new sessions. Sessions
    /// already accepted keep running until they finish on their own.
    pub async fn run(self: Arc<Self>) -> std::io::Result<()> {
        let mut background = AbortOnDrop(Vec::with_capacity(3));
        let mut handles = AbortOnDrop(Vec::new());
        let handles_vec = &mut handles.0;

        let initial = self.state.load_full();
        // Keep one watcher alive for the lifetime of the server. It observes
        // the current generation on every pass, so an API reload can enable,
        // disable, or retune the observatory without restarting listeners.
        let me = Arc::clone(&self);
        background.0.push(tokio::spawn(async move {
            me.run_observatory().await;
        }));
        let me = Arc::clone(&self);
        background.0.push(tokio::spawn(async move {
            me.run_asset_refresh().await;
        }));
        let me = Arc::clone(&self);
        background.0.push(tokio::spawn(async move {
            me.run_strategy_descent().await;
        }));
        let me = Arc::clone(&self);
        background.0.push(tokio::spawn(async move {
            me.run_cdn_watch().await;
        }));
        let me = Arc::clone(&self);
        background.0.push(tokio::spawn(async move {
            me.run_sanction_watch().await;
        }));
        // One supervisor per reverse-proxy bridge, from the configuration
        // this run started with.
        for bridge in initial.config.bridges.iter() {
            let (me, tag, domain) = (Arc::clone(&self), bridge.tag.clone(), bridge.domain.clone());
            let via = bridge.via.clone();
            background.0.push(tokio::spawn(async move {
                let (dialer, router) = (Arc::clone(&me), Arc::clone(&me));
                let (dial_tag, route_tag) = (tag.clone(), tag);
                crate::reverse::run_bridge(
                    move || {
                        let (me, tag, domain) =
                            (Arc::clone(&dialer), dial_tag.clone(), domain.clone());
                        let via = via.clone();
                        async move {
                            let destination = Destination::tcp(Address::domain(&domain), 0);
                            match via {
                                // A VLESS account's reverse: dial the portal
                                // straight through that outbound.
                                Some(outbound) => me.bridge_dial_via(&outbound, &destination).await,
                                None => me.bridge_connect(tag, destination).await,
                            }
                        }
                    },
                    move |destination| {
                        let (me, tag) = (Arc::clone(&router), route_tag.clone());
                        async move {
                            let result = me.bridge_connect(tag.clone(), destination.clone()).await;
                            if let Err(error) = &result {
                                debug!(bridge = %tag, %destination, %error, "reverse bridge session refused");
                            }
                            result
                        }
                    },
                )
                .await;
            }));
        }
        // A VLESS Encryption setting that cannot be used (a key of the wrong
        // size, a typo in the mode) must stop the server at start, not make
        // every client's connection fail one by one.
        for (inbound, compiled) in initial.config.inbounds.iter().zip(initial.inbounds.iter()) {
            if let Some(Err(error)) = &compiled.vless_encryption {
                return Err(std::io::Error::new(
                    std::io::ErrorKind::InvalidInput,
                    format!("inbound {:?}: VLESS decryption: {error}", inbound.tag),
                ));
            }
        }
        for (idx, inbound) in initial.config.inbounds.iter().enumerate() {
            let addr = SocketAddr::new(
                inbound
                    .listen
                    .as_ip()
                    .unwrap_or_else(|| "127.0.0.1".parse().unwrap()),
                inbound.port,
            );

            if let InboundProtocol::WireGuard(wireguard) = &inbound.protocol {
                let socket = UdpSocket::bind(addr).await?;
                info!(tag = %inbound.tag, %addr, protocol = inbound.protocol.kind(), "listening");
                let me = Arc::clone(&self);
                let id = InboundId(idx as u32);
                let (tag, wireguard) = (inbound.tag.clone(), wireguard.clone());
                handles_vec.push(tokio::spawn(async move {
                    me.serve_wireguard(socket, id, tag, wireguard).await;
                }));
                continue;
            }

            if let InboundProtocol::Tun(tun) = &inbound.protocol {
                let me = Arc::clone(&self);
                let id = InboundId(idx as u32);
                let tag = inbound.tag.clone();
                let tun = tun.clone();
                handles_vec.push(tokio::spawn(async move {
                    me.serve_tun(id, tag, tun).await;
                }));
                continue;
            }

            if let InboundProtocol::Hysteria2(hysteria) = &inbound.protocol {
                let zero_config::InboundSecurity::Tls(tls) = &inbound.security else {
                    return Err(std::io::Error::new(
                        std::io::ErrorKind::InvalidInput,
                        "Hysteria2 inbound requires certificate TLS",
                    ));
                };
                let endpoint = zero_transport::xhttp::h3_server_endpoint_obfuscated(
                    addr,
                    &tls.certificate,
                    &tls.private_key,
                    hysteria.obfs_password.as_deref(),
                )
                .map_err(|error| std::io::Error::new(std::io::ErrorKind::InvalidInput, error))?;
                info!(tag = %inbound.tag, %addr, protocol = inbound.protocol.kind(), "listening");
                let me = Arc::clone(&self);
                let id = InboundId(idx as u32);
                handles_vec.push(tokio::spawn(async move {
                    me.accept_hysteria2_loop(endpoint, id).await;
                }));
                continue;
            }

            if let InboundProtocol::Tuic(_) = &inbound.protocol {
                let zero_config::InboundSecurity::Tls(tls) = &inbound.security else {
                    return Err(std::io::Error::new(
                        std::io::ErrorKind::InvalidInput,
                        "TUIC inbound requires certificate TLS",
                    ));
                };
                let endpoint = zero_transport::xhttp::h3_server_endpoint(
                    addr,
                    &tls.certificate,
                    &tls.private_key,
                )
                .map_err(|error| std::io::Error::new(std::io::ErrorKind::InvalidInput, error))?;
                info!(tag = %inbound.tag, %addr, protocol = inbound.protocol.kind(), "listening");
                let me = Arc::clone(&self);
                let id = InboundId(idx as u32);
                handles_vec.push(tokio::spawn(async move {
                    me.accept_tuic_loop(endpoint, id).await;
                }));
                continue;
            }

            if let zero_config::Transport::Xhttp(settings) = &inbound.transport {
                if settings.xhttp_http_version == zero_config::XhttpHttpVersion::Http3 {
                    let zero_config::InboundSecurity::Tls(tls) = &inbound.security else {
                        return Err(std::io::Error::new(
                            std::io::ErrorKind::InvalidInput,
                            "XHTTP HTTP/3 inbound requires certificate TLS",
                        ));
                    };
                    let endpoint = zero_transport::xhttp::h3_server_endpoint(
                        addr,
                        &tls.certificate,
                        &tls.private_key,
                    )
                    .map_err(|error| {
                        std::io::Error::new(std::io::ErrorKind::InvalidInput, error)
                    })?;
                    info!(tag = %inbound.tag, %addr, protocol = inbound.protocol.kind(), "listening");
                    let me = Arc::clone(&self);
                    let id = InboundId(idx as u32);
                    handles_vec.push(tokio::spawn(async move {
                        me.accept_h3_loop(endpoint, id).await;
                    }));
                    continue;
                }
            }

            let mut transparent = false;
            if let InboundProtocol::Dokodemo { tcp, udp, .. } = &inbound.protocol {
                // What it can send a connection to when nothing was redirected.
                let target = inbound.dokodemo_destination(None);
                let follow = dokodemo_follow(inbound);
                transparent = follow == zero_config::Tproxy::Tproxy;
                let id = InboundId(idx as u32);
                if *udp {
                    let tag = inbound.tag.clone();
                    if transparent {
                        let socket = zero_net::transparent::TransparentUdp::bind(addr)?;
                        info!(tag = %inbound.tag, %addr, protocol = "dokodemo (tproxy udp)", "listening");
                        let me = Arc::clone(&self);
                        handles_vec.push(tokio::spawn(async move {
                            me.serve_tproxy_udp(socket, id, tag).await;
                        }));
                    } else if let Some(target) = target.clone() {
                        let socket = UdpSocket::bind(addr).await?;
                        info!(tag = %inbound.tag, %addr, protocol = inbound.protocol.kind(), "listening");
                        let me = Arc::clone(&self);
                        handles_vec.push(tokio::spawn(async move {
                            me.serve_dokodemo_udp(socket, id, tag, target).await;
                        }));
                    } else {
                        debug!(tag = %inbound.tag, "dokodemo-door UDP inbound needs a fixed target or tproxy; skipping");
                    }
                }
                if !*tcp {
                    continue;
                }
                if target.is_none() && follow == zero_config::Tproxy::Off {
                    debug!(tag = %inbound.tag, "dokodemo-door TCP inbound needs a fixed target or followRedirect; skipping");
                    continue;
                }
            }

            let listener = zero_net::prepare_listener_with(
                addr,
                &zero_net::ListenOptions {
                    v6_only: inbound.sockopt.v6_only,
                    mptcp: inbound.sockopt.mptcp,
                    mark: inbound.sockopt.mark,
                    transparent,
                    custom: inbound.sockopt.custom.clone(),
                },
            )?;
            info!(tag = %inbound.tag, %addr, protocol = inbound.protocol.kind(), "listening");

            let me = Arc::clone(&self);
            let id = InboundId(idx as u32);
            handles_vec.push(tokio::spawn(async move {
                me.accept_loop(listener, id).await;
            }));
        }

        if handles_vec.is_empty() && initial.config.bridges.is_empty() {
            return Err(std::io::Error::new(
                std::io::ErrorKind::InvalidInput,
                "no supported inbound to listen on",
            ));
        }

        // Every listener above is bound before its accept loop is spawned, so
        // reaching here means the server is accepting.
        // `send_replace`, not `send`: a `watch` send fails and leaves the
        // value untouched when no receiver happens to exist at that instant,
        // which for a signal that is latched once is a silent loss — every
        // later subscriber would then wait forever for a transition that
        // already happened.
        self.listening.send_replace(true);

        for handle in handles_vec.iter_mut() {
            let _ = handle.await;
        }
        // A server that is only a reverse-proxy bridge listens on nothing; it
        // runs as long as its supervisors do.
        if handles_vec.is_empty() {
            std::future::pending::<()>().await;
        }
        drop(background);
        Ok(())
    }

    /// Resolve once every inbound listener is bound and accepting.
    ///
    /// Returns immediately if that has already happened, and never resolves if
    /// `run` failed before binding — so callers should pair it with a timeout
    /// or with the `run` handle itself.
    pub async fn wait_until_listening(&self) {
        let mut rx = self.listening.subscribe();
        if *rx.borrow_and_update() {
            return;
        }
        let _ = rx.changed().await;
    }

    /// Whether every inbound listener is bound.
    pub fn is_listening(&self) -> bool {
        *self.listening.borrow()
    }

    /// Sessions currently being served.
    pub fn active_sessions(&self) -> u64 {
        self.stats.active.load(Ordering::Relaxed)
    }

    /// Wait until every in-flight TCP session has finished, or `timeout`
    /// elapses. Returns the number of sessions still active when it returned:
    /// `0` means a clean drain, non-zero means the timeout forced the issue.
    /// Listeners are expected to be cancelled by the caller before this is
    /// awaited, so no new sessions arrive while it counts down.
    pub async fn drain(&self, timeout: std::time::Duration) -> u64 {
        let deadline = tokio::time::Instant::now() + timeout;
        loop {
            let active = self.active_sessions();
            if active == 0 {
                return 0;
            }
            if tokio::time::Instant::now() >= deadline {
                return active;
            }
            tokio::time::sleep(std::time::Duration::from_millis(50)).await;
        }
    }

    async fn accept_loop(self: Arc<Self>, listener: TcpListener, id: InboundId) {
        let mut backoff_ms = 10u64;
        // What this inbound's `sockopt` asks of every connection it accepts.
        let accepted = self
            .state
            .load()
            .config
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| zero_net::AcceptedOptions {
                keepalive: inbound.sockopt.keepalive,
                user_timeout_ms: inbound.sockopt.user_timeout_ms,
                window_clamp: inbound.sockopt.window_clamp,
            })
            .unwrap_or_default();
        loop {
            match listener.accept().await {
                Ok((stream, peer)) => {
                    backoff_ms = 10;
                    let _ = stream.set_nodelay(true);
                    if !accepted.is_default() {
                        zero_net::apply_accepted(&stream, &accepted);
                    }
                    #[cfg(target_os = "linux")]
                    {
                        let _ = socket2::SockRef::from(&stream).set_quickack(true);
                    }
                    let me = Arc::clone(&self);
                    tokio::spawn(me.serve_tcp_connection(stream, peer, id));
                }
                // The connection died between SYN and accept: that is the
                // peer's problem, not the listener's, so do not slow down.
                Err(e)
                    if matches!(
                        e.kind(),
                        std::io::ErrorKind::ConnectionAborted
                            | std::io::ErrorKind::ConnectionReset
                            | std::io::ErrorKind::Interrupted
                            | std::io::ErrorKind::WouldBlock
                    ) =>
                {
                    debug!(error = %e, "accepted connection was already gone");
                }
                Err(e) => {
                    // Resource exhaustion (EMFILE/ENFILE/ENOBUFS) must not kill
                    // the listener or spin on it; back off and keep serving.
                    error!(error = %e, backoff_ms, "accept failed");
                    tokio::time::sleep(Duration::from_millis(backoff_ms)).await;
                    backoff_ms = (backoff_ms * 2).min(1000);
                }
            }
        }
    }

    /// Everything one accepted TCP connection goes through: security,
    /// transport, then the inbound protocol.
    async fn serve_tcp_connection(
        self: Arc<Self>,
        stream: tokio::net::TcpStream,
        peer: SocketAddr,
        id: InboundId,
    ) {
        let stats = Arc::clone(&self.stats);
        stats.accepted.fetch_add(1, Ordering::Relaxed);
        let _active = ActiveGuard::new(Arc::clone(&stats));
        let state = self.state.load_full();
        let index = id.0 as usize;
        let (Some(inbound), Some(compiled)) =
            (state.config.inbounds.get(index), state.inbounds.get(index))
        else {
            stats.failed.fetch_add(1, Ordering::Relaxed);
            return;
        };

        // A transparent inbound learns where the client was really going
        // before the stream is wrapped: it is a question for the socket.
        let original = match (&inbound.protocol, dokodemo_follow(inbound)) {
            (InboundProtocol::Dokodemo { .. }, zero_config::Tproxy::Tproxy) => {
                stream.local_addr().ok()
            }
            (InboundProtocol::Dokodemo { .. }, zero_config::Tproxy::Redirect) => {
                zero_net::transparent::original_destination(&stream, peer)
                    .ok()
                    // A client that connected to the port itself was not
                    // redirected; the "original" is then this very listener.
                    .filter(|found| Some(*found) != stream.local_addr().ok())
            }
            _ => None,
        };

        // Behind a load balancer the connection's own peer is the balancer;
        // the client's address is in the PROXY header it sent first.
        let peer = if inbound.accept_proxy_protocol {
            match timeout(handshake_timeout(), read_proxy_header(&stream)).await {
                Ok(Ok(header)) => header.source.unwrap_or(peer),
                Ok(Err(error)) => {
                    stats.failed.fetch_add(1, Ordering::Relaxed);
                    debug!(%peer, %error, "inbound PROXY protocol header refused");
                    return;
                }
                Err(_) => {
                    stats.failed.fetch_add(1, Ordering::Relaxed);
                    debug!(%peer, "inbound PROXY protocol header timed out");
                    return;
                }
            }
        } else {
            peer
        };

        let local = {
            let ip = inbound
                .listen
                .as_ip()
                .unwrap_or(std::net::IpAddr::V4(std::net::Ipv4Addr::UNSPECIFIED));
            Some(SocketAddr::new(ip, inbound.port))
        };
        // A client may hide its server name with an urgent byte
        // (`zero_evasion::urgent`); reading on past the mark keeps such a
        // hello from stalling here.
        let stream = zero_evasion::ReadPastMark::new(stream);
        let (secured, mut conn) = match timeout(
            handshake_timeout(),
            Self::secure_inbound(stream, &inbound.security, compiled, peer),
        )
        .await
        {
            Ok(Ok(Secured::Stream(stream, conn))) => (stream, conn),
            Ok(Ok(Secured::Fallback {
                stream,
                client_hello,
                failure,
            })) => {
                self.relay_reality_fallback(
                    stream,
                    client_hello,
                    failure,
                    peer,
                    local,
                    &inbound.security,
                )
                .await;
                return;
            }
            Ok(Err(error)) => {
                stats.failed.fetch_add(1, Ordering::Relaxed);
                debug!(%peer, %error, "inbound security handshake failed");
                return;
            }
            Err(_) => {
                stats.failed.fetch_add(1, Ordering::Relaxed);
                debug!(%peer, "inbound security handshake timed out");
                return;
            }
        };
        conn.local = local;
        conn.original = original;
        let secured: zero_core::BoxStream = match &compiled.raw_http_header {
            Some(config) => boxed(zero_transport::tcp_header::HttpHeaderStream::server(
                secured, config,
            )),
            None => secured,
        };
        let stream = match self.accept_transport(secured, inbound, compiled).await {
            Ok(Some((stream, more))) => {
                if let Some(more) = more {
                    Arc::clone(&self).serve_additional_streams(
                        more,
                        peer,
                        id,
                        Arc::clone(&state),
                        conn.clone(),
                    );
                }
                stream
            }
            // The request was folded into an existing split-XHTTP session.
            Ok(None) => return,
            Err(error) => {
                stats.failed.fetch_add(1, Ordering::Relaxed);
                debug!(%peer, %error, "inbound transport upgrade failed");
                return;
            }
        };
        if let Err(e) = self
            .handle(stream, peer, id, InboundSession { state, conn })
            .await
        {
            stats.failed.fetch_add(1, Ordering::Relaxed);
            debug!(%peer, error = %e, "session failed");
        }
    }

    /// Serve the further streams a multiplexing transport (gRPC) opens on a
    /// connection that is already established, each as its own session.
    fn serve_additional_streams(
        self: Arc<Self>,
        mut more: tokio::sync::mpsc::Receiver<zero_core::BoxStream>,
        peer: SocketAddr,
        id: InboundId,
        state: Arc<ServerState>,
        conn: ConnInfo,
    ) {
        tokio::spawn(async move {
            while let Some(stream) = more.recv().await {
                let this = Arc::clone(&self);
                let state = Arc::clone(&state);
                let conn = conn.clone();
                tokio::spawn(async move {
                    let stats = Arc::clone(&this.stats);
                    stats.accepted.fetch_add(1, Ordering::Relaxed);
                    let _active = ActiveGuard::new(Arc::clone(&stats));
                    if let Err(e) = this
                        .handle(stream, peer, id, InboundSession { state, conn })
                        .await
                    {
                        stats.failed.fetch_add(1, Ordering::Relaxed);
                        debug!(%peer, error = %e, "multiplexed session failed");
                    }
                });
            }
        });
    }

    /// Terminate the inbound's TLS or REALITY layer.
    ///
    /// `peer` is the address the connection came from, as the server sees it.
    /// It is only used for REALITY's `show` report.
    async fn secure_inbound(
        stream: InboundTcp,
        security: &zero_config::InboundSecurity,
        compiled: &InboundRuntime,
        peer: SocketAddr,
    ) -> Result<Secured, String> {
        match security {
            zero_config::InboundSecurity::None => {
                Ok(Secured::Stream(boxed(stream), ConnInfo::default()))
            }
            zero_config::InboundSecurity::Tls(_) => {
                let config = match &compiled.tls {
                    Some(Ok(config)) => Arc::clone(config),
                    Some(Err(error)) => {
                        return Err(format!("inbound TLS configuration failed: {error}"))
                    }
                    None => return Err("inbound TLS configuration is missing".into()),
                };
                zero_security::server::accept(stream, config)
                    .await
                    .map(|stream| {
                        let session = stream.get_ref().1;
                        let conn = ConnInfo {
                            server_name: session.server_name().map(Arc::from),
                            alpn: session.alpn_protocol().map(Arc::from),
                            original: None,
                            local: None,
                            direct: None,
                        };
                        Secured::Stream(boxed(stream), conn)
                    })
                    .map_err(|error| format!("inbound TLS handshake failed: {error}"))
            }
            zero_config::InboundSecurity::Reality(_) => {
                let params = compiled
                    .reality
                    .as_ref()
                    .ok_or_else(|| "inbound REALITY configuration is missing".to_string())?;
                match reality::handshake_or_fallback(stream, params, Some(peer)).await {
                    reality::HandshakeOutcome::Accepted(stream) => {
                        Ok(Secured::Stream(boxed(stream), ConnInfo::default()))
                    }
                    reality::HandshakeOutcome::Fallback {
                        stream,
                        client_hello,
                        failure,
                    } => Ok(Secured::Fallback {
                        stream,
                        client_hello,
                        failure: failure.to_string(),
                    }),
                    reality::HandshakeOutcome::Rejected(error) => {
                        Err(format!("inbound REALITY handshake failed: {error}"))
                    }
                }
            }
        }
    }

    /// Hand an unauthenticated REALITY client to the camouflage target, so a
    /// prober sees the real site. This relay is deliberately outside the
    /// handshake deadline: to the prober it is an ordinary long-lived session.
    async fn relay_reality_fallback(
        &self,
        stream: InboundTcp,
        client_hello: Vec<u8>,
        failure: String,
        peer: SocketAddr,
        local: Option<SocketAddr>,
        security: &zero_config::InboundSecurity,
    ) {
        let zero_config::InboundSecurity::Reality(reality) = security else {
            return;
        };
        // The target is a host and a port, or a unix socket path: Xray's
        // `type` decides which, and the fallback relay dials whichever it is
        // (`infra/conf/transport_internet.go:820-838`, `RL/tls.go:168`).
        let (destination, remote) = match reality.target.clone() {
            Some(zero_config::RealityTarget::Host(address, port)) => {
                let target = (address, port);
                let destination = Destination::tcp(target.0, target.1);
                let resolver = self.resolver();
                let remote = match outbound::connect_direct_with_resolver(
                    &destination,
                    &zero_config::StreamSettings::default(),
                    &resolver,
                )
                .await
                {
                    Ok(remote) => remote,
                    Err(error) => {
                        self.stats.failed.fetch_add(1, Ordering::Relaxed);
                        debug!(%peer, error = %error, "REALITY fallback target connection failed");
                        return;
                    }
                };
                (destination, remote)
            }
            Some(zero_config::RealityTarget::Unix(path)) => {
                let remote = match connect_unix(&path).await {
                    Ok(remote) => remote,
                    Err(error) => {
                        self.stats.failed.fetch_add(1, Ordering::Relaxed);
                        debug!(%peer, error = %error, "REALITY fallback target connection failed");
                        return;
                    }
                };
                (
                    Destination::tcp(Address::parse_host("localhost"), 0),
                    remote,
                )
            }
            None => {
                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                debug!(
                    %peer,
                    error = %failure,
                    "REALITY handshake rejected without a fallback target"
                );
                return;
            }
        };
        // What happens next — the PROXY header `xver` asks for, the hello the
        // handshake already consumed replayed to the target, the half-close
        // when the visitor stops talking, and the rate the visitor is held to —
        // is REALITY's, not this runtime's, so it lives in `reality::fallback`
        // where a server outside this runtime can reach it too. This function
        // keeps the two things that are the runtime's own: the dial (with the
        // resolver and its deadline) and the counters.
        let policy = reality::fallback::FallbackPolicy::new(
            reality.fallback_xver,
            fallback_limit(reality.fallback_limit_up),
            fallback_limit(reality.fallback_limit_down),
        );
        match reality::fallback::relay(stream, remote, &policy, &client_hello, Some(peer), local)
            .await
        {
            Ok(outcome) => {
                self.stats
                    .uploaded
                    .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
                self.stats
                    .downloaded
                    .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
                if outcome.is_useful() {
                    self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                } else {
                    self.stats.failed.fetch_add(1, Ordering::Relaxed);
                }
                debug!(
                    %peer,
                    target = %destination,
                    up = outcome.transferred.uploaded,
                    down = outcome.transferred.downloaded,
                    stage = ?outcome.stage,
                    error = ?outcome.error,
                    "REALITY fallback relay finished"
                );
            }
            Err(error) => {
                // Only the setup can fail this way — a header or a hello the
                // target would not take — which means the visitor got nothing
                // back at all.
                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                debug!(%peer, target = %destination, error = %error,
                       "REALITY fallback setup failed");
            }
        }
    }

    /// Complete the inbound transport. `Ok(None)` means the connection was
    /// consumed by an existing split-XHTTP session and has nothing left to
    /// serve on its own.
    async fn accept_transport(
        &self,
        secured: zero_core::BoxStream,
        inbound: &zero_config::Inbound,
        compiled: &InboundRuntime,
    ) -> Result<Option<AcceptedTransport>, String> {
        let transport = &inbound.transport;
        if matches!(transport, zero_config::Transport::Raw) {
            return Ok(Some((secured, None)));
        }
        let cfg = compiled
            .transport
            .as_ref()
            .ok_or_else(|| "inbound transport configuration is missing".to_string())?;
        // Split XHTTP legs carry the whole session inside their accept call,
        // so they cannot be bounded by the handshake deadline.
        if let zero_config::Transport::Xhttp(w) = transport {
            return self.accept_xhttp(secured, w, cfg).await;
        }
        let upgrade = async {
            match transport {
                zero_config::Transport::WebSocket(_) => {
                    zero_transport::ws::accept_server(secured, cfg)
                        .await
                        .map(|stream| (boxed(stream), None))
                        .map_err(|error| format!("WebSocket upgrade: {error}"))
                }
                zero_config::Transport::HttpUpgrade(_) => {
                    zero_transport::httpupgrade::accept(secured, cfg)
                        .await
                        .map(|stream| (stream, None))
                        .map_err(|error| format!("HTTPUpgrade: {error}"))
                }
                zero_config::Transport::Grpc(_) => zero_transport::grpc::accept_multi(secured, cfg)
                    .await
                    .map(|(first, more)| (first, Some(more)))
                    .map_err(|error| format!("gRPC upgrade: {error}")),
                zero_config::Transport::Raw | zero_config::Transport::Xhttp(_) => {
                    unreachable!("handled above")
                }
            }
        };
        within_handshake(upgrade).await?.map(Some)
    }

    async fn accept_xhttp(
        &self,
        secured: zero_core::BoxStream,
        w: &zero_config::WebSocketConfig,
        cfg: &zero_transport::ws::WsConfig,
    ) -> Result<Option<AcceptedTransport>, String> {
        use zero_transport::xhttp::{self, H2Server};
        if w.xhttp_http_version == zero_config::XhttpHttpVersion::Http2 {
            // One HTTP/2 connection carries many XHTTP requests; every
            // logical stream after the first is served alongside it.
            let server = match w.xhttp_mode {
                zero_config::XhttpMode::StreamUp => H2Server::StreamUp(Arc::clone(&self.xhttp_hub)),
                zero_config::XhttpMode::Auto | zero_config::XhttpMode::PacketUp => {
                    H2Server::PacketUp(Arc::clone(&self.xhttp_packet_hub))
                }
                zero_config::XhttpMode::StreamOne => H2Server::StreamOne,
            };
            return xhttp::accept_h2_multi(secured, cfg, server)
                .await
                .map(|accepted| accepted.map(|(first, more)| (first, Some(more))))
                .map_err(|error| format!("XHTTP HTTP/2: {error}"));
        }
        let stream = match w.xhttp_mode {
            zero_config::XhttpMode::StreamUp => {
                xhttp::accept_stream_up(secured, cfg, &self.xhttp_hub)
                    .await
                    .map_err(|error| format!("XHTTP split pairing: {error}"))?
            }
            zero_config::XhttpMode::Auto | zero_config::XhttpMode::PacketUp => {
                xhttp::accept_packet_up(secured, cfg, &self.xhttp_packet_hub)
                    .await
                    .map_err(|error| format!("XHTTP packet pairing: {error}"))?
            }
            zero_config::XhttpMode::StreamOne => Some(
                xhttp::accept(secured, cfg)
                    .await
                    .map_err(|error| format!("XHTTP upgrade: {error}"))?,
            ),
        };
        Ok(stream.map(|stream| (stream, None)))
    }

    async fn accept_h3_loop(self: Arc<Self>, endpoint: h3_quinn::quinn::Endpoint, id: InboundId) {
        while let Some(incoming) = endpoint.accept().await {
            // The QUIC handshake is awaited inside the connection's own task:
            // awaiting it here would let one slow or silent client hold up
            // every other connection waiting behind it in the accept queue.
            let me = Arc::clone(&self);
            tokio::spawn(async move {
                let connection = match timeout(handshake_timeout(), incoming).await {
                    Ok(Ok(connection)) => connection,
                    Ok(Err(error)) => {
                        debug!(%error, "HTTP/3 connection failed");
                        return;
                    }
                    Err(_) => {
                        debug!("HTTP/3 handshake timed out");
                        return;
                    }
                };
                let peer = connection.remote_address();
                let mut h3_connection = match timeout(
                    handshake_timeout(),
                    h3::server::Connection::new(h3_quinn::Connection::new(connection)),
                )
                .await
                {
                    Ok(Ok(connection)) => connection,
                    Ok(Err(error)) => {
                        debug!(%peer, %error, "HTTP/3 session setup failed");
                        return;
                    }
                    Err(_) => {
                        debug!(%peer, "HTTP/3 session setup timed out");
                        return;
                    }
                };
                loop {
                    let resolver = match h3_connection.accept().await {
                        Ok(Some(resolver)) => resolver,
                        Ok(None) => break,
                        Err(error) => {
                            debug!(%peer, %error, "HTTP/3 connection ended");
                            break;
                        }
                    };
                    let state = me.state.load_full();
                    let index = id.0 as usize;
                    let (Some(inbound), Some(compiled)) =
                        (state.config.inbounds.get(index), state.inbounds.get(index))
                    else {
                        me.stats.failed.fetch_add(1, Ordering::Relaxed);
                        break;
                    };
                    let (zero_config::Transport::Xhttp(settings), Some(cfg)) =
                        (&inbound.transport, compiled.transport.as_ref())
                    else {
                        me.stats.failed.fetch_add(1, Ordering::Relaxed);
                        break;
                    };
                    // Requests are resolved in arrival order: a packet-up GET
                    // must open its session before the POSTs that feed it are
                    // delivered. Only the resolved session is handed off.
                    let accepted = match settings.xhttp_mode {
                        zero_config::XhttpMode::StreamUp => {
                            zero_transport::xhttp::accept_stream_up_h3(resolver, cfg, &me.xhttp_hub)
                                .await
                        }
                        zero_config::XhttpMode::PacketUp => {
                            zero_transport::xhttp::accept_packet_up_h3(
                                resolver,
                                cfg,
                                &me.xhttp_packet_hub,
                            )
                            .await
                        }
                        _ => zero_transport::xhttp::accept_h3_request(resolver, cfg)
                            .await
                            .map(Some),
                    };
                    let stream = match accepted {
                        Ok(Some(stream)) => stream,
                        Ok(None) => continue,
                        Err(error) => {
                            me.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%error, "HTTP/3 request rejected");
                            continue;
                        }
                    };
                    me.stats.accepted.fetch_add(1, Ordering::Relaxed);
                    // HTTP/3 packet-up keeps the GET downlink open while POST
                    // packet requests arrive on the same QUIC connection.
                    // Handle each resolved request independently so one
                    // logical stream cannot block the connection's request
                    // accept loop.
                    let handler = Arc::clone(&me);
                    let stats = Arc::clone(&me.stats);
                    let session = InboundSession {
                        state: Arc::clone(&state),
                        conn: ConnInfo::default(),
                    };
                    tokio::spawn(async move {
                        let _active = ActiveGuard::new(Arc::clone(&stats));
                        if let Err(error) = handler.handle(stream, peer, id, session).await {
                            stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%peer, %error, "HTTP/3 session failed");
                        }
                    });
                }
            });
        }
    }

    async fn accept_hysteria2_loop(
        self: Arc<Self>,
        endpoint: h3_quinn::quinn::Endpoint,
        id: InboundId,
    ) {
        let mut acceptor = zero_transport::hysteria2::Acceptor::new(endpoint);
        // The website a visitor without credentials sees, from the
        // configuration this inbound started with.
        if let Some(InboundProtocol::Hysteria2(config)) = self
            .state
            .load()
            .config
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| &inbound.protocol)
        {
            if let Some(masquerade) = config.masquerade.as_ref().map(hysteria_masquerade) {
                acceptor = acceptor.with_masquerade(masquerade);
            }
        }
        // Rebuilt only when the configuration changes, not per stream.
        #[allow(clippy::type_complexity)]
        let mut passwords: Option<(Arc<RuntimeConfig>, Arc<[Box<str>]>)> = None;
        loop {
            let state = self.state.load_full();
            let Some(inbound) = state.config.inbounds.get(id.0 as usize) else {
                return;
            };
            let InboundProtocol::Hysteria2(config) = &inbound.protocol else {
                return;
            };
            if !passwords
                .as_ref()
                .is_some_and(|(seen, _)| Arc::ptr_eq(seen, &state.config))
            {
                passwords = Some((Arc::clone(&state.config), config.passwords.clone().into()));
            }
            let current = &passwords.as_ref().expect("set above").1;
            let accepted = match acceptor.accept(current).await {
                Ok(Some(value)) => value,
                Ok(None) => return,
                Err(error) => {
                    self.stats.failed.fetch_add(1, Ordering::Relaxed);
                    debug!(%error, "Hysteria2 connection rejected");
                    continue;
                }
            };
            let tag = inbound.tag.clone();
            let me = Arc::clone(&self);
            tokio::spawn(async move {
                match accepted {
                    zero_transport::hysteria2::Accepted::Tcp {
                        stream,
                        destination,
                        peer,
                        password,
                    } => {
                        me.stats.accepted.fetch_add(1, Ordering::Relaxed);
                        // Accepted here means the QUIC layer already
                        // authenticated the client, so it counts as a user.
                        let _usage = me.stats.usage.open(&tag, peer.ip());
                        let failed_tag = Arc::clone(&tag);
                        let result = match me.password_account(id, &password) {
                            Ok(email) => {
                                let stream =
                                    me.meter_account(email.as_ref(), &tag, peer, stream, 0);
                                Arc::clone(&me)
                                    .handle_hysteria2(stream, peer, id, tag, destination, email)
                                    .await
                            }
                            Err(error) => Err(error),
                        };
                        if let Err(error) = result {
                            me.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%error, "Hysteria2 session failed");
                            me.stats.report_failure(&failed_tag, &error);
                        }
                    }
                    zero_transport::hysteria2::Accepted::Udp {
                        connection,
                        session_id,
                        packet_id,
                        destination,
                        payload,
                        peer,
                        password,
                    } => {
                        me.stats.accepted.fetch_add(1, Ordering::Relaxed);
                        // Accepted here means the QUIC layer already
                        // authenticated the client, so it counts as a user.
                        let _usage = me.stats.usage.open(&tag, peer.ip());
                        let failed_tag = Arc::clone(&tag);
                        let result = match me.password_account(id, &password) {
                            Ok(email) => {
                                Arc::clone(&me)
                                    .handle_hysteria2_udp(
                                        Hysteria2UdpSession {
                                            connection,
                                            session_id,
                                            packet_id,
                                            peer,
                                            destination,
                                            payload,
                                        },
                                        id,
                                        tag,
                                        email,
                                    )
                                    .await
                            }
                            Err(error) => Err(error),
                        };
                        if let Err(error) = result {
                            me.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%error, "Hysteria2 UDP session failed");
                            me.stats.report_failure(&failed_tag, &error);
                        }
                    }
                }
            });
        }
    }

    async fn accept_tuic_loop(self: Arc<Self>, endpoint: h3_quinn::quinn::Endpoint, id: InboundId) {
        let mut acceptor = zero_transport::tuic::Acceptor::new(endpoint);
        // Rebuilt only when the configuration changes, not per request.
        #[allow(clippy::type_complexity)]
        let mut users: Option<(Arc<RuntimeConfig>, Arc<[([u8; 16], Box<str>)]>)> = None;
        loop {
            let state = self.state.load_full();
            let Some(inbound) = state.config.inbounds.get(id.0 as usize) else {
                return;
            };
            let InboundProtocol::Tuic(config) = &inbound.protocol else {
                return;
            };
            if !users
                .as_ref()
                .is_some_and(|(seen, _)| Arc::ptr_eq(seen, &state.config))
            {
                let list: Vec<([u8; 16], Box<str>)> = config
                    .users
                    .iter()
                    .map(|user| (user.uuid, user.password.clone()))
                    .collect();
                users = Some((Arc::clone(&state.config), list.into()));
            }
            let current = &users.as_ref().expect("set above").1;
            let accepted = match acceptor.accept(current).await {
                Ok(Some(value)) => value,
                Ok(None) => return,
                Err(error) => {
                    self.stats.failed.fetch_add(1, Ordering::Relaxed);
                    debug!(%error, "TUIC connection rejected");
                    continue;
                }
            };
            let tag = inbound.tag.clone();
            let me = Arc::clone(&self);
            tokio::spawn(async move {
                match accepted {
                    zero_transport::tuic::Accepted::Tcp {
                        stream,
                        destination,
                        peer,
                        uuid,
                    } => {
                        me.stats.accepted.fetch_add(1, Ordering::Relaxed);
                        // Accepted here means the QUIC layer already
                        // authenticated the client, so it counts as a user.
                        let _usage = me.stats.usage.open(&tag, peer.ip());
                        let failed_tag = Arc::clone(&tag);
                        let result = match me.tuic_account(id, &uuid) {
                            Ok(email) => {
                                let stream =
                                    me.meter_account(email.as_ref(), &tag, peer, stream, 0);
                                Arc::clone(&me)
                                    .handle_hysteria2(stream, peer, id, tag, destination, email)
                                    .await
                            }
                            Err(error) => Err(error),
                        };
                        if let Err(error) = result {
                            me.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%error, "TUIC session failed");
                            me.stats.report_failure(&failed_tag, &error);
                        }
                    }
                    zero_transport::tuic::Accepted::Udp {
                        connection,
                        association,
                        packet,
                        destination,
                        payload,
                        peer,
                        uuid,
                    } => {
                        me.stats.accepted.fetch_add(1, Ordering::Relaxed);
                        // Accepted here means the QUIC layer already
                        // authenticated the client, so it counts as a user.
                        let _usage = me.stats.usage.open(&tag, peer.ip());
                        let failed_tag = Arc::clone(&tag);
                        let result = match me.tuic_account(id, &uuid) {
                            Ok(email) => {
                                Arc::clone(&me)
                                    .handle_tuic_udp(
                                        connection,
                                        association,
                                        packet,
                                        peer,
                                        destination,
                                        payload,
                                        id,
                                        tag,
                                        email,
                                    )
                                    .await
                            }
                            Err(error) => Err(error),
                        };
                        if let Err(error) = result {
                            me.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%error, "TUIC UDP session failed");
                            me.stats.report_failure(&failed_tag, &error);
                        }
                    }
                }
            });
        }
    }

    fn config(&self) -> Arc<RuntimeConfig> {
        Arc::clone(&self.state.load_full().config)
    }

    /// The configuration being served now.
    pub fn config_snapshot(&self) -> Arc<RuntimeConfig> {
        self.config()
    }

    /// The account a QUIC connection of the Hysteria2 inbound `id` logged in
    /// as with `password`, checked against the current accounts: the
    /// connection may have outlived its account, and must then open nothing.
    fn password_account(&self, id: InboundId, password: &str) -> Result<Option<Arc<str>>, String> {
        let state = self.state.load();
        let Some(InboundProtocol::Hysteria2(config)) = state
            .config
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| &inbound.protocol)
        else {
            return Err("the Hysteria2 inbound is gone".into());
        };
        let index = config
            .passwords
            .iter()
            .position(|candidate| &**candidate == password)
            .ok_or_else(|| "the Hysteria2 account is no longer authorised".to_string())?;
        Ok(config.emails.get(index).cloned().flatten())
    }

    /// [`Server::password_account`] for a TUIC connection's `uuid`.
    fn tuic_account(&self, id: InboundId, uuid: &[u8; 16]) -> Result<Option<Arc<str>>, String> {
        let state = self.state.load();
        let Some(InboundProtocol::Tuic(config)) = state
            .config
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| &inbound.protocol)
        else {
            return Err("the TUIC inbound is gone".into());
        };
        config
            .users
            .iter()
            .find(|user| &user.uuid == uuid)
            .map(|user| user.email.clone())
            .ok_or_else(|| "the TUIC account is no longer authorised".to_string())
    }

    #[cfg(test)]
    pub(crate) fn config_for_tests(&self) -> Arc<RuntimeConfig> {
        self.config()
    }

    /// Read `client`, in the shape of an entry of `settings.clients`, as an
    /// account for the inbound tagged `tag`, ready for [`Server::add_accounts`].
    pub fn parse_account(
        &self,
        tag: &str,
        client: &serde_json::Value,
    ) -> Result<zero_config::InboundClient, String> {
        let state = self.state.load();
        let inbound = state
            .config
            .inbounds
            .iter()
            .find(|inbound| &*inbound.tag == tag)
            .ok_or_else(|| format!("there is no inbound tagged {tag:?}"))?;
        match &inbound.protocol {
            InboundProtocol::Shadowsocks(ss) => {
                zero_config::parse_shadowsocks_client(ss.method, client)
            }
            protocol => zero_config::parse_inbound_client(protocol.kind(), client),
        }
    }

    /// The protocol of the inbound tagged `tag` (`"vless"`, …), if there is one.
    pub fn inbound_kind(&self, tag: &str) -> Option<&'static str> {
        self.state
            .load()
            .config
            .inbounds
            .iter()
            .find(|inbound| &*inbound.tag == tag)
            .map(|inbound| inbound.protocol.kind())
    }

    async fn restore_fake_destination(&self, destination: &Destination) -> Destination {
        let Some(ip) = destination.address.as_ip() else {
            return destination.clone();
        };
        let Some(domain) = self.client_resolver().reverse_fake(ip).await else {
            return destination.clone();
        };
        let mut restored = destination.clone();
        restored.address = Address::domain(domain);
        restored
    }

    /// What the inbound with this id asks the sniffer for, in the shape the
    /// UDP relay wants. An inbound that has gone from its generation sniffs
    /// nothing.
    fn sniff_policy(&self, id: InboundId) -> SniffPolicy {
        self.config()
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| SniffPolicy::from(&inbound.sniffing))
            .unwrap_or_default()
    }

    /// A session for a connection `peer` made to inbound `id`.
    ///
    /// `local` is the inbound's own address as configured (a wildcard bind
    /// has no single address, so only the port is known then); it is what
    /// `localIP` and `localPort` routing rules are matched against.
    /// The client stream of an authenticated account, metered for it
    /// ([`crate::accounts`]); an account with no `email` is passed through.
    /// `early_payload` is what the handshake already read past the request
    /// header, which reaches the relay without passing through the meter.
    /// Whether a datagram of `email` passes its speed limit, counted if so
    /// (see [`crate::accounts::Accounts::admit`]). One without an account
    /// always passes.
    fn admit_datagram(&self, email: Option<&Arc<str>>, uplink: usize, downlink: usize) -> bool {
        email.is_none_or(|email| self.stats.accounts.admit(email, uplink, downlink))
    }

    fn meter_account(
        &self,
        email: Option<&Arc<str>>,
        tag: &Arc<str>,
        peer: SocketAddr,
        stream: zero_core::BoxStream,
        early_payload: usize,
    ) -> zero_core::BoxStream {
        match email {
            Some(email) => boxed(
                self.stats
                    .accounts
                    .meter(email, tag, peer.ip(), stream)
                    .with_early_payload(early_payload),
            ),
            None => stream,
        }
    }

    fn new_context(
        &self,
        id: InboundId,
        tag: Arc<str>,
        destination: Destination,
        peer: SocketAddr,
    ) -> SessionContext {
        let state = self.state.load();
        let mut ctx = SessionContext::new(state.generation, id, tag, destination).with_source(peer);
        ctx.local = state.config.inbounds.get(id.0 as usize).map(|inbound| {
            let ip = inbound
                .listen
                .as_ip()
                .unwrap_or(std::net::IpAddr::V4(std::net::Ipv4Addr::UNSPECIFIED));
            SocketAddr::new(ip, inbound.port)
        });
        ctx
    }

    /// What inbound `id` of the running generation asks to sniff.
    fn sniffing_of(&self, id: InboundId) -> Sniffing {
        self.state
            .load()
            .config
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| inbound.sniffing.clone())
            .unwrap_or_default()
    }

    /// Where `decision` sends a session, and the connection there. `None`
    /// when the session is blocked (a block rule, or a black-hole outbound).
    /// The tag of the outbound that carried it comes back too, so the caller
    /// can report how it went; a direct-via-resolver connection has none.
    ///
    /// This is the one place server-side inbounds (VLESS, Trojan, VMess,
    /// Shadowsocks, AnyTLS, Hysteria 2) turn a verdict into a connection, so
    /// they share failover between a balancer's members with the proxy
    /// inbounds.
    async fn connect_decided(
        &self,
        decision: Decision,
        destination: &Destination,
        client: Option<SocketAddr>,
    ) -> Result<Option<(Option<Arc<str>>, zero_core::BoxStream)>, String> {
        let connect = self.connect_decided_for(decision, destination);
        match client {
            Some(client) => outbound::with_client_addr(client, connect).await,
            None => connect.await,
        }
    }

    async fn connect_decided_for(
        &self,
        decision: Decision,
        destination: &Destination,
    ) -> Result<Option<(Option<Arc<str>>, zero_core::BoxStream)>, String> {
        match decision {
            Decision::Block => {
                self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                Ok(None)
            }
            Decision::DirectVia { resolver } => {
                let resolver = self.resolver().for_tag(&resolver);
                outbound::connect_direct_with_resolver(
                    destination,
                    &zero_config::StreamSettings::default(),
                    &resolver,
                )
                .await
                .map(|stream| Some((None, stream)))
                .map_err(|error| error.to_string())
            }
            Decision::Outbound(tag) | Decision::Balancer(tag) => {
                match self.connect_balanced(&tag, destination).await? {
                    Some((outbound, stream)) => Ok(Some((Some(outbound.tag), stream))),
                    None => {
                        self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                        Ok(None)
                    }
                }
            }
        }
    }

    /// Read the first bytes the client sends, when its inbound sniffs, and
    /// let them inform `ctx` (and rewrite `destination` to the sniffed name,
    /// unless the inbound is `routeOnly` or the name is excluded). The bytes
    /// are put back in front of the stream, so the destination sees them.
    ///
    /// Nothing is read when sniffing is off, so a server-speaks-first
    /// protocol pays no wait. BitTorrent is recognised from the first bytes
    /// on any destination; names are only taken for a bare address, because
    /// a destination the client already named needs no help.
    async fn sniff_client(
        &self,
        ctx: &mut SessionContext,
        destination: &mut Destination,
        client: zero_core::BoxStream,
        sniffing: &Sniffing,
    ) -> zero_core::BoxStream {
        if !sniffing.enabled {
            return client;
        }
        let mut client = client;
        let probe = sniff_probe(&mut client).await;
        let mut sniffed = sniffing.inspect(&probe);
        if let Some(domain) = sniffed.domain.as_deref() {
            if sniffing.excludes(domain) {
                // An excluded name keeps its protocol label but never
                // steers the connection.
                sniffed.domain = None;
            }
        }
        if sniffed.domain.is_some() || sniffed.protocol.is_some() {
            ctx.apply_sniff(sniffed, !sniffing.route_only);
            *destination = ctx.destination.clone();
        }
        if probe.is_empty() {
            client
        } else {
            boxed(ChainedStream::new(probe, client))
        }
    }

    fn router(&self) -> Arc<Router> {
        Arc::clone(&self.state.load_full().router)
    }

    /// The resolver for the runtime's own connections: never FakeDNS.
    fn resolver(&self) -> Arc<zero_dns::Resolver> {
        Arc::clone(&self.state.load_full().resolver)
    }

    /// The resolver that answers applications, FakeDNS included.
    fn client_resolver(&self) -> Arc<zero_dns::Resolver> {
        Arc::clone(&self.state.load_full().client_resolver)
    }

    fn generation(&self) -> GenerationId {
        self.state.load().generation
    }

    pub fn current_generation(&self) -> GenerationId {
        self.generation()
    }

    /// One session of an inbound. It is counted in the usage figures from the
    /// moment it is first routed, which is after the protocol authenticated it
    /// (see [`crate::usage::PendingSession`]).
    async fn handle(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        session: InboundSession,
    ) -> Result<(), String> {
        let Some(tag) = session
            .state
            .config
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| inbound.tag.clone())
        else {
            return Err("inbound disappeared from its own generation".into());
        };
        let pending = crate::usage::PendingSession::new(&self.stats.usage, &tag, peer.ip());
        // Boxed: the session future is large, and holding it in this frame
        // as well would double the stack a chain of dialers needs in debug builds.
        let stats = Arc::clone(&self.stats);
        let result = crate::usage::scope(
            pending,
            Box::pin(self.handle_session(stream, peer, id, session)),
        )
        .await;
        if let Err(error) = &result {
            stats.report_failure(&tag, error);
        }
        result
    }

    async fn handle_session(
        self: Arc<Self>,
        mut stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        session: InboundSession,
    ) -> Result<(), String> {
        let Some(inbound) = session.state.config.inbounds.get(id.0 as usize) else {
            return Err("inbound disappeared from its own generation".into());
        };
        let tag = inbound.tag.clone();
        let sniffing = &inbound.sniffing;
        match &inbound.protocol {
            InboundProtocol::Vless(config) => {
                // VLESS Encryption wraps the whole VLESS exchange, request
                // header included, so it is undone first.
                let mut direct = None;
                let stream = match session
                    .state
                    .inbounds
                    .get(id.0 as usize)
                    .and_then(|compiled| compiled.vless_encryption.as_ref())
                {
                    None => stream,
                    Some(Err(error)) => return Err(error.clone()),
                    Some(Ok(server)) => {
                        let encrypted = within_handshake(server.handshake(stream))
                            .await?
                            .map_err(|error| format!("VLESS Encryption handshake: {error}"))?;
                        direct = Some(encrypted.direct_flag());
                        boxed(encrypted)
                    }
                };
                let mut conn = session.conn.clone();
                conn.direct = direct;
                return self
                    .handle_vless(stream, peer, id, tag, config, &conn)
                    .await;
            }
            InboundProtocol::Trojan(config) => {
                return self
                    .handle_trojan(stream, peer, id, tag, config, &session.conn)
                    .await;
            }
            InboundProtocol::Vmess(config) => {
                return self.handle_vmess(stream, peer, id, tag, config).await;
            }
            InboundProtocol::Shadowsocks(config) => {
                let users = session
                    .state
                    .inbounds
                    .get(id.0 as usize)
                    .and_then(|compiled| compiled.shadowsocks_users.clone());
                return self
                    .handle_shadowsocks(stream, peer, id, tag, config, users)
                    .await;
            }
            InboundProtocol::AnyTls(config) => {
                return self.handle_anytls(stream, peer, id, tag, config).await;
            }
            InboundProtocol::Tide(_) => {
                let tide = session
                    .state
                    .inbounds
                    .get(id.0 as usize)
                    .and_then(|compiled| compiled.tide.clone())
                    .ok_or_else(|| "inbound Tide configuration is missing".to_string())?;
                // The streams of a Tide session have no one peer, so the
                // usage figures count its connection. Behind REALITY that
                // connection is already a proven client; behind a plain
                // certificate any prober reaches this point, so it is not
                // counted there.
                if matches!(inbound.security, zero_config::InboundSecurity::Reality(_)) {
                    crate::usage::confirm_current();
                }
                return self.handle_tide(stream, id, tag, tide).await;
            }
            InboundProtocol::TideRelay(_) => {
                let relay = session
                    .state
                    .inbounds
                    .get(id.0 as usize)
                    .and_then(|compiled| compiled.tide_relay.clone())
                    .ok_or_else(|| "inbound Tide relay configuration is missing".to_string())?;
                return relay
                    .serve_connection(stream)
                    .await
                    .map_err(|error| format!("Tide relay connection: {error}"));
            }
            InboundProtocol::Dokodemo { tcp: true, .. } => {
                let Some(destination) = inbound.dokodemo_destination(session.conn.original) else {
                    return Err("no destination: the connection was not redirected".into());
                };
                return self
                    .handle_dokodemo_tcp(stream, peer, id, tag, destination)
                    .await;
            }
            _ => {}
        }

        let socks_auth = &inbound.socks_auth;
        let (mut accepted, mut stream): (Accepted, zero_core::BoxStream) =
            within_handshake(async move {
                let mut first = [0u8; 1];
                let n = stream
                    .read(&mut first)
                    .await
                    .map_err(|e| format!("reading first byte: {e}"))?;
                if n == 0 {
                    return Err("client closed before sending anything".to_string());
                }
                match socks::detect(first[0]) {
                    InboundKind::Socks5 => {
                        // The greeting's first byte was consumed by detection,
                        // so replay it into a chained reader.
                        let mut chained = ChainedStream::new(first.to_vec(), stream);
                        let credentials = match socks_auth {
                            zero_config::SocksAuth::None => Vec::new(),
                            zero_config::SocksAuth::Password(accounts) => accounts
                                .iter()
                                .map(|account| zero_protocol::socks::Credential {
                                    username: account.username.clone(),
                                    password: account.password.clone(),
                                })
                                .collect(),
                        };
                        let accepted =
                            socks::accept_socks5_with_credentials(&mut chained, &credentials)
                                .await?;
                        Ok((accepted, boxed(chained)))
                    }
                    _ => {
                        // The HTTP path needs the same credentials as the
                        // SOCKS5 one. An `http` inbound configured with
                        // accounts was previously ignored here, so the
                        // accounts protected nothing.
                        let http_credentials: Vec<zero_protocol::socks::Credential> =
                            match socks_auth {
                                zero_config::SocksAuth::None => Vec::new(),
                                zero_config::SocksAuth::Password(accounts) => accounts
                                    .iter()
                                    .map(|account| zero_protocol::socks::Credential {
                                        username: account.username.clone(),
                                        password: account.password.clone(),
                                    })
                                    .collect(),
                            };
                        let accepted = socks::accept_http_with_credentials(
                            &mut stream,
                            first[0],
                            &http_credentials,
                        )
                        .await?;
                        Ok((accepted, stream))
                    }
                }
            })
            .await??;

        // FakeDNS addresses are local handles for domains. Restore the name
        // before routing and proxying so synthetic addresses never cross the
        // process boundary and domain rules still match.
        accepted.destination = self.restore_fake_destination(&accepted.destination).await;

        if accepted.destination.network == Network::Udp {
            return self.handle_udp_association(stream, peer, id, tag).await;
        }

        // A client that only knows an IP address sends nothing until the
        // proxy has answered, so the sniff below would always time out. Answer
        // first, as Xray does; a refused or failed dial then closes the
        // connection instead of reporting the error in the reply.
        let replied = sniffing.enabled
            && accepted.destination.network == Network::Tcp
            && accepted.destination.address.is_ip()
            && matches!(
                accepted.kind,
                InboundKind::Socks5 | InboundKind::HttpConnect
            );
        if replied {
            self.finish_handshake(&mut stream, &accepted, true, false)
                .await;
        }

        let mut prefetched = Vec::new();
        let mut probe = accepted.prefix.clone();
        if sniffing.enabled && accepted.destination.network == Network::Tcp {
            let mut extra = vec![0u8; 8192usize.saturating_sub(probe.len())];
            if !extra.is_empty() {
                if let Ok(Ok(read)) =
                    timeout(Duration::from_millis(50), stream.read(&mut extra)).await
                {
                    extra.truncate(read);
                    probe.extend_from_slice(&extra);
                    prefetched = extra;
                }
            }
        }

        let mut ctx = self.new_context(id, tag, accepted.destination.clone(), peer);
        if sniffing.enabled {
            let sniffed = sniffing.inspect(&probe);
            if sniffed.domain.is_some() || sniffed.protocol.is_some() {
                ctx.apply_sniff(sniffed, !sniffing.route_only);
                accepted.destination = ctx.destination.clone();
            }
        }

        let decision = self.route(&ctx).await;
        debug!(dest = %ctx.destination, ?decision, "routed");

        match decision {
            Decision::Block => {
                self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                self.finish_handshake(&mut stream, &accepted, false, replied)
                    .await;
                Ok(())
            }
            Decision::Outbound(tag) | Decision::Balancer(tag) => {
                ctx.outbound = None;
                let connected = outbound::with_client_addr(
                    peer,
                    self.connect_balanced(&tag, &accepted.destination),
                )
                .await;
                let connected = match connected {
                    Ok(connected) => connected,
                    Err(error) => {
                        self.finish_unreachable(&mut stream, &accepted, replied)
                            .await;
                        return Err(error);
                    }
                };
                let Some((ob, remote)) = connected else {
                    self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                    self.finish_handshake(&mut stream, &accepted, false, replied)
                        .await;
                    return Ok(());
                };

                self.finish_handshake(&mut stream, &accepted, true, replied)
                    .await;

                let mut remote = remote;
                if !accepted.prefix.is_empty() {
                    remote
                        .write_all(&accepted.prefix)
                        .await
                        .map_err(|e| format!("replaying request prefix: {e}"))?;
                }

                let client = if prefetched.is_empty() {
                    boxed(stream)
                } else {
                    boxed(ChainedStream::new(prefetched, stream))
                };
                let outcome = relay(client, remote).await;
                self.record_outbound_observation(&ob.tag, &outcome);
                self.record_observation(&outcome).await;
                self.stats.record_tag_traffic(
                    &ctx.inbound_tag,
                    Some(&ob.tag),
                    &outcome.transferred,
                );
                self.stats
                    .uploaded
                    .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
                self.stats
                    .downloaded
                    .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
                if outcome.is_useful() {
                    self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                } else {
                    self.stats.failed.fetch_add(1, Ordering::Relaxed);
                }
                debug!(
                    dest = %accepted.destination,
                    up = outcome.transferred.uploaded,
                    down = outcome.transferred.downloaded,
                    stage = ?outcome.stage,
                    error = ?outcome.error,
                    "session finished"
                );
                Ok(())
            }
            Decision::DirectVia { resolver } => {
                let resolver = self.resolver().for_tag(&resolver);
                let remote = match outbound::connect_direct_with_resolver(
                    &accepted.destination,
                    &zero_config::StreamSettings::default(),
                    &resolver,
                )
                .await
                {
                    Ok(remote) => remote,
                    Err(error) => {
                        self.finish_unreachable(&mut stream, &accepted, replied)
                            .await;
                        return Err(error.to_string());
                    }
                };
                self.finish_handshake(&mut stream, &accepted, true, replied)
                    .await;
                let mut remote = remote;
                if !accepted.prefix.is_empty() {
                    remote
                        .write_all(&accepted.prefix)
                        .await
                        .map_err(|e| format!("replaying request prefix: {e}"))?;
                }
                let client = if prefetched.is_empty() {
                    boxed(stream)
                } else {
                    boxed(ChainedStream::new(prefetched, stream))
                };
                let outcome = relay(client, remote).await;
                self.record_observation(&outcome).await;
                self.stats
                    .record_tag_traffic(&ctx.inbound_tag, None, &outcome.transferred);
                self.stats
                    .uploaded
                    .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
                self.stats
                    .downloaded
                    .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
                if outcome.is_useful() {
                    self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                } else {
                    self.stats.failed.fetch_add(1, Ordering::Relaxed);
                }
                Ok(())
            }
        }
    }

    async fn handle_udp_association(
        self: Arc<Self>,
        mut control: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
    ) -> Result<(), String> {
        let socket = UdpSocket::bind("0.0.0.0:0")
            .await
            .map_err(|e| format!("binding SOCKS5 UDP association: {e}"))?;
        let bound = socket
            .local_addr()
            .map_err(|e| format!("reading SOCKS5 UDP association address: {e}"))?;
        socks::reply(
            &mut control,
            socks::REP_SUCCESS,
            Some(Destination::udp(Address::Ip(bound.ip()), bound.port())),
        )
        .await
        .map_err(|e| format!("sending SOCKS5 UDP association reply: {e}"))?;

        // The association belongs to the control connection's host, and to
        // the first address that uses it from there; replies go to wherever
        // that client last sent from.
        let mut client: Option<SocketAddr> = None;
        let (mut udp, mut replies) =
            UdpRelay::<()>::new(Arc::clone(&self), id, tag, 64, self.sniff_policy(id));
        let mut control_byte = [0u8; 1];
        let mut packet = vec![0u8; 65_535];
        loop {
            tokio::select! {
                result = control.read(&mut control_byte) => {
                    let n = result.map_err(|e| format!("reading SOCKS5 UDP control connection: {e}"))?;
                    if n == 0 {
                        return Ok(());
                    }
                    return Err("SOCKS5 UDP control connection sent unexpected data".into());
                }
                result = socket.recv_from(&mut packet) => {
                    let (len, source) = match result {
                        Ok(value) => value,
                        // An ICMP error for an earlier reply; not fatal.
                        Err(error) if matches!(
                            error.kind(),
                            std::io::ErrorKind::ConnectionReset | std::io::ErrorKind::ConnectionRefused
                        ) => continue,
                        Err(error) => return Err(format!("receiving SOCKS5 UDP datagram: {error}")),
                    };
                    if source.ip() != peer.ip()
                        || client.is_some_and(|client| client.ip() != source.ip())
                    {
                        continue;
                    }
                    client = Some(source);
                    let parsed = match socks::parse_udp_datagram(&packet[..len]) {
                        Ok(parsed) => parsed,
                        Err(error) => {
                            debug!(%source, %error, "discarding malformed SOCKS5 UDP datagram");
                            continue;
                        }
                    };
                    udp.dispatch((), source, parsed.destination, parsed.payload).await;
                }
                Some(reply) = replies.recv() => {
                    let Some(client) = client else { continue };
                    let encoded = match socks::encode_udp_datagram(&reply.source, &reply.payload) {
                        Ok(encoded) => encoded,
                        Err(error) => {
                            debug!(%error, "SOCKS5 UDP reply cannot be framed; dropped");
                            continue;
                        }
                    };
                    match socket.send_to(&encoded, client).await {
                        Ok(_) => {
                            self.stats
                                .downloaded
                                .fetch_add(reply.payload.len() as u64, Ordering::Relaxed);
                            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                        }
                        Err(error) => debug!(%client, %error, "sending SOCKS5 UDP reply failed"),
                    }
                }
            }
        }
    }

    /// Whether TUN inbound `id` was given IPv4 addresses only, which is how a
    /// client says IPv6 is off. The phone (or the OS) may still send IPv6
    /// packets into the tunnel so none can leave around it; those flows have
    /// nowhere to go and must fail fast. An inbound with no addresses listed
    /// (a host-provided interface) is not judged.
    fn tun_is_ipv4_only(&self, id: InboundId) -> bool {
        match self
            .config()
            .inbounds
            .get(id.0 as usize)
            .map(|i| &i.protocol)
        {
            Some(InboundProtocol::Tun(tun)) => {
                !tun.addresses.is_empty() && !tun.addresses.iter().any(|a| a.contains(':'))
            }
            _ => false,
        }
    }

    async fn handle_dokodemo_tcp(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        target: (Address, u16),
    ) -> Result<(), String> {
        // IPv6 is off: close at once instead of sending the flow to a server
        // that may not reach IPv6 either. An app that tries IPv6 first (Telegram
        // does) then falls back to IPv4 immediately, not after its own timeout.
        if matches!(target.0, Address::Ip(std::net::IpAddr::V6(_))) && self.tun_is_ipv4_only(id) {
            return Ok(());
        }
        // The netstack hands over the address the application dialled. For a
        // FakeDNS answer that is a local handle, so restore the name first;
        // sniffing then names connections that only knew a real IP.
        let destination = self
            .restore_fake_destination(&Destination::tcp(target.0, target.1))
            .await;
        let sniffing = self
            .config()
            .inbounds
            .get(id.0 as usize)
            .map(|inbound| inbound.sniffing.clone())
            .unwrap_or_default();
        let mut stream = stream;
        let mut prefetched = Vec::new();
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        if sniffing.enabled && destination.address.is_ip() {
            prefetched = sniff_probe(&mut stream).await;
            let sniffed = sniffing.inspect(&prefetched);
            if sniffed.domain.is_some() || sniffed.protocol.is_some() {
                // The name is for routing only. A flow to a bare IP belongs to
                // an application that chose that address itself (its own DNS,
                // a pinned edge, a server that only answers there), and
                // sending it to whatever the name resolves to on our side
                // breaks exactly those apps.
                ctx.apply_sniff(sniffed, false);
            }
        }
        let mut destination = ctx.destination.clone();
        let stream: zero_core::BoxStream = if prefetched.is_empty() {
            stream
        } else {
            boxed(ChainedStream::new(prefetched, stream))
        };
        let decision = self.route(&ctx).await;
        // The one place the name does replace the address: a sanctioned
        // service. The address the application holds is then a relay's (the
        // anti-sanction resolver answered its DNS query), which only means
        // something when reached from here, so whichever way the flow goes -
        // through that resolver's relay or through the tunnel - it has to be
        // dialled by name.
        if let Some(domain) = ctx.sniffed.domain.as_deref() {
            if destination.address.is_ip()
                && matches!(self.router().route(&ctx, None), Decision::DirectVia { .. })
            {
                destination = Destination::tcp(Address::domain(domain), destination.port);
            }
        }
        let mut health_tag = None;
        let remote = match decision {
            Decision::Block => {
                self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                return Ok(());
            }
            Decision::DirectVia { resolver } => {
                let resolver = self.resolver().for_tag(&resolver);
                outbound::connect_direct_with_resolver(
                    &destination,
                    &zero_config::StreamSettings::default(),
                    &resolver,
                )
                .await
                .map_err(|error| error.to_string())?
            }
            Decision::Outbound(outbound_tag) | Decision::Balancer(outbound_tag) => {
                // The same failover the proxy inbounds have: a member that
                // cannot be reached is noted and the next one tried, so a
                // VPN's sessions do not all go to the one that is broken.
                let Some((outbound, stream)) = outbound::with_client_addr(
                    peer,
                    self.connect_balanced(&outbound_tag, &destination),
                )
                .await?
                else {
                    self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                    return Ok(());
                };
                health_tag = Some(outbound.tag.clone());
                stream
            }
        };
        let outcome = relay(stream, remote).await;
        if let Some(tag) = health_tag {
            self.record_outbound_observation(&tag, &outcome);
        }
        self.record_observation(&outcome).await;
        self.stats
            .uploaded
            .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
        if outcome.is_useful() {
            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        } else {
            self.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
        Ok(())
    }

    async fn serve_tun(
        self: Arc<Self>,
        id: InboundId,
        tag: Arc<str>,
        config: zero_config::TunInboundConfig,
    ) {
        // A host that created the interface itself hands the descriptor over
        // rather than letting this process open one: on Android and iOS
        // opening a TUN device is not permitted, and the interface the user
        // approved already exists (`zero_tun::inherited`).
        let inherited = zero_tun::inherited::take();
        let device_config = zero_tun::TunConfig {
            name: config.name.to_string(),
            no_packet_info: true,
            max_packet_size: 65_535,
            mtu: inherited.map_or(config.mtu, |handover| handover.mtu),
        };
        let opened = match inherited {
            // SAFETY: the descriptor came from `inherited::take`, which yields
            // it exactly once, and the host contract is that it stops using it
            // at that point.
            Some(handover) => unsafe {
                zero_tun::TunDevice::from_raw_fd(handover.fd, device_config, handover.header_len)
            },
            None => zero_tun::TunDevice::open(device_config),
        };
        let device = match opened {
            Ok(device) => Arc::new(device),
            Err(error) => {
                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                error!(%error, %tag, adopted = inherited.is_some(), "TUN device unavailable");
                return;
            }
        };
        if let Some(handover) = inherited {
            info!(
                %tag,
                header_len = handover.header_len,
                mtu = handover.mtu,
                "adopted a TUN descriptor from the host application"
            );
        }
        let parts = match zero_tun::build_netstack(zero_tun::NetstackConfig {
            mtu: config.mtu,
            enable_tcp: config.enable_tcp,
            enable_udp: config.enable_udp,
            enable_icmp: config.enable_icmp,
        }) {
            Ok(parts) => parts,
            Err(error) => {
                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                error!(%error, %tag, "TUN userspace stack failed to build");
                return;
            }
        };
        let addresses = match config
            .addresses
            .iter()
            .map(|value| zero_tun::TunAddress::parse(value))
            .collect::<Result<Vec<_>, _>>()
        {
            Ok(addresses) => addresses,
            Err(error) => {
                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                error!(%error, %tag, "TUN address configuration rejected");
                return;
            }
        };
        let routes = match config
            .routes
            .iter()
            .map(|value| zero_tun::TunRoute::parse(value))
            .collect::<Result<Vec<_>, _>>()
        {
            Ok(routes) => routes,
            Err(error) => {
                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                error!(%error, %tag, "TUN route configuration rejected");
                return;
            }
        };
        // Only configure the link when this process created it. On an adopted
        // interface the addresses, routes and MTU came from a system dialog
        // the user agreed to; running `ip` behind that would be both refused
        // and wrong.
        let _network = if inherited.is_some() {
            debug!(
                %tag,
                "skipping link configuration: the host owns this interface"
            );
            None
        } else {
            let mut bypass_ips = Vec::new();
            for outbound in &self.config().outbounds {
                // AmneziaWG's peer is deliberately left to the tunnel's own
                // routing, as it always has been; every stream proxy's server
                // address must bypass the TUN or its traffic loops back in.
                if matches!(outbound.protocol, OutboundProtocol::AmneziaWireguard(_)) {
                    continue;
                }
                if let Some((Address::Ip(ip), _)) = outbound.endpoint() {
                    bypass_ips.push(ip);
                }
            }
            match device.configure_network(zero_tun::TunNetworkConfig {
                addresses,
                routes,
                bypass_ips,
                auto_route: config.auto_route,
                strict_route: config.strict_route,
            }) {
                Ok(network) => Some(network),
                Err(error) => {
                    self.stats.failed.fetch_add(1, Ordering::Relaxed);
                    error!(%error, %tag, "TUN network configuration failed");
                    return;
                }
            }
        };
        // With the default routes pointing into the tunnel, the engine's own
        // direct connections would follow them back in and loop. Pin them to
        // the interface traffic left by before, for as long as this TUN runs.
        // (An adopted interface's host does this itself.)
        let _bound = _network
            .as_ref()
            .and_then(|network| network.uplink_interface())
            .map(|uplink| zero_core::platform::BoundInterface::set(&uplink));
        let bridge = zero_tun::spawn_netstack_bridge(Arc::clone(&device), parts.stack);
        self.stats.tun.store(TUN_UP, Ordering::Relaxed);
        {
            let me = Arc::clone(&self);
            let bridge_tag = tag.clone();
            tokio::spawn(async move {
                // The bridge only returns when the device is gone or the
                // stack closed. Say so, instead of letting the runtime carry
                // on as if traffic still had somewhere to enter.
                let ended = match bridge.await {
                    Ok(Ok(())) => "the device reached end of file".to_string(),
                    Ok(Err(error)) => error.to_string(),
                    Err(error) => format!("the bridge task failed: {error}"),
                };
                me.stats.tun.store(TUN_LOST, Ordering::Relaxed);
                tracing::warn!(tag = %bridge_tag, reason = %ended, "TUN packet bridge ended");
            });
        }
        if let Some(runner) = parts.runner {
            tokio::spawn(async move {
                if let Err(error) = runner.await {
                    tracing::debug!(%error, "TUN userspace stack stopped");
                }
            });
        }

        if let Some(udp) = parts.udp {
            let me = Arc::clone(&self);
            let udp_tag = tag.clone();
            let udp_device: Arc<dyn PacketOut> = device.clone();
            tokio::spawn(async move {
                me.serve_tun_udp(udp, id, udp_tag, udp_device).await;
            });
        }
        let Some(tcp) = parts.tcp else {
            // A UDP-only TUN remains useful for DNS and datagram transports.
            std::future::pending::<()>().await;
            return;
        };
        info!(%tag, device = %config.name, "TUN userspace stack started");
        self.serve_netstack_tcp(tcp, id, tag).await;
    }

    /// Route the TCP connections a userspace stack terminates (TUN or
    /// WireGuard), each as a session of inbound `id`.
    ///
    /// `local` is the address the application connected *from* and `remote`
    /// is the one it was trying to reach — the netstack names them from its
    /// own point of view, which is the opposite of a listening socket's.
    /// Proxying to the wrong one sends every session back to the machine it
    /// came from, and does so without any error to notice.
    async fn serve_netstack_tcp(
        self: Arc<Self>,
        mut tcp: zero_tun::TcpListener,
        id: InboundId,
        tag: Arc<str>,
    ) {
        while let Some((stream, source, destination)) = tcp.next().await {
            let me = Arc::clone(&self);
            let session_tag = tag.clone();
            tokio::spawn(async move {
                if let Err(error) = me
                    .handle_dokodemo_tcp(
                        boxed(stream),
                        source,
                        id,
                        session_tag,
                        (Address::Ip(destination.ip()), destination.port()),
                    )
                    .await
                {
                    debug!(%error, "userspace stack TCP session failed");
                }
            });
        }
    }

    /// Serve a WireGuard inbound: the peers' packets, decrypted, go into a
    /// userspace stack that terminates their TCP and UDP exactly as a TUN
    /// device's would be, and what the stack answers goes back out to the
    /// peer that owns the destination address.
    async fn serve_wireguard(
        self: Arc<Self>,
        socket: UdpSocket,
        id: InboundId,
        tag: Arc<str>,
        config: zero_config::WireGuardInboundConfig,
    ) {
        let parts = match zero_tun::build_netstack(zero_tun::NetstackConfig {
            mtu: config.mtu,
            enable_tcp: true,
            enable_udp: true,
            enable_icmp: true,
        }) {
            Ok(parts) => parts,
            Err(error) => {
                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                error!(%error, %tag, "WireGuard userspace stack failed to build");
                return;
            }
        };
        let mut link = zero_protocol::wg_server::serve(
            Arc::new(socket),
            config.secret_key,
            peer_specs(&config.peers),
        );
        // Peers with an `email` are metered and held to their speed limits by
        // the addresses they own: a packet from a peer by its source, one to
        // it by its destination. Its peers and owners change at run time
        // ([`Server::sync_running_accounts`]).
        let owners = Arc::new(arc_swap::ArcSwap::from_pointee(WireGuardOwners::of(
            &config.peers,
        )));
        self.wireguard
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner())
            .insert(
                tag.clone(),
                RunningWireGuard {
                    peers: link.peers.clone(),
                    owners: Arc::clone(&owners),
                },
            );
        // Accounts edited before this task got here are in the state but not
        // in `config`, which is the configuration it was started with.
        self.sync_running_accounts(&tag);
        let sessions = Arc::new(WireGuardSessions::default());
        let to_peers = {
            let (sender, mut queue) = tokio::sync::mpsc::channel::<Vec<u8>>(256);
            let (owners, sessions, accounts, upstream) = (
                Arc::clone(&owners),
                Arc::clone(&sessions),
                Arc::clone(&self.stats.accounts),
                link.to_peers.clone(),
            );
            tokio::spawn(async move {
                while let Some(packet) = queue.recv().await {
                    if let Some(email) = owners.load().of_destination(&packet) {
                        if !sessions.to_peer(email) || !accounts.admit(email, 0, packet.len()) {
                            continue;
                        }
                    }
                    if upstream.send(packet).await.is_err() {
                        return;
                    }
                }
            });
            sender
        };
        let (mut sink, mut stream) = parts.stack.split();
        if let Some(runner) = parts.runner {
            tokio::spawn(async move {
                if let Err(error) = runner.await {
                    debug!(%error, "WireGuard userspace stack stopped");
                }
            });
        }
        // Peers to stack.
        let (from_owners, from_sessions, accounts, from_tag) = (
            Arc::clone(&owners),
            Arc::clone(&sessions),
            Arc::clone(&self.stats.accounts),
            tag.clone(),
        );
        tokio::spawn(async move {
            let mut sweep = tokio::time::interval(Duration::from_secs(30));
            loop {
                let (packet, from) = tokio::select! {
                    received = link.from_peers.recv() => match received {
                        Some(received) => received,
                        None => return,
                    },
                    _ = sweep.tick() => {
                        from_sessions.sweep();
                        continue;
                    }
                };
                if let Some(email) = from_owners.load().of_source(&packet) {
                    if !from_sessions.heard_from(&accounts, email, &from_tag, from)
                        || !accounts.admit(email, packet.len(), 0)
                    {
                        continue;
                    }
                }
                match sink.send(packet).await {
                    Ok(()) => {}
                    // A packet the stack cannot parse is dropped; only a
                    // closed stack ends the loop.
                    Err(error) if error.kind() == std::io::ErrorKind::InvalidInput => {}
                    Err(_) => return,
                }
            }
        });
        // Stack to peers.
        let stack_out = to_peers.clone();
        tokio::spawn(async move {
            while let Some(Ok(packet)) = stream.next().await {
                if stack_out.send(packet).await.is_err() {
                    return;
                }
            }
        });
        if let Some(udp) = parts.udp {
            let me = Arc::clone(&self);
            let udp_tag = tag.clone();
            let out: Arc<dyn PacketOut> = Arc::new(to_peers.clone());
            tokio::spawn(async move {
                me.serve_tun_udp(udp, id, udp_tag, out).await;
            });
        }
        if let Some(tcp) = parts.tcp {
            info!(%tag, peers = config.peers.len(), "WireGuard userspace stack started");
            Arc::clone(&self)
                .serve_netstack_tcp(tcp, id, tag.clone())
                .await;
        }
        link.task.abort();
        let mut running = self
            .wireguard
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        if running
            .get(&tag)
            .is_some_and(|entry| entry.peers.same_channel(&link.peers))
        {
            running.remove(&tag);
        }
    }

    async fn serve_tun_udp(
        self: Arc<Self>,
        udp: zero_tun::UdpSocket,
        id: InboundId,
        tag: Arc<str>,
        device: Arc<dyn PacketOut>,
    ) {
        let sniff = self.sniff_policy(id);
        let (mut reader, mut writer) = udp.split();
        // One flow per application socket and destination: the TUN writes
        // every answer as if it came from the address the application sent
        // to, which is what a connected UDP socket insists on.
        let (mut relay, mut replies) =
            UdpRelay::<(SocketAddr, SocketAddr)>::new(Arc::clone(&self), id, tag, 4096, sniff);
        loop {
            tokio::select! {
                datagram = reader.next() => {
                    let Some((payload, source, target)) = datagram else {
                        return;
                    };
                    let destination = Destination::udp(Address::Ip(target.ip()), target.port());
                    if let Dispatch::Rejected(payload) =
                        relay.dispatch((source, target), source, destination, payload).await
                    {
                        reject_udp(&*device, source, target, &payload).await;
                    }
                }
                Some(reply) = replies.recv() => {
                    let (source, target) = reply.key;
                    // Full-cone answers keep their real origin, unless the
                    // request went to a FakeDNS handle: the application only
                    // knows that address, so the answer must come from it.
                    let from = match reply.source.address {
                        Address::Ip(ip) if !reply.restored => {
                            SocketAddr::new(ip, reply.source.port)
                        }
                        _ => target,
                    };
                    let length = reply.payload.len() as u64;
                    if writer.send((reply.payload, from, source)).await.is_ok() {
                        self.stats.downloaded.fetch_add(length, Ordering::Relaxed);
                        self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                    } else {
                        self.stats.failed.fetch_add(1, Ordering::Relaxed);
                    }
                }
            }
        }
    }

    async fn serve_dokodemo_udp(
        self: Arc<Self>,
        socket: UdpSocket,
        id: InboundId,
        tag: Arc<str>,
        target: (Address, u16),
    ) {
        let destination = Destination::udp(target.0, target.1);
        let (mut relay, mut replies) =
            UdpRelay::<SocketAddr>::new(Arc::clone(&self), id, tag, 4096, self.sniff_policy(id));
        let mut buffer = vec![0u8; 65_535];
        loop {
            tokio::select! {
                received = socket.recv_from(&mut buffer) => {
                    let (len, source) = match received {
                        Ok(value) => value,
                        Err(error) if matches!(
                            error.kind(),
                            std::io::ErrorKind::ConnectionReset | std::io::ErrorKind::ConnectionRefused
                        ) => continue,
                        Err(error) => {
                            error!(%error, "dokodemo UDP receive failed");
                            return;
                        }
                    };
                    relay
                        .dispatch(source, source, destination.clone(), buffer[..len].to_vec())
                        .await;
                }
                Some(reply) = replies.recv() => {
                    match socket.send_to(&reply.payload, reply.key).await {
                        Ok(_) => {
                            self.stats
                                .downloaded
                                .fetch_add(reply.payload.len() as u64, Ordering::Relaxed);
                            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                        }
                        Err(error) => {
                            self.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(client = %reply.key, %error, "dokodemo UDP reply failed");
                        }
                    }
                }
            }
        }
    }

    /// The UDP side of a TPROXY dokodemo inbound. Each datagram says where
    /// its client was really sending it, so a flow is the pair (client,
    /// destination), and the answer is sent from a socket bound to that
    /// destination or the client would not accept it.
    async fn serve_tproxy_udp(
        self: Arc<Self>,
        socket: zero_net::transparent::TransparentUdp,
        id: InboundId,
        tag: Arc<str>,
    ) {
        type Flow = (SocketAddr, SocketAddr);
        let (mut relay, mut replies) =
            UdpRelay::<Flow>::new(Arc::clone(&self), id, tag, 4096, self.sniff_policy(id));
        let mut senders: HashMap<SocketAddr, UdpSocket> = HashMap::new();
        let mut buffer = vec![0u8; 65_535];
        loop {
            tokio::select! {
                received = socket.recv(&mut buffer) => {
                    let (len, client, original) = match received {
                        Ok(value) => value,
                        Err(error) if matches!(
                            error.kind(),
                            std::io::ErrorKind::ConnectionReset | std::io::ErrorKind::ConnectionRefused
                        ) => continue,
                        Err(error) => {
                            error!(%error, "tproxy UDP receive failed");
                            return;
                        }
                    };
                    let destination = Destination::udp(Address::Ip(original.ip()), original.port());
                    relay
                        .dispatch((client, original), client, destination, buffer[..len].to_vec())
                        .await;
                }
                Some(reply) = replies.recv() => {
                    let (client, original) = reply.key;
                    if !senders.contains_key(&original) {
                        // One socket per destination; a client scanning a
                        // range must not grow this without bound.
                        if senders.len() >= 256 {
                            senders.clear();
                        }
                        match zero_net::transparent::reply_socket(original) {
                            Ok(sender) => {
                                senders.insert(original, sender);
                            }
                            Err(error) => {
                                self.stats.failed.fetch_add(1, Ordering::Relaxed);
                                debug!(%original, %error, "tproxy UDP reply socket failed");
                                continue;
                            }
                        }
                    }
                    match senders[&original].send_to(&reply.payload, client).await {
                        Ok(_) => {
                            self.stats
                                .downloaded
                                .fetch_add(reply.payload.len() as u64, Ordering::Relaxed);
                            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                        }
                        Err(error) => {
                            self.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%client, %error, "tproxy UDP reply failed");
                        }
                    }
                }
            }
        }
    }

    async fn handle_vmess(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        config: &zero_config::VmessInboundConfig,
    ) -> Result<(), String> {
        let users: Vec<_> = config
            .users
            .iter()
            .map(|user| zero_protocol::vmess::User {
                uuid: user.uuid,
                cipher: outbound::vmess_cipher(user.cipher),
            })
            .collect();
        let accepted = within_handshake(zero_protocol::vmess::server_handshake(stream, &users))
            .await?
            .map_err(|error| format!("reading VMess request: {error}"))?;
        let email = config
            .users
            .get(accepted.user)
            .and_then(|user| user.email.clone());
        let stream = self.meter_account(email.as_ref(), &tag, peer, boxed(accepted.stream), 0);
        if accepted.destination.network != Network::Tcp {
            return self
                .handle_vmess_udp(stream, peer, id, tag, accepted.destination)
                .await;
        }
        let mut destination = self.restore_fake_destination(&accepted.destination).await;
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = email;
        let sniffing = self.sniffing_of(id);
        let client = self
            .sniff_client(&mut ctx, &mut destination, stream, &sniffing)
            .await;
        let decision = self.route(&ctx).await;
        let Some((health, remote)) = self
            .connect_decided(decision, &destination, Some(peer))
            .await?
        else {
            return Ok(());
        };
        let outcome = relay(client, remote).await;
        if let Some(tag) = &health {
            self.record_outbound_observation(tag, &outcome);
        }
        self.record_observation(&outcome).await;
        // The outbound that carried the session is named in the counter, so a
        // panel can tell which outbound an account's traffic went through.
        // A session that went direct has no outbound to name.
        self.stats
            .record_tag_traffic(&ctx.inbound_tag, health.as_deref(), &outcome.transferred);
        self.stats
            .uploaded
            .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
        if outcome.is_useful() {
            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        } else {
            self.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
        debug!(
            %peer,
            dest = %destination,
            up = outcome.transferred.uploaded,
            down = outcome.transferred.downloaded,
            stage = ?outcome.stage,
            error = ?outcome.error,
            "VMess session finished"
        );
        Ok(())
    }

    /// Deal with a connection that did not authenticate. With a fallback
    /// configured it is joined to that address, starting with every byte
    /// already read from it, so whoever connected gets a real web server's
    /// answer to whatever they sent. Without one it is closed with `reason`,
    /// as before.
    ///
    /// This runs outside the handshake deadline on purpose: to the visitor it
    /// is an ordinary connection to a website, and those last.
    async fn fall_back(
        &self,
        fallbacks: &[zero_config::FallbackRule],
        conn: &ConnInfo,
        stream: zero_core::BoxStream,
        seen: Vec<u8>,
        peer: SocketAddr,
        reason: String,
    ) -> Result<(), String> {
        let probe = zero_config::FallbackProbe {
            server_name: conn.server_name.as_deref(),
            alpn: conn.alpn.as_deref(),
            first_bytes: &seen,
        };
        let Some(rule) = zero_config::select_fallback(fallbacks, &probe) else {
            return Err(reason);
        };
        let (address, port) = &rule.dest;
        self.stats.failed.fetch_add(1, Ordering::Relaxed);
        let destination = Destination::tcp(address.clone(), *port);
        let mut remote = outbound::connect_direct_with_resolver(
            &destination,
            &zero_config::StreamSettings::default(),
            &self.resolver(),
        )
        .await
        .map_err(|error| {
            format!("{reason}; and the fallback {destination} is unreachable: {error}")
        })?;
        // The web server behind learns who is really asking, if it wants to;
        // the header and the first bytes go out together, as one segment.
        let mut first = if rule.xver != 0 {
            zero_protocol::proxy_protocol::encode(rule.xver, Some(peer), conn.local)
        } else {
            Vec::new()
        };
        first.extend_from_slice(&seen);
        remote
            .write_all(&first)
            .await
            .map_err(|error| format!("{reason}; and writing to the fallback failed: {error}"))?;
        debug!(%peer, %reason, to = %destination, "unauthenticated connection handed to the fallback");
        let _ = relay(stream, remote).await;
        Ok(())
    }

    /// Serve one connection of a Tide inbound. The streams its sessions carry
    /// are routed by a task of their own, started by the first connection,
    /// because a session is not tied to the connection it arrived on.
    async fn handle_tide(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        id: InboundId,
        tag: Arc<str>,
        tide: Arc<TideInbound>,
    ) -> Result<(), String> {
        let streams = tide
            .streams
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner())
            .take();
        if let Some(mut streams) = streams {
            let (server, users) = (Arc::clone(&self), Arc::clone(&tide));
            tokio::spawn(async move {
                // A session spans connections, so a stream has no one peer
                // address; routing by source does not apply to it.
                let peer = SocketAddr::from(([0, 0, 0, 0], 0));
                while let Some((user, destination, stream)) = streams.recv().await {
                    // Each stream is its user's: metered under its name, and
                    // refused once the user was removed.
                    let Ok(email) = users.account_of(&user) else {
                        continue;
                    };
                    let (server, tag) = (Arc::clone(&server), tag.clone());
                    if destination.network == Network::Udp {
                        tokio::spawn(async move {
                            let flow = zero_protocol::tide::UdpFlow::new(stream);
                            if let Err(error) = server.handle_tide_udp(flow, id, tag, email).await {
                                debug!(%error, "Tide UDP flow ended with an error");
                            }
                        });
                        continue;
                    }
                    tokio::spawn(async move {
                        let stream =
                            server.meter_account(email.as_ref(), &tag, peer, boxed(stream), 0);
                        if let Err(error) = server
                            .handle_hysteria2(stream, peer, id, tag, destination, email)
                            .await
                        {
                            debug!(%error, "Tide stream ended with an error");
                        }
                    });
                }
            });
        }
        tide.server
            .serve_connection(stream)
            .await
            .map_err(|error| format!("Tide connection: {error}"))
    }

    /// One UDP flow from a Tide client. Every datagram names its own
    /// destination, so the flow is routed and answered like any UDP ingress:
    /// the shared relay does the routing, the NAT sockets and the proxying,
    /// and what it gets back goes into the flow.
    async fn handle_tide_udp(
        self: Arc<Self>,
        flow: zero_protocol::tide::UdpFlow,
        id: InboundId,
        tag: Arc<str>,
        email: Option<Arc<str>>,
    ) -> Result<(), String> {
        let flow = Arc::new(flow);
        // A session spans connections, so a flow has no one peer address.
        let peer = SocketAddr::from(([0, 0, 0, 0], 0));
        // The flow is its user's session while it lasts.
        let session = email
            .as_ref()
            .map(|email| self.stats.accounts.open_session(email, &tag, None));
        let (mut udp, mut replies) =
            UdpRelay::<()>::new(Arc::clone(&self), id, tag, 64, self.sniff_policy(id));
        let writer = {
            let (flow, server, email) = (Arc::clone(&flow), Arc::clone(&self), email.clone());
            tokio::spawn(async move {
                let stats = Arc::clone(&server.stats);
                while let Some(reply) = replies.recv().await {
                    if !server.admit_datagram(email.as_ref(), 0, reply.payload.len()) {
                        continue;
                    }
                    let length = reply.payload.len() as u64;
                    if flow.send(&reply.source, &reply.payload).is_err() {
                        return;
                    }
                    stats.downloaded.fetch_add(length, Ordering::Relaxed);
                    stats.succeeded.fetch_add(1, Ordering::Relaxed);
                }
            })
        };
        let _writer = AbortOnDrop(vec![writer]);
        let mut seen = udp.activity();
        loop {
            if session.as_ref().is_some_and(|session| session.is_ended()) {
                return Ok(());
            }
            match timeout(UDP_SESSION_IDLE, flow.recv()).await {
                Ok(Ok((destination, payload))) => {
                    if self.admit_datagram(email.as_ref(), payload.len(), 0) {
                        udp.dispatch((), peer, destination, payload.to_vec()).await;
                    }
                }
                Ok(Err(_)) => return Ok(()),
                Err(_) => {
                    let now = udp.activity();
                    if now == seen {
                        return Ok(());
                    }
                    seen = now;
                }
            }
        }
    }

    async fn handle_anytls(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        config: &zero_config::AnyTlsInboundConfig,
    ) -> Result<(), String> {
        let passwords: Vec<[u8; 32]> = config
            .passwords
            .iter()
            .map(|password| {
                use sha2::{Digest, Sha256};
                let mut hash = [0u8; 32];
                hash.copy_from_slice(Sha256::digest(password.as_bytes()).as_slice());
                hash
            })
            .collect();
        let (stream, announced, user) =
            within_handshake(zero_protocol::anytls::server_handshake(stream, &passwords))
                .await?
                .map_err(|error| format!("AnyTLS handshake: {error}"))?;
        let email = config.emails.get(user).cloned().flatten();
        let stream = self.meter_account(email.as_ref(), &tag, peer, boxed(stream), 0);
        let mut destination = self.restore_fake_destination(&announced).await;
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = email;
        let sniffing = self.sniffing_of(id);
        let client = self
            .sniff_client(&mut ctx, &mut destination, stream, &sniffing)
            .await;
        let decision = self.route(&ctx).await;
        let Some((health, remote)) = self
            .connect_decided(decision, &destination, Some(peer))
            .await?
        else {
            return Ok(());
        };
        let outcome = relay(client, remote).await;
        if let Some(tag) = &health {
            self.record_outbound_observation(tag, &outcome);
        }
        self.record_observation(&outcome).await;
        self.stats
            .uploaded
            .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
        if outcome.is_useful() {
            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        } else {
            self.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
        debug!(
            dest = %destination,
            up = outcome.transferred.uploaded,
            down = outcome.transferred.downloaded,
            stage = ?outcome.stage,
            error = ?outcome.error,
            "AnyTLS session finished"
        );
        Ok(())
    }

    async fn handle_hysteria2(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        destination: Destination,
        email: Option<Arc<str>>,
    ) -> Result<(), String> {
        let mut destination = self.restore_fake_destination(&destination).await;
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = email;
        let sniffing = self.sniffing_of(id);
        let client = self
            .sniff_client(&mut ctx, &mut destination, boxed(stream), &sniffing)
            .await;
        let decision = self.route(&ctx).await;
        let Some((health, remote)) = self
            .connect_decided(decision, &destination, Some(peer))
            .await?
        else {
            return Ok(());
        };
        let outcome = relay(client, remote).await;
        if let Some(tag) = &health {
            self.record_outbound_observation(tag, &outcome);
        }
        self.record_observation(&outcome).await;
        self.stats
            .uploaded
            .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
        if outcome.is_useful() {
            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        } else {
            self.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
        debug!(
            dest = %destination,
            up = outcome.transferred.uploaded,
            down = outcome.transferred.downloaded,
            stage = ?outcome.stage,
            error = ?outcome.error,
            "Hysteria2 session finished"
        );
        Ok(())
    }

    async fn handle_hysteria2_udp(
        self: Arc<Self>,
        session: Hysteria2UdpSession,
        id: InboundId,
        tag: Arc<str>,
        email: Option<Arc<str>>,
    ) -> Result<(), String> {
        let Hysteria2UdpSession {
            connection,
            session_id,
            packet_id,
            peer,
            destination,
            payload,
        } = session;
        let destination = self.restore_fake_destination(&destination).await;
        let datagram = socks::UdpDatagram {
            destination: destination.clone(),
            payload,
        };
        if !self.admit_datagram(email.as_ref(), datagram.payload.len(), 0) {
            return Ok(());
        }
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = email.clone();
        let decision = self.route(&ctx).await;
        let resolver = match &decision {
            Decision::DirectVia { resolver } => Arc::new(self.resolver().for_tag(resolver)),
            _ => self.resolver(),
        };
        let proxy = match decision {
            Decision::Block => {
                self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                return Ok(());
            }
            Decision::DirectVia { .. } => None,
            Decision::Outbound(outbound_tag) | Decision::Balancer(outbound_tag) => {
                Some(self.pick_outbound(&outbound_tag).ok_or_else(|| {
                    format!("no outbound for Hysteria2 UDP route {outbound_tag:?}")
                })?)
            }
        };
        let (response_destination, response) = if let Some(outbound) = proxy {
            if matches!(outbound.protocol, OutboundProtocol::Freedom { .. }) {
                self.direct_udp(&resolver, &datagram, Some(&outbound.stream))
                    .await?
            } else {
                self.proxy_udp(&outbound, &datagram).await?
            }
        } else {
            self.direct_udp(&resolver, &datagram, None).await?
        };
        if !self.admit_datagram(email.as_ref(), 0, response.len()) {
            return Ok(());
        }
        let frame = zero_transport::hysteria2::encode_udp_datagram(
            session_id,
            packet_id,
            &response_destination,
            &response,
        )?;
        connection
            .send_datagram(bytes::Bytes::from(frame))
            .map_err(|error| format!("sending Hysteria2 UDP response: {error}"))?;
        self.stats
            .uploaded
            .fetch_add(datagram.payload.len() as u64, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(response.len() as u64, Ordering::Relaxed);
        self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        Ok(())
    }

    #[allow(clippy::too_many_arguments)]
    async fn handle_tuic_udp(
        self: Arc<Self>,
        connection: h3_quinn::quinn::Connection,
        association: u16,
        packet: u16,
        peer: SocketAddr,
        destination: Destination,
        payload: Vec<u8>,
        id: InboundId,
        tag: Arc<str>,
        email: Option<Arc<str>>,
    ) -> Result<(), String> {
        let destination = self.restore_fake_destination(&destination).await;
        let datagram = socks::UdpDatagram {
            destination: destination.clone(),
            payload,
        };
        if !self.admit_datagram(email.as_ref(), datagram.payload.len(), 0) {
            return Ok(());
        }
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = email.clone();
        let decision = self.route(&ctx).await;
        let resolver = match &decision {
            Decision::DirectVia { resolver } => Arc::new(self.resolver().for_tag(resolver)),
            _ => self.resolver(),
        };
        let proxy = match decision {
            Decision::Block => {
                self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                return Ok(());
            }
            Decision::DirectVia { .. } => None,
            Decision::Outbound(outbound_tag) | Decision::Balancer(outbound_tag) => Some(
                self.pick_outbound(&outbound_tag)
                    .ok_or_else(|| format!("no outbound for TUIC UDP route {outbound_tag:?}"))?,
            ),
        };
        let (response_destination, response) = if let Some(outbound) = proxy {
            if matches!(outbound.protocol, OutboundProtocol::Freedom { .. }) {
                self.direct_udp(&resolver, &datagram, Some(&outbound.stream))
                    .await?
            } else {
                self.proxy_udp(&outbound, &datagram).await?
            }
        } else {
            self.direct_udp(&resolver, &datagram, None).await?
        };
        if !self.admit_datagram(email.as_ref(), 0, response.len()) {
            return Ok(());
        }
        let max_datagram = connection
            .max_datagram_size()
            .ok_or_else(|| "TUIC peer does not support QUIC datagrams".to_string())?;
        for frame in zero_transport::tuic::encode_packet_fragments(
            max_datagram,
            association,
            packet,
            &response_destination,
            &response,
        )? {
            connection
                .send_datagram(bytes::Bytes::from(frame))
                .map_err(|error| format!("sending TUIC UDP response: {error}"))?;
        }
        self.stats
            .uploaded
            .fetch_add(datagram.payload.len() as u64, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(response.len() as u64, Ordering::Relaxed);
        self.stats.succeeded.fetch_add(1, Ordering::Relaxed);

        // `send_datagram` only queues. A QUIC connection closes as soon as its
        // last handle drops, taking anything still queued with it, so returning
        // here would routinely discard the reply that was just produced. Hold
        // the connection until the peer closes it, bounded so a client that
        // never closes cannot pin the connection open.
        tokio::spawn(async move {
            let _ = timeout(Duration::from_secs(30), connection.closed()).await;
        });
        Ok(())
    }

    async fn handle_vmess_udp(
        self: Arc<Self>,
        mut stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        destination: Destination,
    ) -> Result<(), String> {
        let destination = self.restore_fake_destination(&destination).await;
        let ctx = self.new_context(id, tag, destination.clone(), peer);
        let decision = self.route(&ctx).await;
        let outbound = match decision {
            Decision::Block => {
                self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                return Ok(());
            }
            Decision::DirectVia { .. } => None,
            Decision::Outbound(tag) | Decision::Balancer(tag) => Some(
                self.pick_outbound(&tag)
                    .ok_or_else(|| format!("no usable outbound for {tag:?}"))?,
            ),
        };
        if let Some(outbound) = outbound {
            if matches!(outbound.protocol, OutboundProtocol::Freedom { .. }) {
                return self.relay_vmess_udp_direct(&mut stream, &destination).await;
            }
            let mut payload = vec![0u8; 65_535];
            loop {
                let n = match timeout(UDP_SESSION_IDLE, stream.read(&mut payload)).await {
                    Ok(read) => {
                        read.map_err(|error| format!("reading VMess UDP payload: {error}"))?
                    }
                    Err(_) => return Ok(()),
                };
                if n == 0 {
                    return Ok(());
                }
                let datagram = socks::UdpDatagram {
                    destination: destination.clone(),
                    payload: payload[..n].to_vec(),
                };
                let response = match self.proxy_udp(&outbound, &datagram).await {
                    Ok((_, response)) => response,
                    // One unanswered datagram is not a reason to end the
                    // client's whole UDP session.
                    Err(error) => {
                        self.stats.failed.fetch_add(1, Ordering::Relaxed);
                        debug!(%destination, %error, "VMess UDP exchange failed");
                        continue;
                    }
                };
                stream
                    .write_all(&response)
                    .await
                    .map_err(|error| format!("writing VMess UDP response: {error}"))?;
                stream
                    .flush()
                    .await
                    .map_err(|error| format!("flushing VMess UDP response: {error}"))?;
            }
        }
        self.relay_vmess_udp_direct(&mut stream, &destination).await
    }

    async fn relay_vmess_udp_direct(
        &self,
        stream: &mut zero_core::BoxStream,
        destination: &Destination,
    ) -> Result<(), String> {
        let addrs = self
            .resolver()
            .resolve_address(
                &destination.address,
                self.resolver().settings().query_strategy,
            )
            .await
            .map_err(|error| error.to_string())?;
        let target = SocketAddr::new(
            *addrs
                .first()
                .ok_or_else(|| "resolver returned no VMess UDP destinations".to_string())?,
            destination.port,
        );
        let socket = bind_outbound_udp(target.is_ipv4(), None)
            .await
            .map_err(|error| format!("binding VMess UDP socket: {error}"))?;
        socket
            .connect(target)
            .await
            .map_err(|error| format!("connecting VMess UDP socket: {error}"))?;
        let mut client_payload = vec![0u8; 65_535];
        let mut remote_payload = vec![0u8; 65_535];
        let idle = tokio::time::sleep(UDP_SESSION_IDLE);
        tokio::pin!(idle);
        loop {
            tokio::select! {
                () = &mut idle => return Ok(()),
                result = stream.read(&mut client_payload) => {
                    idle.as_mut().reset(tokio::time::Instant::now() + UDP_SESSION_IDLE);
                    let length = result.map_err(|error| format!("reading VMess UDP payload: {error}"))?;
                    if length == 0 { return Ok(()); }
                    match socket.send(&client_payload[..length]).await {
                        Ok(_) => {}
                        Err(error) if matches!(
                            error.kind(),
                            std::io::ErrorKind::ConnectionRefused | std::io::ErrorKind::ConnectionReset
                        ) => {}
                        Err(error) => return Err(format!("sending VMess UDP payload: {error}")),
                    }
                }
                result = socket.recv(&mut remote_payload) => {
                    idle.as_mut().reset(tokio::time::Instant::now() + UDP_SESSION_IDLE);
                    let length = match result {
                        Ok(length) => length,
                        // ICMP unreachable reported on the connected socket.
                        Err(error) if matches!(
                            error.kind(),
                            std::io::ErrorKind::ConnectionRefused | std::io::ErrorKind::ConnectionReset
                        ) => continue,
                        Err(error) => return Err(format!("receiving VMess UDP response: {error}")),
                    };
                    stream.write_all(&remote_payload[..length]).await
                        .map_err(|error| format!("writing VMess UDP response: {error}"))?;
                    stream.flush().await
                        .map_err(|error| format!("flushing VMess UDP response: {error}"))?;
                }
            }
        }
    }

    async fn handle_vless(
        self: Arc<Self>,
        mut stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        config: &VlessInboundConfig,
        conn: &ConnInfo,
    ) -> Result<(), String> {
        let fallbacks = &config.fallbacks;
        let read = within_handshake(read_vless_request(&mut stream, !fallbacks.is_empty())).await?;
        let (mut request, consumed, buffered) = match read {
            Ok(read) => read,
            Err((reason, seen)) => {
                return self
                    .fall_back(fallbacks, conn, stream, seen, peer, reason)
                    .await
            }
        };
        let Some(user) = config.users.iter().find(|user| user.uuid == request.uuid) else {
            let reason = "VLESS UUID is not authorised".to_string();
            return self
                .fall_back(fallbacks, conn, stream, buffered, peer, reason)
                .await;
        };
        let request_is_vision = request.flow.is_some();
        let user_is_vision = user.flow.is_vision();
        if request_is_vision != user_is_vision {
            return Err("VLESS Vision flow does not match the authorised user".into());
        }
        // Every path below (TCP, UDP, Mux, reverse) carries this account.
        let early = buffered.len().saturating_sub(consumed);
        let stream = self.meter_account(user.email.as_ref(), &tag, peer, stream, early);

        if request.mux {
            if user_is_vision {
                return Err("VLESS Mux cannot be combined with Vision".into());
            }
            let mut outer = ChainedStream::new(buffered[consumed..].to_vec(), stream);
            let first = within_handshake(zero_protocol::mux::read_frame(&mut outer))
                .await?
                .map_err(|error| format!("reading VLESS Mux frame: {error}"))?;
            let destination = first
                .target
                .clone()
                .ok_or_else(|| "VLESS Mux first frame has no destination".to_string())?;
            if destination.network == Network::Udp {
                return self.handle_vless_mux_udp(outer, first, peer, id, tag).await;
            }
            return self
                .handle_vless_mux(outer, first, peer, id, tag, destination)
                .await;
        }

        // A reverse-proxy account may only dial in as a bridge, and a plain
        // account may not: what each end is allowed to be is fixed by the
        // account, not by what the client asks for.
        if request.reverse {
            let Some(tag) = user.reverse.clone() else {
                return Err("this VLESS account is not allowed to create a reverse proxy".into());
            };
            let stream = with_vless_response(stream);
            let client = ChainedStream::new(buffered[consumed..].to_vec(), stream);
            let client: zero_core::BoxStream = if user_is_vision {
                boxed(zero_protocol::vision::VisionStream::new_server(
                    client,
                    request.uuid,
                ))
            } else {
                boxed(client)
            };
            let domain: Arc<str> = Arc::from(zero_protocol::vless::REVERSE_HOST);
            return self
                .portal(&tag, &domain)
                .adopt(client)
                .map_err(|error| format!("reverse proxy: {error}"));
        }
        if user.reverse.is_some() {
            return Err("for safety, a reverse-proxy account may not use the forward proxy".into());
        }

        request.destination = self.restore_fake_destination(&request.destination).await;

        if request.destination.network == Network::Udp {
            if user_is_vision {
                return Err("VLESS Vision is only valid for TCP sessions".into());
            }
            return self
                .handle_vless_udp(
                    stream,
                    peer,
                    id,
                    tag,
                    request.destination,
                    buffered[consumed..].to_vec(),
                )
                .await;
        }

        let mut destination = request.destination.clone();
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = user.email.clone();
        ctx.vless_route = Some(u16::from_be_bytes([request.uuid[6], request.uuid[7]]));
        let stream = with_vless_response(stream);
        let client = ChainedStream::new(buffered[consumed..].to_vec(), stream);
        let client: zero_core::BoxStream = if user_is_vision {
            let mut vision = zero_protocol::vision::VisionStream::new_server(client, request.uuid)
                .with_seed(
                    user.vision_seed
                        .map_or_else(Default::default, zero_protocol::vision::VisionSeed::new),
                );
            // A client that goes direct (writes its raw inner stream below
            // the encryption layer) says so with a Vision frame; the layer
            // under this one must then stop decrypting.
            if let Some(flag) = conn.direct.clone() {
                vision = vision.with_direct_read_switch(move |_| {
                    flag.store(true, std::sync::atomic::Ordering::Release);
                });
            }
            boxed(vision)
        } else {
            boxed(client)
        };
        let sniffing = self.sniffing_of(id);
        let client = self
            .sniff_client(&mut ctx, &mut destination, client, &sniffing)
            .await;
        let decision = self.route(&ctx).await;
        let Some((health, remote)) = self
            .connect_decided(decision, &destination, Some(peer))
            .await?
        else {
            return Ok(());
        };
        debug!(%peer, vision = user_is_vision, "VLESS route connected; starting relay");
        let outcome = relay(client, remote).await;
        if let Some(tag) = &health {
            self.record_outbound_observation(tag, &outcome);
        }
        self.record_observation(&outcome).await;
        // The outbound that carried the session is named in the counter, so a
        // panel can tell which outbound an account's traffic went through.
        // A session that went direct has no outbound to name.
        self.stats
            .record_tag_traffic(&ctx.inbound_tag, health.as_deref(), &outcome.transferred);
        self.stats
            .uploaded
            .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
        if outcome.is_useful() {
            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        } else {
            self.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
        debug!(
            %peer,
            dest = %destination,
            up = outcome.transferred.uploaded,
            down = outcome.transferred.downloaded,
            stage = ?outcome.stage,
            error = ?outcome.error,
            "VLESS session finished"
        );
        Ok(())
    }

    async fn handle_vless_mux_udp(
        self: Arc<Self>,
        outer: ChainedStream,
        first: zero_protocol::mux::Frame,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
    ) -> Result<(), String> {
        if first.status != zero_protocol::mux::STATUS_NEW
            || first
                .target
                .as_ref()
                .is_none_or(|target| target.network != Network::Udp)
            || first.option & zero_protocol::mux::OPTION_DATA == 0
        {
            return Err("VLESS XUDP must start with a UDP NEW data frame".into());
        }

        let mut outer = with_vless_response(boxed(outer));

        let mut targets = HashMap::<u16, Destination>::new();
        let mut pending = Some(first);
        loop {
            let frame = if let Some(frame) = pending.take() {
                frame
            } else {
                match zero_protocol::mux::read_frame(&mut outer).await {
                    Ok(frame) => frame,
                    Err(error) if error.kind() == std::io::ErrorKind::UnexpectedEof => break,
                    Err(error) => return Err(format!("reading VLESS XUDP frame: {error}")),
                }
            };

            match frame.status {
                zero_protocol::mux::STATUS_NEW | zero_protocol::mux::STATUS_KEEP => {
                    let destination = match frame.status {
                        zero_protocol::mux::STATUS_NEW => {
                            let destination = frame.target.clone().ok_or_else(|| {
                                "VLESS XUDP NEW frame has no destination".to_string()
                            })?;
                            if destination.network != Network::Udp {
                                return Err("VLESS XUDP NEW frame is not UDP".into());
                            }
                            targets.insert(frame.session_id, destination.clone());
                            destination
                        }
                        _ => {
                            if let Some(destination) = frame.target.clone() {
                                if destination.network != Network::Udp {
                                    return Err("VLESS XUDP KEEP target is not UDP".into());
                                }
                                targets.insert(frame.session_id, destination.clone());
                                destination
                            } else {
                                targets.get(&frame.session_id).cloned().ok_or_else(|| {
                                    "VLESS XUDP KEEP frame has no known destination".to_string()
                                })?
                            }
                        }
                    };
                    if frame.option & zero_protocol::mux::OPTION_DATA == 0
                        || frame.payload.is_empty()
                    {
                        continue;
                    }

                    let destination = self.restore_fake_destination(&destination).await;
                    let ctx = self.new_context(id, tag.clone(), destination.clone(), peer);
                    let decision = self.route(&ctx).await;
                    let session_id = frame.session_id;
                    let resolver = match &decision {
                        Decision::DirectVia { resolver } => {
                            Arc::new(self.resolver().for_tag(resolver))
                        }
                        _ => self.resolver(),
                    };
                    let response = match decision {
                        Decision::Block => {
                            self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                            continue;
                        }
                        Decision::DirectVia { .. } => {
                            self.direct_udp(
                                &resolver,
                                &socks::UdpDatagram {
                                    destination: destination.clone(),
                                    payload: frame.payload,
                                },
                                None,
                            )
                            .await
                        }
                        Decision::Outbound(outbound_tag) | Decision::Balancer(outbound_tag) => {
                            let outbound = self.pick_outbound(&outbound_tag).ok_or_else(|| {
                                format!("no outbound for VLESS XUDP route {outbound_tag:?}")
                            })?;
                            let datagram = socks::UdpDatagram {
                                destination: destination.clone(),
                                payload: frame.payload,
                            };
                            if matches!(outbound.protocol, OutboundProtocol::Freedom { .. }) {
                                self.direct_udp(&resolver, &datagram, Some(&outbound.stream))
                                    .await
                            } else {
                                self.proxy_udp(&outbound, &datagram).await
                            }
                        }
                    };
                    // The carrier multiplexes many UDP sessions; one datagram
                    // that goes unanswered must not tear all of them down.
                    let response = match response {
                        Ok(response) => response,
                        Err(error) => {
                            self.stats.failed.fetch_add(1, Ordering::Relaxed);
                            debug!(%destination, %error, "VLESS XUDP exchange failed");
                            continue;
                        }
                    };
                    let response_frame = zero_protocol::mux::Frame::udp_keep(
                        session_id,
                        Some(response.0),
                        response.1,
                    );
                    zero_protocol::mux::write_frame(&mut outer, &response_frame)
                        .await
                        .map_err(|error| format!("writing VLESS XUDP response frame: {error}"))?;
                    outer
                        .flush()
                        .await
                        .map_err(|error| format!("flushing VLESS XUDP response frame: {error}"))?;
                    self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
                }
                zero_protocol::mux::STATUS_END => {
                    targets.remove(&frame.session_id);
                }
                zero_protocol::mux::STATUS_KEEP_ALIVE => {}
                other => return Err(format!("unexpected VLESS XUDP status {other}")),
            }
        }
        Ok(())
    }

    async fn handle_vless_mux(
        self: Arc<Self>,
        outer: ChainedStream,
        first: zero_protocol::mux::Frame,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        destination: Destination,
    ) -> Result<(), String> {
        if first.status != zero_protocol::mux::STATUS_NEW
            || first.session_id == 0
            || destination.network != Network::Tcp
        {
            return Err("VLESS Mux currently accepts nonzero TCP NEW sessions only".into());
        }
        let (_, remote) = self
            .connect_vless_mux_target(&destination, peer, id, tag.clone())
            .await?;

        let outer = with_vless_response(boxed(outer));

        let server = self.clone();
        let route_tag = tag.clone();
        let route = move |target: Destination| {
            let server = server.clone();
            let route_tag = route_tag.clone();
            async move {
                server
                    .connect_vless_mux_target(&target, peer, id, route_tag)
                    .await
                    .map(|(_, stream)| stream)
                    .map_err(|error| {
                        std::io::Error::new(std::io::ErrorKind::ConnectionRefused, error)
                    })
            }
        };
        zero_protocol::mux::relay_server_pool(outer, first, remote, route)
            .await
            .map_err(|error| format!("VLESS Mux relay: {error}"))?;
        self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        Ok(())
    }

    async fn connect_vless_mux_target(
        &self,
        requested: &Destination,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
    ) -> Result<(Destination, zero_core::BoxStream), String> {
        let destination = self.restore_fake_destination(requested).await;
        let ctx = self.new_context(id, tag, destination.clone(), peer);
        let remote = match self.route(&ctx).await {
            Decision::Block => {
                self.stats.blocked.fetch_add(1, Ordering::Relaxed);
                return Err("VLESS Mux target is blocked".into());
            }
            Decision::Outbound(outbound_tag) | Decision::Balancer(outbound_tag) => {
                let outbound = self
                    .pick_outbound(&outbound_tag)
                    .ok_or_else(|| format!("no usable outbound for {outbound_tag:?}"))?;
                match &outbound.protocol {
                    OutboundProtocol::Freedom { .. } => outbound::connect_direct_with_resolver(
                        &destination,
                        &outbound.stream,
                        &self.resolver(),
                    )
                    .await
                    .map_err(|error| error.to_string())?,
                    OutboundProtocol::Vless(_)
                    | OutboundProtocol::Trojan(_)
                    | OutboundProtocol::Shadowsocks(_)
                    | OutboundProtocol::Vmess(_)
                    | OutboundProtocol::AnyTls(_)
                    | OutboundProtocol::Naive(_)
                    | OutboundProtocol::Socks(_)
                    | OutboundProtocol::Tor(_)
                    | OutboundProtocol::Psiphon(_)
                    | OutboundProtocol::MasterDns(_)
                    | OutboundProtocol::Tide(_)
                    | OutboundProtocol::Hysteria2(_)
                    | OutboundProtocol::Tuic(_)
                    | OutboundProtocol::Juicity(_)
                    | OutboundProtocol::AmneziaWireguard(_) => {
                        let stream = self
                            .open_outbound(&outbound, &destination)
                            .await
                            .map_err(|error| error.to_string())?;
                        outbound::strip_response(&outbound, stream)
                    }
                    other => {
                        return Err(format!(
                            "{} cannot carry a VLESS Mux TCP session",
                            other.name()
                        ))
                    }
                }
            }
            Decision::DirectVia { resolver } => {
                let resolver = self.resolver().for_tag(&resolver);
                outbound::connect_direct_with_resolver(
                    &destination,
                    &zero_config::StreamSettings::default(),
                    &resolver,
                )
                .await
                .map_err(|error| error.to_string())?
            }
        };
        Ok((destination, remote))
    }

    async fn handle_trojan(
        self: Arc<Self>,
        mut stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        config: &zero_config::TrojanInboundConfig,
        conn: &ConnInfo,
    ) -> Result<(), String> {
        let fallbacks = &config.fallbacks;
        let read =
            within_handshake(read_trojan_request(&mut stream, !fallbacks.is_empty())).await?;
        let (mut request, consumed, buffered) = match read {
            Ok(read) => read,
            Err((reason, seen)) => {
                return self
                    .fall_back(fallbacks, conn, stream, seen, peer, reason)
                    .await
            }
        };
        let Some(account) = config
            .password_hashes
            .iter()
            .position(|candidate| candidate == &request.password_hash)
        else {
            let reason = "Trojan password is not authorised".to_string();
            return self
                .fall_back(fallbacks, conn, stream, buffered, peer, reason)
                .await;
        };
        let email = config.emails.get(account).cloned().flatten();
        let early = buffered.len().saturating_sub(consumed);
        let stream = self.meter_account(email.as_ref(), &tag, peer, stream, early);
        request.destination = self.restore_fake_destination(&request.destination).await;
        if request.destination.network == Network::Udp {
            return self
                .handle_trojan_udp(stream, peer, id, tag, buffered[consumed..].to_vec())
                .await;
        }
        let mut destination = request.destination.clone();
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = email;
        let client = boxed(ChainedStream::new(buffered[consumed..].to_vec(), stream));
        let sniffing = self.sniffing_of(id);
        let client = self
            .sniff_client(&mut ctx, &mut destination, client, &sniffing)
            .await;
        let decision = self.route(&ctx).await;
        let Some((health, remote)) = self
            .connect_decided(decision, &destination, Some(peer))
            .await?
        else {
            return Ok(());
        };
        let outcome = relay(client, remote).await;
        if let Some(tag) = &health {
            self.record_outbound_observation(tag, &outcome);
        }
        self.record_observation(&outcome).await;
        // The outbound that carried the session is named in the counter, so a
        // panel can tell which outbound an account's traffic went through.
        // A session that went direct has no outbound to name.
        self.stats
            .record_tag_traffic(&ctx.inbound_tag, health.as_deref(), &outcome.transferred);
        self.stats
            .uploaded
            .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
        if outcome.is_useful() {
            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        } else {
            self.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
        Ok(())
    }

    async fn handle_shadowsocks(
        self: Arc<Self>,
        mut stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        config: &zero_config::ShadowsocksInboundConfig,
        users: Option<Result<Arc<zero_protocol::shadowsocks2022::ServerUsers>, String>>,
    ) -> Result<(), String> {
        let email_of = |user: usize| config.users.get(user).and_then(|u| u.email.clone());
        if config.multi_user && config.users.is_empty() {
            // Never the password instead: see `multi_user`.
            return Err("this Shadowsocks inbound has no account".into());
        }
        if config.method.is_2022() {
            let (stream, destination, email) = match users {
                Some(users) => {
                    let users = users?;
                    let (stream, destination, user) = within_handshake(
                        zero_protocol::shadowsocks2022::Stream::server_multi(stream, &users),
                    )
                    .await?
                    .map_err(|error| format!("reading Shadowsocks 2022 destination: {error}"))?;
                    (stream, destination, email_of(user))
                }
                None => {
                    let (stream, destination) = within_handshake(
                        zero_protocol::shadowsocks2022::Stream::server(
                            stream,
                            ss2022_method(config.method),
                            &config.password,
                        ),
                    )
                    .await?
                    .map_err(|error| format!("reading Shadowsocks 2022 destination: {error}"))?;
                    (stream, destination, config.email.clone())
                }
            };
            let stream = self.meter_account(email.as_ref(), &tag, peer, boxed(stream), 0);
            return self
                .complete_shadowsocks(stream, destination, peer, id, tag, email)
                .await;
        }
        let method = shadowsocks_method(config.method);
        let (stream, password, email): (zero_core::BoxStream, &str, _) = if !config.multi_user {
            (stream, &config.password, config.email.clone())
        } else {
            // Whose key sealed it shows only once the first chunk's length
            // opens; those bytes are then replayed to the stream that reads it.
            let mut head = vec![0u8; zero_protocol::shadowsocks::identify_len(method)];
            within_handshake(stream.read_exact(&mut head))
                .await?
                .map_err(|error| format!("reading Shadowsocks request: {error}"))?;
            let passwords: Vec<&[u8]> = config
                .users
                .iter()
                .map(|user| user.password.as_bytes())
                .collect();
            let user = zero_protocol::shadowsocks::identify_user(method, &head, &passwords)
                .ok_or_else(|| "Shadowsocks key is not authorised".to_string())?;
            (
                boxed(ChainedStream::new(head, stream)),
                &config.users[user].password,
                email_of(user),
            )
        };
        let mut stream =
            zero_protocol::shadowsocks::Stream::new_server(stream, method, password.as_bytes());
        let (destination, _) = within_handshake(stream.read_destination())
            .await?
            .map_err(|error| format!("reading Shadowsocks destination: {error}"))?;
        let stream = self.meter_account(email.as_ref(), &tag, peer, boxed(stream), 0);
        self.complete_shadowsocks(stream, destination, peer, id, tag, email)
            .await
    }

    async fn complete_shadowsocks(
        &self,
        stream: zero_core::BoxStream,
        destination: zero_core::Destination,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        email: Option<Arc<str>>,
    ) -> Result<(), String> {
        let mut destination = self.restore_fake_destination(&destination).await;
        let mut ctx = self.new_context(id, tag, destination.clone(), peer);
        ctx.user = email;
        let sniffing = self.sniffing_of(id);
        let client = self
            .sniff_client(&mut ctx, &mut destination, boxed(stream), &sniffing)
            .await;
        let decision = self.route(&ctx).await;
        let Some((health, remote)) = self
            .connect_decided(decision, &destination, Some(peer))
            .await?
        else {
            return Ok(());
        };
        let outcome = relay(client, remote).await;
        if let Some(tag) = &health {
            self.record_outbound_observation(tag, &outcome);
        }
        self.record_observation(&outcome).await;
        self.stats
            .uploaded
            .fetch_add(outcome.transferred.uploaded, Ordering::Relaxed);
        self.stats
            .downloaded
            .fetch_add(outcome.transferred.downloaded, Ordering::Relaxed);
        if outcome.is_useful() {
            self.stats.succeeded.fetch_add(1, Ordering::Relaxed);
        } else {
            self.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
        debug!(
            %peer,
            dest = %destination,
            up = outcome.transferred.uploaded,
            down = outcome.transferred.downloaded,
            stage = ?outcome.stage,
            error = ?outcome.error,
            "Shadowsocks session finished"
        );
        Ok(())
    }

    async fn handle_trojan_udp(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        buffered: Vec<u8>,
    ) -> Result<(), String> {
        let (mut reader, writer) = tokio::io::split(ChainedStream::new(buffered, stream));
        let (mut udp, replies) =
            UdpRelay::<()>::new(Arc::clone(&self), id, tag, 64, self.sniff_policy(id));
        let writer = AbortOnDrop(vec![tokio::spawn(write_udp_replies(
            writer,
            replies,
            Arc::clone(&self.stats),
            |reply: &UdpReply<()>| {
                zero_protocol::trojan::encode_udp_packet(&reply.source, &reply.payload)
            },
        ))]);
        let mut pending = Vec::with_capacity(2048);
        let mut scratch = vec![0u8; 16 * 1024];
        let mut seen = udp.activity();
        loop {
            let packet = match timeout(
                UDP_SESSION_IDLE,
                read_trojan_udp_packet(&mut reader, &mut pending, &mut scratch),
            )
            .await
            {
                Ok(packet) => packet?,
                Err(_) => {
                    let now = udp.activity();
                    if now == seen {
                        return Ok(());
                    }
                    seen = now;
                    continue;
                }
            };
            let Some((destination, payload)) = packet else {
                return Ok(());
            };
            if writer.0.iter().all(|task| task.is_finished()) {
                return Err("Trojan UDP client stopped accepting replies".into());
            }
            udp.dispatch((), peer, destination, payload).await;
        }
    }

    async fn handle_vless_udp(
        self: Arc<Self>,
        stream: zero_core::BoxStream,
        peer: SocketAddr,
        id: InboundId,
        tag: Arc<str>,
        destination: Destination,
        buffered: Vec<u8>,
    ) -> Result<(), String> {
        let stream = with_vless_response(stream);
        let (mut reader, writer) = tokio::io::split(ChainedStream::new(buffered, stream));
        let (mut udp, replies) =
            UdpRelay::<()>::new(Arc::clone(&self), id, tag, 4, self.sniff_policy(id));
        let writer = AbortOnDrop(vec![tokio::spawn(write_udp_replies(
            writer,
            replies,
            Arc::clone(&self.stats),
            |reply: &UdpReply<()>| zero_protocol::vless::encode_udp_frame(&reply.payload),
        ))]);
        let mut pending = Vec::new();
        let mut seen = udp.activity();
        loop {
            let payload = match timeout(
                UDP_SESSION_IDLE,
                read_vless_udp_frame(&mut reader, &mut pending),
            )
            .await
            {
                Ok(payload) => payload?,
                Err(_) => {
                    let now = udp.activity();
                    if now == seen {
                        return Ok(());
                    }
                    seen = now;
                    continue;
                }
            };
            let Some(payload) = payload else {
                return Ok(());
            };
            if writer.0.iter().all(|task| task.is_finished()) {
                return Err("VLESS UDP client stopped accepting replies".into());
            }
            udp.dispatch((), peer, destination.clone(), payload).await;
        }
    }

    async fn direct_udp(
        &self,
        resolver: &zero_dns::Resolver,
        datagram: &socks::UdpDatagram,
        stream: Option<&zero_config::StreamSettings>,
    ) -> Result<(Destination, Vec<u8>), String> {
        let noise = stream.map_or(&[][..], |stream| stream.evasion.udp_noise.as_slice());
        let policy = stream.and_then(|stream| stream.direct.as_deref());
        let destination = outbound::redirected(&datagram.destination, policy);
        let addrs = resolver
            .resolve_address(&destination.address, resolver.settings().query_strategy)
            .await
            .map_err(|error| error.to_string())?;
        let remote_socket = bind_outbound_udp(
            addrs.first().map(|ip| ip.is_ipv4()).unwrap_or(true),
            stream.map(|stream| &stream.sockopt),
        )
        .await
        .map_err(|e| format!("binding direct UDP socket: {e}"))?;
        let target = SocketAddr::new(
            *addrs
                .first()
                .ok_or_else(|| "resolver returned no UDP destinations".to_string())?,
            destination.port,
        );
        if let Some(policy) = policy {
            outbound::allowed_by_final_rules(policy, destination.network, vec![target])
                .await
                .map_err(|failure| failure.to_string())?;
        }
        // The first payload is sent after the decoys. This preserves the
        // configured wire order; sending the real datagram first would make
        // the noise visible only to a receiver that already knows the flow.
        for (packet, delay) in noise_policy(noise).plan() {
            if !packet.is_empty() {
                remote_socket
                    .send_to(&packet, target)
                    .await
                    .map_err(|error| format!("sending UDP noise: {error}"))?;
            }
            if !delay.is_zero() {
                tokio::time::sleep(delay).await;
            }
        }
        remote_socket
            .send_to(&datagram.payload, target)
            .await
            .map_err(|error| format!("sending UDP payload: {error}"))?;
        // One exchange per datagram, up to thousands at once: the buffer is
        // reserved but never zero-filled, so only what the answer touches is
        // ever written, and it becomes the reply itself instead of a copy.
        let mut response = Vec::with_capacity(65_535);
        let remote = timeout(
            Duration::from_secs(5),
            remote_socket.recv_buf_from(&mut response),
        )
        .await
        .map_err(|_| "UDP response timed out".to_string())?
        .map_err(|e| format!("receiving UDP response: {e}"))?
        .1;
        Ok((
            Destination::udp(Address::Ip(remote.ip()), remote.port()),
            response,
        ))
    }

    async fn proxy_udp(
        &self,
        outbound: &zero_config::Outbound,
        datagram: &socks::UdpDatagram,
    ) -> Result<(Destination, Vec<u8>), String> {
        let started = std::time::Instant::now();
        let result = timeout(
            UDP_EXCHANGE_DEADLINE,
            self.proxy_udp_inner(outbound, datagram),
        )
        .await
        .unwrap_or_else(|_| {
            Err(format!(
                "UDP exchange through {} timed out after {}s",
                outbound.tag,
                UDP_EXCHANGE_DEADLINE.as_secs()
            ))
        });
        let mut health = self
            .health
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        match result.is_ok() {
            true => health.record_success(&outbound.tag, started.elapsed()),
            false => health.record_failure(&outbound.tag),
        }
        result
    }

    async fn proxy_udp_inner(
        &self,
        outbound: &zero_config::Outbound,
        datagram: &socks::UdpDatagram,
    ) -> Result<(Destination, Vec<u8>), String> {
        // Datagrams cannot follow a `dialerProxy` chain yet. Sending them
        // straight to the server instead would show its address to the very
        // network the chain exists to hide it from, so refuse.
        if !matches!(self.resolve_chain(outbound), Ok(chain) if chain.len() == 1) {
            return Err(format!(
                "outbound {} runs through dialerProxy, which does not carry UDP yet",
                outbound.tag
            ));
        }
        // QUIC over a mux (`xudpProxyUDP443`): refused by default, so the
        // application falls back to TCP; `skip` sends it as plain UDP below.
        let quic = datagram.destination.port == 443;
        if outbound.mux.enabled && quic && outbound.mux.udp443 == zero_config::Udp443::Reject {
            return Err("UDP port 443 is refused on a mux outbound (xudpProxyUDP443)".into());
        }
        if outbound.mux.enabled && !(quic && outbound.mux.udp443 == zero_config::Udp443::Skip) {
            let carrier = outbound::connect_mux_carrier_with_resolver(outbound, &self.resolver())
                .await
                .map_err(|error| error.to_string())?;
            let (source, response) = timeout(
                Duration::from_secs(5),
                zero_protocol::mux::exchange_udp(
                    carrier,
                    datagram.destination.clone(),
                    &datagram.payload,
                    [0; 8],
                ),
            )
            .await
            .map_err(|_| "VLESS XUDP response timed out".to_string())?
            .map_err(|error| format!("VLESS XUDP exchange failed: {error}"))?;
            return Ok((
                source.unwrap_or_else(|| datagram.destination.clone()),
                response,
            ));
        }
        if let OutboundProtocol::AmneziaWireguard(wireguard) = &outbound.protocol {
            let (address, port) = outbound
                .endpoint()
                .ok_or_else(|| "AmneziaWG outbound has no endpoint".to_string())?;
            let peer_endpoints = self
                .resolver()
                .resolve_address(&address, self.resolver().settings().query_strategy)
                .await
                .map_err(|error| error.to_string())?
                .into_iter()
                .map(|ip| SocketAddr::new(ip, port))
                .collect::<Vec<_>>();
            let peer = *peer_endpoints
                .first()
                .ok_or_else(|| "AmneziaWG peer has no address".to_string())?;
            let stack = crate::warp::tunnel(wireguard, Some(peer)).await?;
            let destination = match &datagram.destination.address {
                Address::Ip(ip) => SocketAddr::new(*ip, datagram.destination.port),
                // Resolved inside the tunnel, like the TCP path.
                Address::Domain(name) => stack
                    .resolve(name)
                    .await?
                    .into_iter()
                    .find(|ip| stack.carries(*ip))
                    .map(|ip| SocketAddr::new(ip, datagram.destination.port))
                    .ok_or_else(|| "AmneziaWG destination has no usable address".to_string())?,
            };
            let result = stack.exchange_udp(destination, &datagram.payload).await;
            stack.report(&result);
            let (source, response) = result?;
            return Ok((
                Destination::udp(Address::Ip(source.ip()), source.port()),
                response,
            ));
        }
        if let OutboundProtocol::Tuic(tuic) = &outbound.protocol {
            let (address, port) = outbound
                .endpoint()
                .ok_or_else(|| "TUIC outbound has no endpoint".to_string())?;
            let addrs = self
                .resolver()
                .resolve_address(&address, self.resolver().settings().query_strategy)
                .await
                .map_err(|error| error.to_string())?
                .into_iter()
                .map(|ip| SocketAddr::new(ip, port))
                .collect::<Vec<_>>();
            let tls = outbound::tls_params(&outbound.stream, &address.host_string())
                .ok_or_else(|| "TUIC requires ordinary certificate TLS".to_string())?;
            return zero_transport::tuic::exchange_udp(
                &addrs,
                &tls,
                &tuic.uuid,
                &tuic.password,
                &datagram.destination,
                &datagram.payload,
            )
            .await;
        }
        if let OutboundProtocol::Juicity(juicity) = &outbound.protocol {
            let (address, port) = outbound
                .endpoint()
                .ok_or_else(|| "Juicity outbound has no endpoint".to_string())?;
            let addrs = self
                .resolver()
                .resolve_address(&address, self.resolver().settings().query_strategy)
                .await
                .map_err(|error| error.to_string())?
                .into_iter()
                .map(|ip| SocketAddr::new(ip, port))
                .collect::<Vec<_>>();
            let tls = outbound::tls_params(&outbound.stream, &address.host_string())
                .ok_or_else(|| "Juicity requires ordinary certificate TLS".to_string())?;
            return zero_transport::juicity::exchange_udp(
                &addrs,
                &tls,
                &juicity.uuid,
                &juicity.password,
                &datagram.destination,
                &datagram.payload,
            )
            .await;
        }
        if let OutboundProtocol::Hysteria2(hysteria) = &outbound.protocol {
            let (address, port) = outbound
                .endpoint()
                .ok_or_else(|| "Hysteria2 outbound has no endpoint".to_string())?;
            let addrs = self
                .resolver()
                .resolve_address(&address, self.resolver().settings().query_strategy)
                .await
                .map_err(|error| error.to_string())?
                .into_iter()
                .map(|ip| SocketAddr::new(ip, port))
                .collect::<Vec<_>>();
            let tls = outbound::tls_params(&outbound.stream, &address.host_string())
                .ok_or_else(|| "Hysteria2 requires ordinary certificate TLS".to_string())?;
            let shape = outbound::hysteria2_shape(outbound, hysteria)?;
            return zero_transport::hysteria2::exchange_udp(
                &addrs,
                &tls,
                &hysteria.password,
                &shape,
                &datagram.destination,
                &datagram.payload,
            )
            .await;
        }
        let stream =
            outbound::connect_with_resolver(outbound, &datagram.destination, &self.resolver())
                .await
                .map_err(|error| error.to_string())?;
        let mut stream = outbound::strip_response(outbound, stream);
        match &outbound.protocol {
            OutboundProtocol::Vless(_) => {
                let frame = zero_protocol::vless::encode_udp_frame(&datagram.payload)?;
                stream
                    .write_all(&frame)
                    .await
                    .map_err(|error| format!("writing VLESS UDP frame: {error}"))?;
                stream
                    .flush()
                    .await
                    .map_err(|error| format!("flushing VLESS UDP frame: {error}"))?;
                let mut length = [0u8; 2];
                timeout(Duration::from_secs(5), stream.read_exact(&mut length))
                    .await
                    .map_err(|_| "VLESS UDP response timed out".to_string())?
                    .map_err(|error| format!("reading VLESS UDP length: {error}"))?;
                let length = u16::from_be_bytes(length) as usize;
                if length == 0 {
                    return Err("VLESS returned an empty UDP response".into());
                }
                let mut response = vec![0u8; length];
                stream
                    .read_exact(&mut response)
                    .await
                    .map_err(|error| format!("reading VLESS UDP payload: {error}"))?;
                Ok((datagram.destination.clone(), response))
            }
            OutboundProtocol::Trojan(_) => {
                let frame = zero_protocol::trojan::encode_udp_packet(
                    &datagram.destination,
                    &datagram.payload,
                )?;
                stream
                    .write_all(&frame)
                    .await
                    .map_err(|error| format!("writing Trojan UDP frame: {error}"))?;
                stream
                    .flush()
                    .await
                    .map_err(|error| format!("flushing Trojan UDP frame: {error}"))?;
                // Starts small and grows with the frame, up to the frame limit:
                // a DNS answer never needs the 64 KiB a full frame would.
                const FRAME_LIMIT: usize = 65_535;
                let mut response: Vec<u8> = Vec::with_capacity(2048);
                loop {
                    let remaining = FRAME_LIMIT - response.len();
                    let mut room = bytes::BufMut::limit(&mut response, remaining);
                    let n = stream
                        .read_buf(&mut room)
                        .await
                        .map_err(|error| format!("reading Trojan UDP response: {error}"))?;
                    if n == 0 {
                        return Err("Trojan closed before returning a UDP response".into());
                    }
                    if let Ok((destination, payload, _)) =
                        zero_protocol::trojan::decode_udp_packet(&response)
                    {
                        return Ok((destination, payload));
                    }
                    if response.len() >= FRAME_LIMIT {
                        return Err("Trojan UDP response exceeded the frame limit".into());
                    }
                }
            }
            OutboundProtocol::Vmess(_) => {
                stream
                    .write_all(&datagram.payload)
                    .await
                    .map_err(|error| format!("writing VMess UDP payload: {error}"))?;
                stream
                    .flush()
                    .await
                    .map_err(|error| format!("flushing VMess UDP payload: {error}"))?;
                let mut payload = Vec::with_capacity(65_535);
                let n = stream
                    .read_buf(&mut payload)
                    .await
                    .map_err(|error| format!("reading VMess UDP response: {error}"))?;
                if n == 0 {
                    return Err("VMess closed before returning a UDP response".into());
                }
                Ok((datagram.destination.clone(), payload))
            }
            other => Err(format!("{} cannot carry UDP", other.name())),
        }
    }

    /// Pick a concrete outbound, expanding a balancer tag if needed.
    async fn route(&self, ctx: &SessionContext) -> Decision {
        // The first route of a session happens after its client authenticated.
        crate::usage::confirm_current();
        let resolved = match (
            ctx.destination.address.as_domain(),
            self.config().routing.domain_strategy,
        ) {
            (Some(_), zero_config::routing::DomainStrategy::AsIs) => None,
            (Some(domain), _) => self
                .resolver()
                .lookup(domain, self.resolver().settings().query_strategy)
                .await
                .ok()
                .and_then(|addresses| addresses.into_iter().next()),
            _ => None,
        };
        let decision = self.router().route(ctx, resolved);
        self.adapt_sanctioned(ctx, decision).await
    }

    /// A sanctioned name goes direct only through a resolver measured to
    /// relay it here, and only when that resolver's answer is its relay.
    /// Otherwise a direct connection would reach the service from an Iranian
    /// address and be refused, so the name goes the default way (the tunnel).
    /// Until the first measurement, the configured behaviour stands.
    fn default_tunnel_decision(&self) -> Decision {
        let config = self.config();
        match config.default_outbound() {
            Some(outbound) => Decision::Outbound(outbound.tag.clone()),
            None => Decision::Block,
        }
    }

    async fn adapt_sanctioned(&self, ctx: &SessionContext, decision: Decision) -> Decision {
        let Decision::DirectVia { resolver } = &decision else {
            return decision;
        };
        if resolver.as_ref() != crate::sanction_dns::TAG {
            return decision;
        }
        let sniffed = ctx.sniffed.domain.as_deref();
        let name = ctx.destination.address.as_domain().or(sniffed);
        let Some(state) = self
            .sanction
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner())
            .clone()
        else {
            // Not measured yet: a direct connection to a relay that may
            // present the wrong certificate would break HSTS sites for good.
            self.announce_sanction(name, "the anti-sanction resolver is not measured yet");
            return self.default_tunnel_decision();
        };
        let tunnel = || self.default_tunnel_decision();
        let Some(pinned) = state.pinned_tag() else {
            self.announce_sanction(name, "no anti-sanction resolver relays on this network");
            return tunnel();
        };
        // Only a name can be checked against the relay; an address with no
        // name (an IP literal, QUIC without SNI) goes the safe way.
        let Some(domain) = name else {
            return tunnel();
        };
        let answers = self
            .resolver()
            .for_tag(&pinned)
            .lookup(domain, zero_config::dns::QueryStrategy::UseIpv4)
            .await
            .unwrap_or_default();
        if state.relays(&answers) {
            self.announce_sanction(name, "sent through the anti-sanction relay");
            Decision::DirectVia {
                resolver: pinned.into(),
            }
        } else {
            self.announce_sanction(name, "the anti-sanction resolver does not relay it");
            tunnel()
        }
    }

    /// Say once per name, at info level, which way a sanctioned name went and
    /// why. A name that "does not work" is otherwise a silent routing choice;
    /// with the app's detailed log on this shows what was decided. Bounded, so
    /// a long session cannot grow it without limit.
    fn announce_sanction(&self, name: Option<&str>, verdict: &str) {
        const LIMIT: usize = 256;
        let Some(name) = name else { return };
        let mut seen = self
            .announced
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        if seen.len() < LIMIT && seen.insert(format!("{name}|{verdict}")) {
            info!(%name, "anti-sanction: {verdict}");
        }
    }

    /// What this server has measured about built-in techniques on the
    /// current network, as `(method id, worked)` for the crowd report. Only
    /// ids from the fixed vocabulary; nothing about the user's own configs.
    pub fn method_observations(&self) -> Vec<(&'static str, bool)> {
        let mut observed = crate::cdn_check::observations(self.stats.cdn_condition()).to_vec();
        observed.extend(self.tls_observations());
        let sanction = self
            .sanction
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner())
            .clone();
        if let Some(id) = sanction.as_ref().and_then(crate::sanction_dns::method_id) {
            observed.push((id, true));
        }
        observed
    }

    /// Whether TLS servers got through as is and whether they did with the
    /// ClientHello split, from the health the sessions and probes already
    /// recorded — nothing is sent to find out. A kind that was not tried is
    /// not reported.
    fn tls_observations(&self) -> Vec<(&'static str, bool)> {
        let config = self.config();
        let health = self
            .health
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        let mut plain = None::<bool>;
        let mut fragment = None::<bool>;
        for outbound in config.outbounds.iter() {
            let zero_config::Security::Tls(tls) = &outbound.stream.security else {
                continue;
            };
            if tls.ech.is_some() {
                continue;
            }
            let sample = health.sample(&outbound.tag);
            if sample.successes + sample.failures == 0 {
                continue;
            }
            let slot = if outbound.stream.evasion.tcp_fragment.is_some() {
                &mut fragment
            } else {
                &mut plain
            };
            *slot = Some(slot.unwrap_or(false) || sample.successes > 0);
        }
        let mut observed = Vec::new();
        if let Some(ok) = plain {
            observed.push(("tls:plain", ok));
        }
        if let Some(ok) = fragment {
            observed.push(("tls:fragment", ok));
        }
        observed
    }

    /// Keep the anti-sanction measurement current: at start, after a network
    /// change, and every [`crate::sanction_dns::RECHECK`].
    async fn run_sanction_watch(self: Arc<Self>) {
        use crate::sanction_dns;
        loop {
            let candidates = sanction_dns::candidates(&self.config().dns);
            if !candidates.is_empty() {
                let state = sanction_dns::probe(&candidates).await;
                let mut slot = self
                    .sanction
                    .lock()
                    .unwrap_or_else(|poisoned| poisoned.into_inner());
                if slot.as_ref() != Some(&state) {
                    info!(
                        chosen = ?state.chosen,
                        relay = ?state.relay,
                        candidates = candidates.len(),
                        "anti-sanction resolver measured"
                    );
                }
                *slot = Some(state);
            }
            tokio::select! {
                _ = tokio::time::sleep(sanction_dns::RECHECK) => {}
                _ = crate::cdn_check::NETWORK_CHANGED.notified() => {}
            }
        }
    }

    /// Open `outbound` to `destination`, following `sockopt.dialerProxy`
    /// and using a warm carrier when one is ready ([`crate::warm`]).
    ///
    /// A chain is resolved hop by hop — each hop's own `dialerProxy` too — so
    /// every server behind the first is reached only through the one before
    /// it and never dialled directly. Loops and chains deeper than
    /// [`MAX_CHAIN`] are refused before anything is dialled.
    async fn open_outbound(
        &self,
        outbound: &zero_config::Outbound,
        destination: &Destination,
    ) -> Result<zero_core::BoxStream, zero_core::Failure> {
        if !outbound::warmable(outbound) {
            return self.open_cold(outbound, destination).await;
        }
        let key = crate::warm::key(outbound);
        if let Some(carrier) = self.warm.take(key) {
            match outbound::finish_carrier(outbound, carrier, destination).await {
                Ok(stream) => {
                    debug!(outbound = %outbound.tag, "used a warm carrier");
                    self.prepare_carrier(outbound, key);
                    return Ok(stream);
                }
                // A carrier that died unnoticed costs a retry, not a request.
                Err(error) => debug!(outbound = %outbound.tag, %error, "warm carrier failed"),
            }
        }
        let opened = self.open_cold(outbound, destination).await;
        if opened.is_ok() {
            self.prepare_carrier(outbound, key);
        }
        opened
    }

    /// Open `outbound` with nothing prepared.
    async fn open_cold(
        &self,
        outbound: &zero_config::Outbound,
        destination: &Destination,
    ) -> Result<zero_core::BoxStream, zero_core::Failure> {
        if outbound.stream.sockopt.dialer_proxy.is_none() {
            return outbound::connect_with_resolver(outbound, destination, &self.resolver()).await;
        }
        let chain = self.resolve_chain(outbound)?;
        let resolver = self.resolver();
        // A `dialerProxy` that only names a direct, fragmenting outbound
        // leaves one hop: the exit, dialled directly with that outbound's
        // fragmentation.
        if chain.len() == 1 {
            return outbound::connect_with_resolver(&chain[0], destination, &resolver).await;
        }
        // A Tide exit asks for its connections itself, as many as it needs.
        if matches!(chain[0].protocol, OutboundProtocol::Tide(_)) {
            let chain: Arc<[zero_config::Outbound]> = Arc::from(chain);
            let (route, carrier) = tide_carrier(&chain, 0, &resolver);
            return outbound::connect_tide_via(&chain[0], destination, &route, carrier).await;
        }
        Box::pin(outbound::within_setup_deadline(async {
            let carried = Box::pin(carry_to_exit(&chain, &resolver)).await?;
            Box::pin(outbound::connect_over(&chain[0], carried, destination)).await
        }))
        .await
    }

    /// The outbounds a connection through `outbound` passes: `outbound`
    /// (the exit) first, then each hop that carries the one before it.
    ///
    /// A `freedom` outbound named as a `dialerProxy` is not a hop. It stands
    /// for "dial the TCP connection the way that outbound does", which is how
    /// panels ask for a fragmented ClientHello (`"dialerProxy": "fragment"`).
    /// So its fragmentation is copied onto the outbound it dials for, when
    /// that outbound can take it (a plain or certificate-TLS one that has no
    /// ECH and no shaping of its own; fragmenting REALITY or ShadowTLS breaks
    /// them), and the chain ends there.
    fn resolve_chain(
        &self,
        outbound: &zero_config::Outbound,
    ) -> Result<Vec<zero_config::Outbound>, zero_core::Failure> {
        use zero_core::{Failure, FailureKind, Stage};
        let refuse = |detail: String| {
            Failure::new(FailureKind::LocalPolicy, Stage::SocketConnected).with_detail(detail)
        };
        let mut chain = vec![outbound.clone()];
        let mut next = outbound.stream.sockopt.dialer_proxy.clone();
        while let Some(tag) = next {
            if chain.iter().any(|hop| *hop.tag == *tag) {
                return Err(refuse(format!("dialerProxy loop through {tag:?}")));
            }
            if chain.len() >= MAX_CHAIN {
                return Err(refuse(format!(
                    "dialerProxy chain is longer than {MAX_CHAIN} hops"
                )));
            }
            let hop = self
                .pick_outbound(&tag)
                .ok_or_else(|| refuse(format!("dialerProxy {tag:?} is not a usable outbound")))?;
            if matches!(hop.protocol, OutboundProtocol::Freedom { .. }) {
                if let Some(dialed) = chain.last_mut() {
                    lend_direct_dial(dialed, &hop);
                }
                break;
            }
            next = hop.stream.sockopt.dialer_proxy.clone();
            chain.push(hop);
        }
        // Mux is an optimisation of how many streams share a connection, and
        // a chained hop opens one connection per stream (the hops cannot be
        // multiplexed here), so the setting is dropped rather than refusing
        // a chain a panel built with it on.
        if chain.len() > 1 {
            for hop in &mut chain {
                hop.mux.enabled = false;
            }
        }
        Ok(chain)
    }

    /// Prepare the next connection for `outbound` in the background, unless
    /// one is ready or on its way, or the pool is full.
    fn prepare_carrier(&self, outbound: &zero_config::Outbound, key: u64) {
        if !self.warm.begin(key) {
            return;
        }
        let chain = match self.resolve_chain(outbound) {
            Ok(chain) => chain,
            Err(_) => {
                self.warm.finish(key, None);
                return;
            }
        };
        let resolver = self.resolver();
        let pool = Arc::clone(&self.warm);
        tokio::spawn(async move {
            let opened = Box::pin(outbound::within_setup_deadline(async {
                let exit = &chain[0];
                let (secured, host) = if chain.len() == 1 {
                    Box::pin(outbound::open_secured(exit, &resolver)).await?
                } else {
                    let carried = Box::pin(carry_to_exit(&chain, &resolver)).await?;
                    Box::pin(outbound::secure_over(exit, carried)).await?
                };
                Box::pin(outbound::open_carrier(exit, secured, &host)).await
            }))
            .await;
            pool.finish(key, opened.ok());
        });
    }

    /// The portal behind outbound `tag`, made the first time it is asked for.
    fn portal(&self, tag: &Arc<str>, domain: &Arc<str>) -> Arc<crate::reverse::Portal> {
        let mut portals = self
            .portals
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        match portals.get(tag) {
            Some(portal) if portal.domain() == &**domain => Arc::clone(portal),
            _ => {
                let portal = crate::reverse::Portal::new(Arc::clone(domain));
                portals.insert(Arc::clone(tag), Arc::clone(&portal));
                portal
            }
        }
    }

    /// The dial-in of a VLESS reverse bridge: a connection to the portal
    /// through outbound `via`, which sends it as the reverse command.
    async fn bridge_dial_via(
        &self,
        via: &str,
        destination: &Destination,
    ) -> std::io::Result<zero_core::BoxStream> {
        match self
            .connect_balanced(via, destination)
            .await
            .map_err(std::io::Error::other)?
        {
            Some((_, stream)) => Ok(stream),
            None => Err(std::io::Error::new(
                std::io::ErrorKind::PermissionDenied,
                "the bridge's outbound refused the dial-in",
            )),
        }
    }

    /// One connection of a reverse-proxy bridge `tag`, to `destination`,
    /// routed as if it had arrived on an inbound of that name: the dial-in to
    /// the portal, or what one of the portal's sessions asks for.
    async fn bridge_connect(
        &self,
        tag: Arc<str>,
        destination: Destination,
    ) -> std::io::Result<zero_core::BoxStream> {
        let other = |error: String| std::io::Error::other(error);
        let unspecified = SocketAddr::from(([0, 0, 0, 0], 0));
        let ctx = self.new_context(InboundId(u32::MAX), tag, destination.clone(), unspecified);
        let decision = self.route(&ctx).await;
        match self
            .connect_decided(decision, &destination, None)
            .await
            .map_err(other)?
        {
            Some((_, stream)) => Ok(stream),
            None => Err(std::io::Error::new(
                std::io::ErrorKind::PermissionDenied,
                "routing refused the bridge connection",
            )),
        }
    }

    /// [`Self::connect_balanced_once`], after following any `loopback`
    /// outbounds: a loopback is not a connection but a second look at the
    /// routing, as if the session had arrived on another inbound, so it is
    /// followed in a loop here and the connection is made once, by whatever
    /// the last look chose. Following it in a loop (and not by calling back
    /// into the connector) keeps the stack flat however it is configured.
    ///
    /// The rule it keeps: a chain of loopbacks ends. After
    /// [`MAX_LOOPBACK_DEPTH`] hops the session is refused, so rules that send
    /// a flow round in a circle fail it instead of spinning.
    ///
    /// Only an outbound named by its own tag is followed; a loopback that is
    /// a member of a balancer is refused when it is picked.
    async fn connect_balanced(
        &self,
        tag: &str,
        destination: &Destination,
    ) -> Result<Option<(zero_config::Outbound, zero_core::BoxStream)>, String> {
        let mut tag = std::borrow::Cow::Borrowed(tag);
        for _ in 0..=MAX_LOOPBACK_DEPTH {
            let config = self.config();
            let Some(OutboundProtocol::Loopback { inbound_tag }) =
                config.outbound_by_tag(&tag).map(|o| &o.protocol)
            else {
                return self.connect_balanced_once(&tag, destination).await;
            };
            let index = config
                .inbounds
                .iter()
                .position(|inbound| inbound.tag == *inbound_tag)
                .ok_or_else(|| format!("loopback names an unknown inbound {inbound_tag:?}"))?;
            let ctx = SessionContext::new(
                self.generation(),
                InboundId(index as u32),
                Arc::clone(inbound_tag),
                destination.clone(),
            );
            match self.route(&ctx).await {
                Decision::Outbound(next) | Decision::Balancer(next) => {
                    tag = std::borrow::Cow::Owned(next.to_string());
                }
                Decision::Block => return Ok(None),
                Decision::DirectVia { resolver } => {
                    let resolver = self.resolver().for_tag(&resolver);
                    let stream = outbound::connect_direct_with_resolver(
                        destination,
                        &zero_config::StreamSettings::default(),
                        &resolver,
                    )
                    .await
                    .map_err(|error| error.to_string())?;
                    return Ok(Some((loopback_direct(), stream)));
                }
            }
        }
        Err(format!(
            "loopback went round more than {MAX_LOOPBACK_DEPTH} times"
        ))
    }

    /// Open a connection to `destination` through `tag`, an outbound or a
    /// balancer, and return the outbound that carried it. `Ok(None)` is a
    /// black hole: the session is refused, not failed.
    ///
    /// For a balancer, one dead or silent member must cost a slow session,
    /// not a failed one:
    ///
    /// * a member that fails to connect is noted in the health table and the
    ///   next best is tried, once;
    /// * a member that has not connected after [`HEDGE_AFTER`] gets a second
    ///   attempt through the next best, in parallel, and whichever connects
    ///   first carries the session (the other is dropped where it stands).
    ///
    /// Trade-off: a server that is merely slow to set up (a cold Worker) gets
    /// a second, wasted connection attempt now and then.
    async fn connect_balanced_once(
        &self,
        tag: &str,
        destination: &Destination,
    ) -> Result<Option<(zero_config::Outbound, zero_core::BoxStream)>, String> {
        let first = self
            .pick_outbound(tag)
            .ok_or_else(|| format!("no usable outbound for {tag:?}"))?;
        let start = |ob: zero_config::Outbound| {
            Box::pin(async move { self.connect_session(&ob, destination).await })
        };
        let mut attempt_a = start(first.clone());
        if self.config().balancer_by_tag(tag).is_none() {
            return attempt_a.await.map(|r| r.map(|stream| (first, stream)));
        }
        let note_failure = |ob: &zero_config::Outbound, error: &str| {
            debug!(outbound = %ob.tag, %error, "connect failed");
            self.health
                .lock()
                .unwrap_or_else(|poisoned| poisoned.into_inner())
                .record_failure(&ob.tag);
        };
        // The first member gets HEDGE_AFTER to connect on its own.
        let early = tokio::select! {
            result = &mut attempt_a => Some(result),
            () = tokio::time::sleep(HEDGE_AFTER) => None,
        };
        let mut skip = vec![first.tag.clone()];
        let mut second_error = None;
        let a_done = early.is_some();
        match early {
            Some(Ok(connected)) => return Ok(connected.map(|stream| (first, stream))),
            Some(Err(error)) => {
                note_failure(&first, &error);
                second_error = Some(error);
            }
            None => {}
        }
        let Some(second) = self.pick_outbound_skipping(tag, &skip) else {
            // Nothing else to turn to: wait for the first as long as it takes.
            return if a_done {
                Err(second_error.unwrap_or_default())
            } else {
                attempt_a.await.map(|r| r.map(|stream| (first, stream)))
            };
        };
        skip.push(second.tag.clone());
        let mut attempt_b = start(second.clone());
        // Both in flight (or only the second, when the first already failed):
        // the first to connect wins.
        let mut a_open = !a_done;
        let mut b_open = true;
        let mut last_error = second_error.unwrap_or_default();
        while a_open || b_open {
            tokio::select! {
                result = &mut attempt_a, if a_open => match result {
                    Ok(connected) => return Ok(connected.map(|stream| (first, stream))),
                    Err(error) => {
                        note_failure(&first, &error);
                        a_open = false;
                        last_error = error;
                    }
                },
                result = &mut attempt_b, if b_open => match result {
                    Ok(connected) => return Ok(connected.map(|stream| (second, stream))),
                    Err(error) => {
                        note_failure(&second, &error);
                        b_open = false;
                        last_error = error;
                    }
                },
            }
        }
        Err(last_error)
    }

    /// Open the connection to `destination` through `ob`: `Ok(None)` for a
    /// black hole (the session is refused, not failed).
    async fn connect_session(
        &self,
        ob: &zero_config::Outbound,
        destination: &Destination,
    ) -> Result<Option<zero_core::BoxStream>, String> {
        match &ob.protocol {
            OutboundProtocol::Freedom { .. } => {
                outbound::connect_direct_with_resolver(destination, &ob.stream, &self.resolver())
                    .await
                    .map(Some)
                    .map_err(|e| e.to_string())
            }
            OutboundProtocol::Blackhole { response: None } => Ok(None),
            // A canned answer: the client reads it, then the connection ends.
            OutboundProtocol::Blackhole {
                response: Some(response),
            } => {
                let (near, mut far) = tokio::io::duplex(64 * 1024);
                let response = Arc::clone(response);
                tokio::spawn(async move {
                    let _ = far.write_all(&response).await;
                    let _ = far.shutdown().await;
                });
                Ok(Some(zero_core::boxed(near)))
            }
            OutboundProtocol::Loopback { .. } => {
                Err("a loopback outbound is followed by name, not as a member of a balancer".into())
            }
            OutboundProtocol::Portal { domain } => {
                let portal = self.portal(&ob.tag, domain);
                if portal.is_bridge(destination) {
                    // A bridge announcing itself: this connection is not
                    // forwarded, it becomes the carrier the portal runs its
                    // mux client on. The relay pumps bytes between the two.
                    let (near, far) = tokio::io::duplex(64 * 1024);
                    portal
                        .adopt(zero_core::boxed(far))
                        .map_err(|error| error.to_string())?;
                    return Ok(Some(zero_core::boxed(near)));
                }
                if destination.network != Network::Tcp {
                    return Err("a reverse-proxy portal carries TCP only".into());
                }
                portal
                    .open(destination)
                    .map(Some)
                    .map_err(|error| error.to_string())
            }
            OutboundProtocol::Vless(_)
            | OutboundProtocol::Trojan(_)
            | OutboundProtocol::Shadowsocks(_)
            | OutboundProtocol::Vmess(_)
            | OutboundProtocol::AnyTls(_)
            | OutboundProtocol::Naive(_)
            | OutboundProtocol::Socks(_)
            | OutboundProtocol::Tor(_)
            | OutboundProtocol::Psiphon(_)
            | OutboundProtocol::MasterDns(_)
            | OutboundProtocol::Tide(_)
            | OutboundProtocol::Hysteria2(_)
            | OutboundProtocol::Tuic(_)
            | OutboundProtocol::Juicity(_)
            | OutboundProtocol::AmneziaWireguard(_) => self
                .open_outbound(ob, destination)
                .await
                .map(|s| Some(outbound::strip_response(ob, s)))
                .map_err(|e| e.to_string()),
            other => Err(format!(
                "outbound protocol {} cannot carry a session",
                other.name()
            )),
        }
    }

    fn pick_outbound(&self, tag: &str) -> Option<zero_config::Outbound> {
        self.pick_outbound_skipping(tag, &[])
    }

    /// [`Self::pick_outbound`], leaving out the balancer members named in
    /// `skip` (the ones a connection just failed through). A plain outbound
    /// tag has no other member to turn to and is returned as it is.
    fn pick_outbound_skipping(
        &self,
        tag: &str,
        skip: &[Arc<str>],
    ) -> Option<zero_config::Outbound> {
        let config = self.config();
        let cdn = self.stats.cdn_condition();
        if let Some(o) = config.outbound_by_tag(tag) {
            let mut outbound = o.clone();
            self.apply_planner_strategy(&mut outbound);
            crate::cdn_check::apply(cdn, &mut outbound);
            return Some(outbound);
        }
        let b = config.balancer_by_tag(tag)?;
        let mut members = config.expand_balancer(b);
        members.retain(|id| !skip.contains(&config.outbounds[id.0 as usize].tag));
        // With the CDN unusable here, choose among the other members, if
        // there are any; a balancer of CDN configs only keeps trying them.
        if cdn == crate::cdn_check::CdnCondition::Blocked {
            let usable: Vec<_> = members
                .iter()
                .copied()
                .filter(|id| !crate::cdn_check::is_cloudflare_cdn(&config.outbounds[id.0 as usize]))
                .collect();
            if !usable.is_empty() {
                members = usable;
            }
        }
        if members.is_empty() {
            return None;
        }

        // Every member failing and a fallback named: the fallback carries the
        // traffic, and the members are tried again when a probe reaches one.
        if let Some(fallback) = b
            .fallback
            .as_deref()
            .and_then(|tag| config.outbound_by_tag(tag))
        {
            let tags: Vec<_> = members
                .iter()
                .map(|id| config.outbounds[id.0 as usize].tag.clone())
                .collect();
            let down = self
                .health
                .lock()
                .unwrap_or_else(|poisoned| poisoned.into_inner())
                .all_failing(&tags);
            if down {
                let mut outbound = fallback.clone();
                self.apply_planner_strategy(&mut outbound);
                crate::cdn_check::apply(cdn, &mut outbound);
                return Some(outbound);
            }
        }
        let ticket = self.selection_counter.fetch_add(1, Ordering::Relaxed);
        let index = match b.strategy {
            zero_config::routing::BalancerStrategy::LeastPing => {
                let tags = members
                    .iter()
                    .map(|id| config.outbounds[id.0 as usize].tag.clone())
                    .collect::<Vec<_>>();
                self.health
                    .lock()
                    .unwrap_or_else(|poisoned| poisoned.into_inner())
                    .choose(
                        &b.tag,
                        zero_observatory::BalancerHealthStrategy::LeastPing,
                        &tags,
                        ticket,
                    )
            }
            zero_config::routing::BalancerStrategy::LeastLoad => {
                let tags = members
                    .iter()
                    .map(|id| config.outbounds[id.0 as usize].tag.clone())
                    .collect::<Vec<_>>();
                self.health
                    .lock()
                    .unwrap_or_else(|poisoned| poisoned.into_inner())
                    .choose(
                        &b.tag,
                        zero_observatory::BalancerHealthStrategy::LeastLoad,
                        &tags,
                        ticket,
                    )
            }
            strategy => choose_balancer_index(strategy, ticket, members.len()),
        };
        let mut outbound = config.outbounds[members[index].0 as usize].clone();
        self.apply_planner_strategy(&mut outbound);
        crate::cdn_check::apply(cdn, &mut outbound);
        Some(outbound)
    }

    /// Keep [`Stats::cdn`] current: probe one Cloudflare CDN outbound when
    /// the server starts, when the network changes, and every so often.
    ///
    /// Anti-flapping: a working method is adopted at once (a success is
    /// proof), but "blocked" only after two failed probes in a row, so one bad
    /// moment on a working network does not switch every CDN config off.
    async fn run_cdn_watch(self: Arc<Self>) {
        use crate::cdn_check::{self, CdnCondition};
        let mut failures = 0u8;
        loop {
            // Only an outbound that is dialled directly can be probed as it
            // stands; one behind another hop would be dialled around it.
            let candidate = self
                .config()
                .outbounds
                .iter()
                .filter_map(|outbound| match self.resolve_chain(outbound) {
                    Ok(mut chain) if chain.len() == 1 => Some(chain.remove(0)),
                    _ => None,
                })
                .find(cdn_check::is_cloudflare_cdn);
            let wait = match candidate {
                None => {
                    self.stats
                        .cdn
                        .store(CdnCondition::Unknown.as_u8(), Ordering::Relaxed);
                    cdn_check::RECHECK
                }
                Some(outbound) => {
                    let found = cdn_check::probe(&outbound, &self.resolver()).await;
                    let previous = self.stats.cdn_condition();
                    let adopted = if found == CdnCondition::Blocked {
                        failures = failures.saturating_add(1);
                        if failures >= 2 || previous == CdnCondition::Unknown {
                            CdnCondition::Blocked
                        } else {
                            previous
                        }
                    } else {
                        failures = 0;
                        found
                    };
                    if adopted != previous {
                        info!(outbound = %outbound.tag, from = ?previous, to = ?adopted, "Cloudflare CDN condition changed");
                    }
                    self.stats.cdn.store(adopted.as_u8(), Ordering::Relaxed);
                    match (found, adopted) {
                        // Confirm a first failure soon rather than in 20 minutes.
                        (CdnCondition::Blocked, a) if a != CdnCondition::Blocked => {
                            Duration::from_secs(30)
                        }
                        (_, CdnCondition::Blocked) => cdn_check::RECHECK_BLOCKED,
                        _ => cdn_check::RECHECK,
                    }
                }
            };
            tokio::select! {
                _ = tokio::time::sleep(wait) => {}
                _ = cdn_check::NETWORK_CHANGED.notified() => failures = 0,
            }
        }
    }

    /// Materialise the planner's current rung for a new session. Every
    /// adaptation here either changes a compiled, bounded field or selects a
    /// separately validated outbound class; raw packet injection is kept out
    /// of this safe stream boundary.
    fn apply_planner_strategy(&self, outbound: &mut zero_config::Outbound) {
        let strategy =
            zero_observatory::PathStrategy::from_u8(self.planner_strategy.load(Ordering::Relaxed));
        self.apply_strategy_to(outbound, strategy);
    }

    /// Materialise one specific rung onto an outbound. Separated from the
    /// session path so a descent probe can test a rung without first making it
    /// live for real traffic.
    fn apply_strategy_to(
        &self,
        outbound: &mut zero_config::Outbound,
        strategy: zero_observatory::PathStrategy,
    ) {
        if let Some(candidate) = self.planner_candidate(strategy) {
            debug!(
                from = %outbound.tag,
                to = %candidate.tag,
                ?strategy,
                "planner switched outbound access class"
            );
            *outbound = candidate;
        }
        if strategy == zero_observatory::PathStrategy::FingerprintRotation {
            self.rotate_fingerprint(outbound);
        }
        if strategy == zero_observatory::PathStrategy::CdnCleanIp {
            self.apply_clean_ip(outbound);
        }
        if strategy == zero_observatory::PathStrategy::KeepaliveShaping
            && outbound.stream.evasion.keepalive.is_none()
        {
            // Size the shape from what was actually measured. With no
            // measurement — a probe testing this rung before any timeout has
            // been seen — fall back to the conservative default rather than
            // inventing a deadline.
            let observed = self.planner_flow_lifetime_ms.load(Ordering::Relaxed);
            let policy = (observed > 0)
                .then(|| {
                    zero_evasion::KeepalivePolicy::from_observed_reset(
                        std::time::Duration::from_millis(observed),
                    )
                })
                .flatten();
            let config = match policy {
                Some(policy) => zero_config::KeepaliveConfig {
                    idle_after: policy.idle_after,
                    max_flow_lifetime: policy.max_flow_lifetime,
                },
                None => zero_config::KeepaliveConfig::default(),
            };
            debug!(
                outbound = %outbound.tag,
                observed_ms = observed,
                idle_ms = config.idle_after.as_millis(),
                lifetime_ms = config.max_flow_lifetime.map(|l| l.as_millis()),
                "planner enabled keepalive shaping"
            );
            outbound.stream.evasion.keepalive = Some(config);
        }
        if matches!(
            strategy,
            zero_observatory::PathStrategy::ClientHelloFragment
                | zero_observatory::PathStrategy::SniDesync
        ) && !matches!(outbound.stream.security, zero_config::Security::None)
            && !matches!(
                &outbound.stream.security,
                zero_config::Security::Tls(zero_config::TlsConfig { ech: Some(_), .. })
            )
            && outbound.stream.evasion.tcp_fragment.is_none()
        {
            outbound.stream.evasion.tcp_fragment = Some(zero_config::FragmentConfig::default());
            debug!(
                outbound = %outbound.tag,
                ?strategy,
                "planner enabled ClientHello fragmentation"
            );
        }
        if strategy == zero_observatory::PathStrategy::SniDesync
            && !matches!(
                &outbound.stream.security,
                zero_config::Security::Tls(zero_config::TlsConfig { ech: Some(_), .. })
            )
        {
            outbound.stream.evasion.sni_desync = Some(zero_config::SniDesyncConfig::default());
        }
    }

    fn planner_candidate(
        &self,
        strategy: zero_observatory::PathStrategy,
    ) -> Option<zero_config::Outbound> {
        let config = self.config();
        config
            .outbounds
            .iter()
            .find(|candidate| match strategy {
                zero_observatory::PathStrategy::RealityXhttp => {
                    matches!(
                        &candidate.stream.transport,
                        zero_config::Transport::Xhttp(_)
                    ) && matches!(
                        &candidate.stream.security,
                        zero_config::Security::Reality(_)
                    )
                }
                zero_observatory::PathStrategy::CdnWebSocket
                | zero_observatory::PathStrategy::CdnAlternatePort
                | zero_observatory::PathStrategy::CdnCleanIp => {
                    matches!(
                        &candidate.stream.transport,
                        zero_config::Transport::WebSocket(_)
                            | zero_config::Transport::HttpUpgrade(_)
                            | zero_config::Transport::Grpc(_)
                            | zero_config::Transport::Xhttp(_)
                    ) && matches!(&candidate.stream.security, zero_config::Security::Tls(_))
                        && (strategy != zero_observatory::PathStrategy::CdnAlternatePort
                            || candidate.endpoint().is_some_and(|(_, port)| port != 443))
                }
                zero_observatory::PathStrategy::AmneziaWireguard => {
                    matches!(
                        &candidate.protocol,
                        zero_config::OutboundProtocol::AmneziaWireguard(_)
                    )
                }
                _ => false,
            })
            .cloned()
    }

    fn rotate_fingerprint(&self, outbound: &mut zero_config::Outbound) {
        const PROFILES: [zero_config::Fingerprint; 6] = [
            zero_config::Fingerprint::Chrome,
            zero_config::Fingerprint::Firefox,
            zero_config::Fingerprint::Safari,
            zero_config::Fingerprint::Edge,
            zero_config::Fingerprint::Ios,
            zero_config::Fingerprint::Android,
        ];
        let ticket = self.selection_counter.fetch_add(1, Ordering::Relaxed) as usize;
        match &mut outbound.stream.security {
            zero_config::Security::Tls(tls) => {
                tls.fingerprint = PROFILES[ticket % PROFILES.len()].clone()
            }
            zero_config::Security::Reality(reality) => {
                // Not every browser shape carries an X25519 key share, and a
                // REALITY hello without one cannot hide its tag. Rotating into
                // such a profile would turn a working connection into a silent
                // fallback to the decoy site, so the rotation draws only from
                // the shapes that can actually carry it.
                let usable: Vec<&zero_config::Fingerprint> = PROFILES
                    .iter()
                    .filter(|profile| profile.supports_reality())
                    .collect();
                if let Some(profile) = usable.get(ticket % usable.len().max(1)) {
                    reality.fingerprint = (*profile).clone();
                }
            }
            zero_config::Security::None => {}
            // ShadowTLS carries no configurable fingerprint: the client always
            // sends a fixed browser-shaped ClientHello, so there is nothing to
            // rotate.
            zero_config::Security::ShadowTls(_) => {}
        }
    }

    /// Materialise the best measured CDN edge only for the clean-IP rung. The
    /// original hostname is retained as SNI/Host so replacing the TCP address
    /// does not turn a fronted connection into certificate verification for an
    /// IP literal. A candidate is never used before the HTTP probe has shown
    /// application progress.
    fn apply_clean_ip(&self, outbound: &mut zero_config::Outbound) {
        let candidate = self
            .clean_ip_results
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner())
            .iter()
            .find(|result| result.success)
            .map(|result| (result.address.ip(), result.address.port()));
        let Some((ip, port)) = candidate else {
            return;
        };
        let Some((address, _)) = outbound.endpoint() else {
            return;
        };
        let Some(host) = address.as_domain().map(str::to_owned) else {
            return;
        };
        let replacement = Address::Ip(ip);
        replace_outbound_endpoint(outbound, replacement.clone(), port);
        preserve_stream_host(&mut outbound.stream, &host);
        if let zero_config::Transport::Xhttp(settings) = &mut outbound.stream.transport {
            if let Some(download) = &mut settings.xhttp_download {
                if let Some(download_host) = download.address.as_domain().map(str::to_owned) {
                    download.address = replacement;
                    download.port = port;
                    preserve_stream_host(&mut download.stream, &download_host);
                }
            }
        }
        debug!(outbound = %outbound.tag, %ip, port, "planner selected measured clean IP");
    }

    fn record_outbound_observation(&self, tag: &str, outcome: &crate::relay::RelayOutcome) {
        let mut health = self
            .health
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        // Liveness only: `outcome.elapsed` is the whole session, not a round
        // trip, so latency stays with the observatory's probes.
        if outcome.is_useful() {
            health.record_alive(tag);
        } else {
            health.record_failure(tag);
        }
    }

    async fn record_observation(&self, outcome: &crate::relay::RelayOutcome) {
        let mut planner = self.planner.lock().await;
        if outcome.is_useful() {
            zero_core::path_mss::note_progress();
            planner.record_success(outcome.stage, outcome.elapsed);
        } else {
            let kind = outcome
                .error
                .as_deref()
                .map(|error| crate::relay::classify_error(error, outcome.stage))
                .unwrap_or(zero_core::FailureKind::Unknown);
            // The black-hole signature: the server was reached, nothing came
            // back before the handshake timed out.
            if kind == zero_core::FailureKind::TlsTimeout
                && outcome.transferred.downloaded == 0
                && zero_core::path_mss::note_stall()
            {
                info!(
                    mss = zero_core::path_mss::current(),
                    "handshakes keep stalling; lowered the TCP segment size"
                );
            }
            let failure = zero_core::Failure::new(kind, outcome.stage)
                .with_bytes(outcome.transferred.uploaded + outcome.transferred.downloaded)
                .with_elapsed(outcome.elapsed)
                .with_detail(
                    outcome
                        .error
                        .clone()
                        .unwrap_or_else(|| "relay ended without useful progress".into()),
                );
            match planner.record_failure(&failure) {
                zero_observatory::Transition::Hold => {}
                zero_observatory::Transition::Climb { to } => {
                    info!(
                        ?to,
                        kind = kind.as_str(),
                        "planner climbed the evasion ladder"
                    );
                }
                zero_observatory::Transition::ClassChange { to, at } => {
                    // The loud one: the endpoint family itself is gone, and
                    // every session from here on uses a different class.
                    warn!(
                        class = ?to,
                        strategy = ?at,
                        kind = kind.as_str(),
                        "access class is unreachable; failing over"
                    );
                }
            }
        }
        self.planner_strategy
            .store(planner.current().as_u8(), Ordering::Relaxed);
        self.planner_flow_lifetime_ms.store(
            planner
                .observed_flow_lifetime()
                .map(|lifetime| lifetime.as_millis().min(u64::MAX as u128) as u64)
                .unwrap_or(0),
            Ordering::Relaxed,
        );
    }

    /// Periodically re-test one rung below the current one.
    ///
    /// Blocking in Iran is event-driven and often temporary. Without this a
    /// client that climbed to a CDN during a shutdown stays there indefinitely,
    /// paying the detour long after the direct path came back (PLAN-02 §5,
    /// "descend too"). The probe is a real connection through a real outbound,
    /// because a rung that merely opens a socket is not a rung that works.
    async fn run_strategy_descent(self: Arc<Self>) {
        const INTERVAL: Duration = Duration::from_secs(300);
        loop {
            tokio::time::sleep(INTERVAL).await;

            let candidate = {
                let mut planner = self.planner.lock().await;
                planner.schedule_downgrade_probe()
            };
            let Some(candidate) = candidate else { continue };

            let Some(config) = self.config().observatory.clone() else {
                // Without a probe target there is no way to test a rung
                // honestly, so the probe is withdrawn rather than guessed.
                let mut planner = self.planner.lock().await;
                planner.record_probe(candidate, false);
                continue;
            };
            let Ok(target) = parse_probe_target(&config.probe_url) else {
                let mut planner = self.planner.lock().await;
                planner.record_probe(candidate, false);
                continue;
            };

            let Some(mut outbound) = self.descent_probe_outbound(candidate) else {
                let mut planner = self.planner.lock().await;
                planner.record_probe(candidate, false);
                continue;
            };
            self.apply_strategy_to(&mut outbound, candidate);

            let succeeded = timeout(
                Duration::from_secs(15),
                self.probe_outbound(&outbound, &target),
            )
            .await
            .ok()
            .and_then(Result::ok)
            .is_some();

            let adopted = {
                let mut planner = self.planner.lock().await;
                let adopted = planner.record_probe(candidate, succeeded);
                self.planner_strategy
                    .store(planner.current().as_u8(), Ordering::Relaxed);
                adopted
            };
            if adopted {
                info!(
                    strategy = ?candidate,
                    "cheaper path is working again; descended the evasion ladder"
                );
            } else {
                debug!(strategy = ?candidate, succeeded, "descent probe did not adopt");
            }
        }
    }

    /// The outbound a descent probe should test: the class candidate for the
    /// lower rung, or the current default when the rung does not change class.
    fn descent_probe_outbound(
        &self,
        strategy: zero_observatory::PathStrategy,
    ) -> Option<zero_config::Outbound> {
        if let Some(candidate) = self.planner_candidate(strategy) {
            return Some(candidate);
        }
        let config = self.config();
        config
            .outbounds
            .iter()
            .find(|outbound| outbound.protocol.is_proxy())
            .cloned()
    }

    /// Keep routing rule sets current.
    ///
    /// The loop re-reads configuration every pass, so a reload can add, remove
    /// or retune assets without a restart. It sleeps for the retry interval
    /// after a failure and for the refresh interval otherwise, which keeps a
    /// permanently blocked mirror from being re-dialled in a tight loop — the
    /// situation a censored network produces by design.
    async fn run_asset_refresh(self: Arc<Self>) {
        // See `run_observatory`: a reload is the only way an asset block can
        // appear, and it wakes this task at once, so the periodic re-check
        // while none is configured only guards against a signal that never
        // arrives and is kept long to stay off the CPU on an idle session.
        const IDLE_RECHECK: Duration = Duration::from_secs(300);
        let mut config_changed = self.config_changed.subscribe();
        let mut first_pass = true;
        loop {
            // Snapshot the reload version before reading the config so a
            // reload racing the read below still wakes us (see run_observatory).
            config_changed.mark_unchanged();
            let config = self.config();
            let Some(assets) = config.assets.clone() else {
                tokio::select! {
                    _ = config_changed.changed() => {}
                    _ = tokio::time::sleep(IDLE_RECHECK) => {}
                }
                continue;
            };
            let specs = asset_specs(&assets);
            // The host supplies the files itself; they are loaded at start
            // and never re-fetched.
            if specs.is_empty() || !assets.auto_update {
                tokio::time::sleep(assets.refresh_interval).await;
                continue;
            }
            let store = asset_store(&assets);
            let force = first_pass && assets.refresh_on_start;
            first_pass = false;

            let outcomes = store.refresh_all(&specs, force).await;
            let mut any_failed = false;
            let mut changed = false;
            let mut statuses = Vec::with_capacity(outcomes.len());
            for (name, outcome) in &outcomes {
                let (label, detail, entries) = match outcome {
                    zero_router::RefreshOutcome::Fresh => ("fresh", None, None),
                    zero_router::RefreshOutcome::Unchanged => ("unchanged", None, None),
                    zero_router::RefreshOutcome::Updated { bytes, entries } => {
                        changed = true;
                        info!(asset = %name, bytes, entries, "rule set updated");
                        ("updated", None, Some(*entries))
                    }
                    zero_router::RefreshOutcome::Failed { reasons } => {
                        any_failed = true;
                        let detail = reasons.join("; ");
                        // Downloading rule sets over a censored network fails
                        // routinely. It is a warning, not an error: the cached
                        // copy keeps serving.
                        warn!(asset = %name, %detail, "rule set refresh failed; keeping the cached copy");
                        ("failed", Some(detail), None)
                    }
                };
                statuses.push(AssetStatus {
                    name: name.clone(),
                    outcome: label.into(),
                    detail,
                    entries,
                    at: std::time::SystemTime::now(),
                });
            }
            *self
                .asset_status
                .lock()
                .unwrap_or_else(|poisoned| poisoned.into_inner()) = statuses;

            if changed {
                let mut merged = zero_router::GeoData::from_environment();
                let (cached, problems) = store.load_geodata(&specs);
                for problem in &problems {
                    warn!(%problem, "rule set is unusable after refresh");
                }
                merged.merge(cached);
                let counts = (merged.geosite.len(), merged.geoip.len());
                self.geodata.store(Arc::new(merged));
                self.rebuild_router_for_new_geodata();
                info!(
                    geosite_tags = counts.0,
                    geoip_tags = counts.1,
                    "router recompiled against refreshed rule sets"
                );
            }

            let sleep = if any_failed {
                assets.retry_interval
            } else {
                assets.refresh_interval
            };
            tokio::time::sleep(sleep).await;
        }
    }

    /// Refresh every configured rule set immediately, bypassing the TTL, and
    /// recompile the router if anything changed. Used by the management API
    /// and the CLI; the periodic task keeps running independently.
    pub async fn refresh_assets_now(&self) -> serde_json::Value {
        let config = self.config();
        let Some(assets) = config.assets.clone() else {
            return serde_json::json!({"error": "no assets are configured"});
        };
        let specs = asset_specs(&assets);
        if specs.is_empty() {
            return serde_json::json!({"error": "no rule-set files are configured"});
        }
        let store = asset_store(&assets);
        let outcomes = store.refresh_all(&specs, true).await;
        let changed = outcomes.iter().any(|(_, outcome)| outcome.changed());
        if changed {
            let mut merged = zero_router::GeoData::from_environment();
            let (cached, _) = store.load_geodata(&specs);
            merged.merge(cached);
            self.geodata.store(Arc::new(merged));
            self.rebuild_router_for_new_geodata();
        }
        serde_json::json!({
            "changed": changed,
            "files": outcomes
                .iter()
                .map(|(name, outcome)| {
                    let (state, detail) = match outcome {
                        zero_router::RefreshOutcome::Fresh => ("fresh", None),
                        zero_router::RefreshOutcome::Unchanged => ("unchanged", None),
                        zero_router::RefreshOutcome::Updated { .. } => ("updated", None),
                        zero_router::RefreshOutcome::Failed { reasons } => {
                            ("failed", Some(reasons.join("; ")))
                        }
                    };
                    serde_json::json!({"name": name, "outcome": state, "detail": detail})
                })
                .collect::<Vec<_>>(),
        })
    }

    /// Rule-set freshness for the management API.
    pub fn asset_snapshot(&self) -> serde_json::Value {
        let statuses = self
            .asset_status
            .lock()
            .unwrap_or_else(|poisoned| poisoned.into_inner());
        let geodata = self.geodata.load();
        serde_json::json!({
            "geositeTags": geodata.geosite.len(),
            "geoipTags": geodata.geoip.len(),
            "files": statuses
                .iter()
                .map(|status| serde_json::json!({
                    "name": status.name,
                    "outcome": status.outcome,
                    "detail": status.detail,
                    "entries": status.entries,
                    "atUnixSeconds": status
                        .at
                        .duration_since(std::time::SystemTime::UNIX_EPOCH)
                        .map(|since| since.as_secs())
                        .unwrap_or_default(),
                }))
                .collect::<Vec<_>>(),
        })
    }

    async fn run_observatory(self: Arc<Self>) {
        // How long to re-check the configuration even when no reload has
        // signalled one. A reload is the only way an observatory block can
        // appear and it wakes this task at once, so this is just a safety net
        // against a signal that never arrives; it is kept long so an idle
        // session with no observatory barely touches the CPU.
        const IDLE_RECHECK: Duration = Duration::from_secs(300);
        let mut config_changed = self.config_changed.subscribe();
        loop {
            // Snapshot the reload version *before* reading the config, so a
            // reload that lands between the read and the wait below is seen as
            // a change and wakes us rather than being missed.
            config_changed.mark_unchanged();
            let Some(config) = self.config().observatory.clone() else {
                tokio::select! {
                    _ = config_changed.changed() => {}
                    _ = tokio::time::sleep(IDLE_RECHECK) => {}
                }
                continue;
            };
            let target = match parse_probe_target(&config.probe_url) {
                Ok(target) => target,
                Err(error) => {
                    error!(%error, "observatory probe URL rejected");
                    tokio::time::sleep(config.probe_interval).await;
                    continue;
                }
            };
            let snapshot = self.config();
            for outbound in snapshot.outbounds.iter() {
                if !outbound.protocol.is_proxy()
                    && !matches!(outbound.protocol, OutboundProtocol::Freedom { .. })
                {
                    continue;
                }
                if !config.subject_selector.is_empty()
                    && !config
                        .subject_selector
                        .iter()
                        .any(|selector| outbound.tag.starts_with(selector.as_ref()))
                {
                    continue;
                }
                let tag = outbound.tag.clone();
                let result = timeout(
                    Duration::from_secs(15),
                    self.probe_outbound(outbound, &target),
                )
                .await
                .ok()
                .and_then(Result::ok);
                let mut health = self
                    .health
                    .lock()
                    .unwrap_or_else(|poisoned| poisoned.into_inner());
                match result {
                    Some(elapsed) => health.record_success(&tag, elapsed),
                    None => health.record_failure(&tag),
                }
            }
            if let Some(clean_ip) = config.clean_ip.as_ref() {
                let candidates = if clean_ip.candidates.is_empty() {
                    zero_net::clean_ip::cloudflare_candidates(
                        clean_ip.host.as_ref(),
                        &zero_net::clean_ip::CDN_TLS_PORTS,
                        1,
                        1,
                    )
                } else {
                    clean_ip
                        .candidates
                        .iter()
                        .copied()
                        .map(|address| {
                            zero_net::clean_ip::CleanIpCandidate::new(
                                address,
                                clean_ip.host.as_ref(),
                            )
                        })
                        .collect::<Vec<_>>()
                };
                let results = zero_net::clean_ip::probe_http(
                    &candidates,
                    &clean_ip.path,
                    Duration::from_secs(15),
                )
                .await;
                let mut stored = self
                    .clean_ip_results
                    .lock()
                    .unwrap_or_else(|poisoned| poisoned.into_inner());
                *stored = results;
            }
            tokio::time::sleep(config.probe_interval).await;
        }
    }

    async fn probe_outbound(
        &self,
        outbound: &zero_config::Outbound,
        target: &ProbeTarget,
    ) -> Result<Duration, String> {
        let started = std::time::Instant::now();
        let mut stream = match &outbound.protocol {
            OutboundProtocol::Freedom { .. } => outbound::connect_direct_with_resolver(
                &target.destination,
                &outbound.stream,
                &self.resolver(),
            )
            .await
            .map_err(|error| error.to_string())?,
            OutboundProtocol::Blackhole { .. } | OutboundProtocol::Dns { .. } => {
                return Err("outbound cannot be probed".into())
            }
            _ => self
                .open_outbound(outbound, &target.destination)
                .await
                .map_err(|error| error.to_string())?,
        };
        let host = target.destination.address.host_string();
        if target.tls {
            // An https:// probe is a real, certificate-verified TLS request.
            // It used to send plain HTTP to port 443, which the server just
            // closes, so every balancer member failed every probe: the
            // balancer ranked servers (and Smart Fragment variants) at
            // random and routed browser traffic onto dead ones, and the
            // evasion ladder could never descend again. It is also the
            // stronger check: a path that answers plain HTTP but cannot
            // carry a verified TLS session is exactly what breaks browsing.
            // Unshaped: the probe already travels inside the tunnel, so its
            // own hello is not what the network sees.
            let params = zero_security::TlsParams::new(host.clone())
                .with_alpn(&["http/1.1"])
                .with_profile(zero_security::FingerprintProfile::Unshaped);
            let mut tls = zero_security::connect(stream, &params)
                .await
                .map_err(|failure| format!("probe TLS: {failure}"))?;
            http_probe_status(&mut tls, &host, &target.path).await?;
        } else {
            http_probe_status(&mut stream, &host, &target.path).await?;
        }
        Ok(started.elapsed())
    }

    /// Tell a client its destination could not be reached, unless it was
    /// already told the connection was open. A SOCKS client gets "host
    /// unreachable" and an HTTP client a 502, so the failure reaches it as an
    /// answer it can show, not as a connection that simply vanishes.
    async fn finish_unreachable(
        &self,
        stream: &mut zero_core::BoxStream,
        accepted: &Accepted,
        replied: bool,
    ) {
        if replied {
            return;
        }
        match accepted.kind {
            InboundKind::Socks5 => {
                let _ = socks::reply(stream, socks::REP_HOST_UNREACHABLE, None).await;
            }
            InboundKind::HttpConnect | InboundKind::HttpForward => {
                let _ = stream
                    .write_all(b"HTTP/1.1 502 Bad Gateway\r\nContent-Length: 0\r\n\r\n")
                    .await;
            }
        }
    }

    async fn finish_handshake(
        &self,
        stream: &mut zero_core::BoxStream,
        accepted: &Accepted,
        ok: bool,
        replied: bool,
    ) {
        if replied {
            return;
        }
        match accepted.kind {
            InboundKind::Socks5 => {
                let code = if ok {
                    socks::REP_SUCCESS
                } else {
                    socks::REP_NOT_ALLOWED
                };
                let _ = socks::reply(stream, code, None).await;
            }
            InboundKind::HttpConnect => {
                let msg: &[u8] = if ok {
                    socks::CONNECT_OK
                } else {
                    b"HTTP/1.1 403 Forbidden\r\nContent-Length: 0\r\n\r\n"
                };
                let _ = stream.write_all(msg).await;
            }
            // Plain HTTP forwarding has no handshake to complete; a blocked
            // request still deserves an answer rather than a silent close.
            InboundKind::HttpForward => {
                if !ok {
                    let _ = stream
                        .write_all(b"HTTP/1.1 403 Forbidden\r\nContent-Length: 0\r\n\r\n")
                        .await;
                }
            }
        }
    }
}

/// Reads whatever the client sends first, for at most 50 ms: enough for a
/// TLS ClientHello or an HTTP request head to name its destination.
async fn sniff_probe(stream: &mut zero_core::BoxStream) -> Vec<u8> {
    let mut buffer = vec![0u8; 8192];
    match timeout(Duration::from_millis(50), stream.read(&mut buffer)).await {
        Ok(Ok(read)) => {
            buffer.truncate(read);
            buffer
        }
        _ => Vec::new(),
    }
}

// ------------------------------------------------------------------ UDP relay

/// A datagram on its way back to the client side of a UDP ingress.
struct UdpReply<K> {
    key: K,
    /// Where the answer came from, as the client should see it.
    source: Destination,
    payload: Vec<u8>,
    /// The request's destination was a FakeDNS handle that was restored to a
    /// domain, so `source` is a real address the client never talked to.
    restored: bool,
}

/// The outbound recorded for a connection a loopback's second routing sent
/// direct through a resolver rule: it has no outbound of its own.
fn loopback_direct() -> zero_config::Outbound {
    zero_config::Outbound {
        tag: Arc::from("loopback-direct"),
        protocol: OutboundProtocol::Freedom {
            domain_strategy: zero_config::DomainStrategy::AsIs,
        },
        stream: zero_config::StreamSettings::default(),
        mux: zero_config::MuxConfig::default(),
    }
}

/// How many times a flow may be sent back through routing by `loopback`
/// outbounds before the connection is refused.
const MAX_LOOPBACK_DEPTH: u32 = 8;

/// What an inbound's `sniffing` block asks for, kept by value so a UDP relay
/// never keeps a configuration generation alive.
#[derive(Debug, Clone, Default)]
struct SniffPolicy {
    enabled: bool,
    quic: bool,
    route_only: bool,
    /// Names that never steer a flow (`domainsExcluded`).
    sniffing: Sniffing,
}

impl From<&Sniffing> for SniffPolicy {
    fn from(sniffing: &Sniffing) -> Self {
        Self {
            enabled: sniffing.enabled,
            quic: sniffing.sniff_quic,
            route_only: sniffing.route_only,
            sniffing: sniffing.clone(),
        }
    }
}

/// What became of one datagram.
#[derive(Debug)]
enum Dispatch {
    /// Handed to a flow, a proxy, or the resolver.
    Sent,
    /// Refused before anything left the process. The datagram comes back so a
    /// TUN ingress can quote it in an ICMP port-unreachable: a QUIC client
    /// waiting on a handshake that will never be answered stays on it until
    /// its own timer expires, while the ICMP error moves it to TCP at once.
    Rejected(Vec<u8>),
}

/// Send an ICMP port-unreachable for a datagram this proxy refused.
///
/// The packet goes straight to the device rather than back through the
/// userspace stack: it is addressed to the application's own address, so its
/// kernel is the one that has to see it, exactly as it would see one from a
/// host with nothing listening on the port.
async fn reject_udp(
    device: &dyn PacketOut,
    source: SocketAddr,
    target: SocketAddr,
    payload: &[u8],
) {
    match zero_tun::build_icmp_unreachable(source, target, payload) {
        Ok(packet) => device.send(&packet).await,
        Err(error) => debug!(%error, "could not build a port-unreachable notice"),
    }
}

/// Where the packets a userspace stack's owner writes itself (ICMP notices)
/// go: the TUN device, or a WireGuard server's link to its peers.
trait PacketOut: Send + Sync {
    fn send<'a>(
        &'a self,
        packet: &'a [u8],
    ) -> std::pin::Pin<Box<dyn std::future::Future<Output = ()> + Send + 'a>>;
}

impl PacketOut for zero_tun::TunDevice {
    fn send<'a>(
        &'a self,
        packet: &'a [u8],
    ) -> std::pin::Pin<Box<dyn std::future::Future<Output = ()> + Send + 'a>> {
        Box::pin(async move {
            if let Err(error) = zero_tun::TunDevice::send(self, packet).await {
                debug!(%error, "could not send a port-unreachable notice");
            }
        })
    }
}

impl PacketOut for tokio::sync::mpsc::Sender<Vec<u8>> {
    fn send<'a>(
        &'a self,
        packet: &'a [u8],
    ) -> std::pin::Pin<Box<dyn std::future::Future<Output = ()> + Send + 'a>> {
        Box::pin(async move {
            let _ = tokio::sync::mpsc::Sender::send(self, packet.to_vec()).await;
        })
    }
}

/// One direct (Freedom) UDP flow: an outbound socket owned by one client flow
/// and address family, plus the task that carries its answers back.
struct NatFlow {
    socket: Arc<UdpSocket>,
    reader: tokio::task::JoinHandle<()>,
    /// Milliseconds since the relay's epoch at which the flow last carried a
    /// datagram in either direction.
    last_active: Arc<AtomicU64>,
    /// Targets this flow has already sent its configured noise to. Noise
    /// precedes the first datagram to a peer, not every datagram.
    noised: std::collections::HashSet<SocketAddr>,
    restored: Arc<std::sync::atomic::AtomicBool>,
}

impl Drop for NatFlow {
    fn drop(&mut self) {
        self.reader.abort();
    }
}

/// One UDP flow carried through a Tide outbound. A task owns the datagram
/// flow, opening it on first use (which may take a handshake, so the relay
/// never waits on it) and carrying answers back; datagrams are handed to it
/// through a bounded queue and dropped when it is full, as a UDP socket would.
struct TideFlow {
    outgoing: tokio::sync::mpsc::Sender<(Destination, Vec<u8>)>,
    task: tokio::task::JoinHandle<()>,
    last_active: Arc<AtomicU64>,
    restored: Arc<std::sync::atomic::AtomicBool>,
    /// When the flow was started. One that ended within [`TIDE_RETRY`] of it
    /// (it could not be opened) is not made again until that has passed, or a
    /// dead server would cost a handshake attempt per datagram.
    started: tokio::time::Instant,
}

impl Drop for TideFlow {
    fn drop(&mut self) {
        self.task.abort();
    }
}

/// How long a Tide flow that failed is left alone before another try.
const TIDE_RETRY: Duration = Duration::from_secs(3);
/// Datagrams queued to a Tide flow that is still opening or busy.
const TIDE_QUEUE: usize = 128;

/// Idle limit for one direct UDP flow (Xray's UDP session default).
const UDP_FLOW_IDLE: Duration = Duration::from_secs(60);
/// Idle limit for a UDP session carried inside one client stream (Trojan,
/// VLESS, VMess): matches the TCP relay's idle policy.
const UDP_SESSION_IDLE: Duration = crate::relay::DEFAULT_IDLE_TIMEOUT;
/// Distinct targets remembered per flow for noise purposes.
const UDP_NOISE_TARGET_LIMIT: usize = 256;
/// Replies queued towards a client before the slowest reader applies
/// backpressure to the flows feeding it.
const UDP_REPLY_QUEUE: usize = 256;

/// Routing and forwarding for everything one UDP ingress receives.
///
/// Direct traffic goes through a long-lived socket per client flow, so a
/// request that produces several answers (QUIC, games, DNS over UDP
/// retransmits, STUN) gets all of them, and a datagram that produces none
/// (an ACK) costs nothing. Proxied traffic is an exchange per datagram,
/// concurrently and under a hard deadline, so no single unanswered datagram
/// can stall the ingress. Both are bounded: flows by `flow_limit`, exchanges
/// by [`UDP_INFLIGHT_LIMIT`]; beyond either, datagrams are dropped.
struct UdpRelay<K> {
    server: Arc<Server>,
    id: InboundId,
    tag: Arc<str>,
    replies: tokio::sync::mpsc::Sender<UdpReply<K>>,
    flows: HashMap<(K, bool), NatFlow>,
    /// Flows carried by a Tide (ZeroV1) outbound, one per client flow and
    /// outbound.
    tide_flows: HashMap<(K, Arc<str>), TideFlow>,
    flow_limit: usize,
    inflight: Arc<tokio::sync::Semaphore>,
    exchanges: tokio::task::JoinSet<()>,
    epoch: tokio::time::Instant,
    /// Bumped whenever anything moves, so a session can tell idle from busy.
    activity: Arc<AtomicU64>,
    /// What this ingress' inbound asks the sniffer for.
    sniff: SniffPolicy,
}

impl<K> UdpRelay<K>
where
    K: Copy + Eq + std::hash::Hash + Send + Sync + 'static,
{
    fn new(
        server: Arc<Server>,
        id: InboundId,
        tag: Arc<str>,
        flow_limit: usize,
        sniff: SniffPolicy,
    ) -> (Self, tokio::sync::mpsc::Receiver<UdpReply<K>>) {
        let (replies, receiver) = tokio::sync::mpsc::channel(UDP_REPLY_QUEUE);
        (
            Self {
                server,
                id,
                tag,
                replies,
                flows: HashMap::new(),
                tide_flows: HashMap::new(),
                flow_limit: flow_limit.max(1),
                inflight: Arc::new(tokio::sync::Semaphore::new(UDP_INFLIGHT_LIMIT)),
                exchanges: tokio::task::JoinSet::new(),
                epoch: tokio::time::Instant::now(),
                activity: Arc::new(AtomicU64::new(0)),
                sniff,
            },
            receiver,
        )
    }

    fn activity(&self) -> u64 {
        self.activity.load(Ordering::Relaxed)
    }

    /// Route one client datagram and send it on its way. Failures are
    /// per-datagram: they are counted and logged, never fatal to the session.
    async fn dispatch(
        &mut self,
        key: K,
        source: SocketAddr,
        destination: Destination,
        payload: Vec<u8>,
    ) -> Dispatch {
        self.activity.fetch_add(1, Ordering::Relaxed);
        // Reap finished exchanges so the set does not grow with history.
        while self.exchanges.try_join_next().is_some() {}
        let server = Arc::clone(&self.server);
        let restored_destination = server.restore_fake_destination(&destination).await;
        let mut restored = restored_destination != destination;
        let before_sniff = restored_destination;
        let mut ctx = SessionContext::new(
            server.generation(),
            self.id,
            self.tag.clone(),
            before_sniff.clone(),
        )
        .with_source(source);
        // A QUIC flow names itself in its first datagram, and until it does
        // routing sees only the address the client dialled. `inspect` refuses
        // everything that is not an Initial packet, so this costs one byte
        // test on every other datagram of the flow.
        if self.sniff.enabled && self.sniff.quic && before_sniff.address.is_ip() {
            if let Some(mut sniffed) = crate::quic_sniff::inspect(&payload) {
                if sniffed
                    .domain
                    .as_deref()
                    .is_some_and(|d| self.sniff.sniffing.excludes(d))
                {
                    sniffed.domain = None;
                }
                ctx.apply_sniff(sniffed, !self.sniff.route_only);
            }
        }
        // uTP, BitTorrent's UDP transport, opens with a recognisable SYN.
        // It supplies no name, only the label a `bittorrent` rule matches.
        if self.sniff.enabled
            && ctx.sniffed.protocol.is_none()
            && zero_core::sniff::is_utp_syn(&payload)
        {
            ctx.sniffed.protocol = Some("bittorrent");
        }
        let destination = ctx.destination.clone();
        // The name now decides where this flow goes while the client still
        // only knows the address it sent to, so answers have to keep coming
        // from that address.
        restored |= destination != before_sniff;
        let (resolver, outbound) = match server.route(&ctx).await {
            Decision::Block => {
                server.stats.blocked.fetch_add(1, Ordering::Relaxed);
                return Dispatch::Rejected(payload);
            }
            Decision::DirectVia { resolver } => {
                (Arc::new(server.resolver().for_tag(&resolver)), None)
            }
            Decision::Outbound(tag) | Decision::Balancer(tag) => {
                let Some(outbound) = server.pick_outbound(&tag) else {
                    server.stats.failed.fetch_add(1, Ordering::Relaxed);
                    debug!(outbound = %tag, "no outbound for UDP route");
                    return Dispatch::Rejected(payload);
                };
                if let OutboundProtocol::Dns { rules } = &outbound.protocol {
                    self.spawn_dns_answer(key, destination, payload, restored, rules.clone());
                    return Dispatch::Sent;
                }
                // A blackhole outbound is how a config says "drop this", not a
                // server to connect to; the TCP path already treats it as a
                // refusal, and a UDP flow has to as well or the datagram is
                // handed to a proxy that is not a proxy.
                if matches!(outbound.protocol, OutboundProtocol::Blackhole { .. }) {
                    server.stats.blocked.fetch_add(1, Ordering::Relaxed);
                    return Dispatch::Rejected(payload);
                }
                if matches!(&outbound.protocol, OutboundProtocol::Tide(tide) if tide.datagrams) {
                    self.send_tide(key, outbound, destination, payload, restored);
                    return Dispatch::Sent;
                }
                if !matches!(outbound.protocol, OutboundProtocol::Freedom { .. }) {
                    self.spawn_exchange(key, outbound, destination, payload, restored);
                    return Dispatch::Sent;
                }
                (server.resolver(), Some(outbound))
            }
        };
        let stream = outbound.as_ref().map(|outbound| &outbound.stream);
        let length = payload.len() as u64;
        match self
            .send_direct(key, &resolver, &destination, &payload, stream, restored)
            .await
        {
            Ok(()) => {
                server.stats.uploaded.fetch_add(length, Ordering::Relaxed);
                Dispatch::Sent
            }
            Err(error) => {
                server.stats.failed.fetch_add(1, Ordering::Relaxed);
                debug!(%destination, %error, "direct UDP datagram failed");
                Dispatch::Rejected(payload)
            }
        }
    }

    /// Send a datagram through a Tide outbound's flow for `key`, starting the
    /// flow if there is none. Never waits: a flow that is still connecting
    /// queues the datagram, and one that is full or dead drops it.
    fn send_tide(
        &mut self,
        key: K,
        outbound: zero_config::Outbound,
        destination: Destination,
        payload: Vec<u8>,
        restored: bool,
    ) {
        let slot = (key, outbound.tag.clone());
        if let Some(flow) = self.tide_flows.get(&slot) {
            if flow.task.is_finished() && flow.started.elapsed() < TIDE_RETRY {
                return;
            }
            if flow.task.is_finished() {
                self.tide_flows.remove(&slot);
            }
        }
        if !self.tide_flows.contains_key(&slot) {
            if self.tide_flows.len() >= self.flow_limit {
                self.tide_flows.retain(|_, flow| !flow.task.is_finished());
                if self.tide_flows.len() >= self.flow_limit {
                    self.server.stats.failed.fetch_add(1, Ordering::Relaxed);
                    return;
                }
            }
            let (outgoing, queue) = tokio::sync::mpsc::channel(TIDE_QUEUE);
            let last_active = Arc::new(AtomicU64::new(millis_since(self.epoch)));
            let restored_flag = Arc::new(std::sync::atomic::AtomicBool::new(restored));
            let task = tokio::spawn(run_tide_flow(
                Arc::clone(&self.server),
                outbound,
                destination.clone(),
                key,
                queue,
                self.replies.clone(),
                self.epoch,
                Arc::clone(&last_active),
                Arc::clone(&self.activity),
                Arc::clone(&restored_flag),
            ));
            self.tide_flows.insert(
                slot.clone(),
                TideFlow {
                    outgoing,
                    task,
                    last_active,
                    restored: restored_flag,
                    started: tokio::time::Instant::now(),
                },
            );
        }
        let Some(flow) = self.tide_flows.get(&slot) else {
            return;
        };
        flow.restored.store(restored, Ordering::Relaxed);
        flow.last_active
            .store(millis_since(self.epoch), Ordering::Relaxed);
        let length = payload.len() as u64;
        if flow.outgoing.try_send((destination, payload)).is_ok() {
            self.server
                .stats
                .uploaded
                .fetch_add(length, Ordering::Relaxed);
        } else {
            self.server.stats.failed.fetch_add(1, Ordering::Relaxed);
        }
    }

    /// Answer a DNS query routed to a `dns` outbound from the runtime's own
    /// resolver (`crate::dns_out`). Bounded by the same in-flight limit as
    /// proxied exchanges, so a flood of queries cannot spawn without limit.
    fn spawn_dns_answer(
        &mut self,
        key: K,
        destination: Destination,
        payload: Vec<u8>,
        restored: bool,
        rules: Box<[zero_config::DnsOutboundRule]>,
    ) {
        let Ok(permit) = Arc::clone(&self.inflight).try_acquire_owned() else {
            self.server.stats.failed.fetch_add(1, Ordering::Relaxed);
            debug!(%destination, "UDP exchange limit reached; dropping DNS query");
            return;
        };
        let server = Arc::clone(&self.server);
        let replies = self.replies.clone();
        let activity = Arc::clone(&self.activity);
        self.exchanges.spawn(async move {
            let _permit = permit;
            server
                .stats
                .uploaded
                .fetch_add(payload.len() as u64, Ordering::Relaxed);
            let resolver = server.client_resolver();
            let Some(response) = crate::dns_out::answer(&resolver, &payload, &rules).await else {
                server.stats.failed.fetch_add(1, Ordering::Relaxed);
                debug!(%destination, "dropping a datagram that is not a DNS query, or one a rule drops");
                return;
            };
            activity.fetch_add(1, Ordering::Relaxed);
            let _ = replies
                .send(UdpReply {
                    key,
                    source: destination,
                    payload: response,
                    restored,
                })
                .await;
        });
    }

    fn spawn_exchange(
        &mut self,
        key: K,
        outbound: zero_config::Outbound,
        destination: Destination,
        payload: Vec<u8>,
        restored: bool,
    ) {
        let Ok(permit) = Arc::clone(&self.inflight).try_acquire_owned() else {
            self.server.stats.failed.fetch_add(1, Ordering::Relaxed);
            debug!(%destination, "UDP exchange limit reached; dropping datagram");
            return;
        };
        let server = Arc::clone(&self.server);
        let replies = self.replies.clone();
        let activity = Arc::clone(&self.activity);
        self.exchanges.spawn(async move {
            let _permit = permit;
            let datagram = socks::UdpDatagram {
                destination,
                payload,
            };
            match server.proxy_udp(&outbound, &datagram).await {
                Ok((source, response)) => {
                    server
                        .stats
                        .uploaded
                        .fetch_add(datagram.payload.len() as u64, Ordering::Relaxed);
                    activity.fetch_add(1, Ordering::Relaxed);
                    let _ = replies
                        .send(UdpReply {
                            key,
                            source,
                            payload: response,
                            restored,
                        })
                        .await;
                }
                Err(error) => {
                    server.stats.failed.fetch_add(1, Ordering::Relaxed);
                    debug!(destination = %datagram.destination, %error, "proxied UDP exchange failed");
                }
            }
        });
    }

    async fn send_direct(
        &mut self,
        key: K,
        resolver: &zero_dns::Resolver,
        destination: &Destination,
        payload: &[u8],
        stream: Option<&zero_config::StreamSettings>,
        restored: bool,
    ) -> Result<(), String> {
        let noise = stream.map_or(&[][..], |stream| stream.evasion.udp_noise.as_slice());
        let policy = stream.and_then(|stream| stream.direct.as_deref());
        let destination = &outbound::redirected(destination, policy);
        let target = match &destination.address {
            Address::Ip(ip) => SocketAddr::new(*ip, destination.port),
            Address::Domain(_) => {
                let addrs = resolver
                    .resolve_address(&destination.address, resolver.settings().query_strategy)
                    .await
                    .map_err(|error| error.to_string())?;
                let ip = addrs
                    .first()
                    .ok_or_else(|| "resolver returned no UDP destinations".to_string())?;
                SocketAddr::new(*ip, destination.port)
            }
        };
        if let Some(policy) = policy {
            outbound::allowed_by_final_rules(policy, destination.network, vec![target])
                .await
                .map_err(|failure| failure.to_string())?;
        }
        let epoch = self.epoch;
        let flow = self
            .flow(key, target.is_ipv4(), stream.map(|stream| &stream.sockopt))
            .await?;
        flow.restored.store(restored, Ordering::Relaxed);
        if !noise.is_empty() && !flow.noised.contains(&target) {
            if flow.noised.len() >= UDP_NOISE_TARGET_LIMIT {
                flow.noised.clear();
            }
            flow.noised.insert(target);
            // The first payload is sent after the decoys. This preserves the
            // configured wire order; sending the real datagram first would
            // make the noise visible only to a receiver that already knows
            // the flow.
            for (packet, delay) in noise_policy(noise).plan() {
                if !packet.is_empty() {
                    flow.socket
                        .send_to(&packet, target)
                        .await
                        .map_err(|error| format!("sending UDP noise: {error}"))?;
                }
                if !delay.is_zero() {
                    tokio::time::sleep(delay).await;
                }
            }
        }
        flow.socket
            .send_to(payload, target)
            .await
            .map_err(|error| format!("sending UDP payload: {error}"))?;
        flow.last_active
            .store(millis_since(epoch), Ordering::Relaxed);
        Ok(())
    }

    /// The live flow for `key` and address family, opening one if needed.
    async fn flow(
        &mut self,
        key: K,
        ipv4: bool,
        sockopt: Option<&zero_config::Sockopt>,
    ) -> Result<&mut NatFlow, String> {
        let slot = (key, ipv4);
        if self
            .flows
            .get(&slot)
            .is_some_and(|flow| flow.reader.is_finished())
        {
            self.flows.remove(&slot);
        }
        if !self.flows.contains_key(&slot) {
            if self.flows.len() >= self.flow_limit {
                self.flows.retain(|_, flow| !flow.reader.is_finished());
                if self.flows.len() >= self.flow_limit {
                    return Err("UDP flow table is full".into());
                }
            }
            let socket = Arc::new(
                bind_outbound_udp(ipv4, sockopt)
                    .await
                    .map_err(|error| format!("binding direct UDP socket: {error}"))?,
            );
            let last_active = Arc::new(AtomicU64::new(millis_since(self.epoch)));
            let restored = Arc::new(std::sync::atomic::AtomicBool::new(false));
            let reader = tokio::spawn(read_nat_flow(
                key,
                Arc::clone(&socket),
                self.replies.clone(),
                self.epoch,
                Arc::clone(&last_active),
                Arc::clone(&self.activity),
                Arc::clone(&restored),
            ));
            self.flows.insert(
                slot,
                NatFlow {
                    socket,
                    reader,
                    last_active,
                    noised: std::collections::HashSet::new(),
                    restored,
                },
            );
        }
        self.flows
            .get_mut(&slot)
            .ok_or_else(|| "UDP flow vanished while opening".to_string())
    }
}

fn millis_since(epoch: tokio::time::Instant) -> u64 {
    epoch.elapsed().as_millis().min(u64::MAX as u128) as u64
}

/// The life of one Tide UDP flow: open it, send what the relay queues, carry
/// answers back, and end when it has been idle for [`UDP_FLOW_IDLE`] or the
/// session stops listening.
#[allow(clippy::too_many_arguments)]
async fn run_tide_flow<K: Copy + Send + 'static>(
    server: Arc<Server>,
    outbound: zero_config::Outbound,
    first: Destination,
    key: K,
    mut queue: tokio::sync::mpsc::Receiver<(Destination, Vec<u8>)>,
    replies: tokio::sync::mpsc::Sender<UdpReply<K>>,
    epoch: tokio::time::Instant,
    last_active: Arc<AtomicU64>,
    activity: Arc<AtomicU64>,
    restored: Arc<std::sync::atomic::AtomicBool>,
) {
    let resolver = server.resolver();
    let opened = match server.resolve_chain(&outbound) {
        // Dialled directly (a direct dialer's fragmentation is on `chain[0]`).
        Ok(chain) if chain.len() == 1 => {
            outbound::connect_tide_udp(&chain[0], &first, &resolver).await
        }
        Ok(chain) => {
            let chain: Arc<[zero_config::Outbound]> = Arc::from(chain);
            let (route, carrier) = tide_carrier(&chain, 0, &resolver);
            outbound::connect_tide_udp_via(&chain[0], &first, &route, carrier).await
        }
        Err(failure) => Err(failure.to_string()),
    };
    let flow = match opened {
        Ok(flow) => Arc::new(flow),
        Err(error) => {
            server.stats.failed.fetch_add(1, Ordering::Relaxed);
            debug!(%error, "Tide UDP flow could not be opened");
            return;
        }
    };
    let writer = {
        let flow = Arc::clone(&flow);
        async move {
            while let Some((destination, payload)) = queue.recv().await {
                if flow.send(&destination, &payload).is_err() {
                    return;
                }
            }
        }
    };
    let reader = async {
        loop {
            match timeout(UDP_FLOW_IDLE, flow.recv()).await {
                Ok(Ok((source, payload))) => {
                    last_active.store(millis_since(epoch), Ordering::Relaxed);
                    activity.fetch_add(1, Ordering::Relaxed);
                    let reply = UdpReply {
                        key,
                        source,
                        payload: payload.to_vec(),
                        restored: restored.load(Ordering::Relaxed),
                    };
                    if replies.send(reply).await.is_err() {
                        return;
                    }
                }
                Ok(Err(error)) => {
                    debug!(%error, "Tide UDP flow ended");
                    return;
                }
                Err(_) => {
                    let idle =
                        millis_since(epoch).saturating_sub(last_active.load(Ordering::Relaxed));
                    if idle >= UDP_FLOW_IDLE.as_millis() as u64 {
                        return;
                    }
                }
            }
        }
    };
    tokio::select! {
        () = writer => {}
        () = reader => {}
    }
}

/// Carry a direct flow's answers back until it has been idle for
/// [`UDP_FLOW_IDLE`] or the session stops listening.
async fn read_nat_flow<K: Copy + Send + 'static>(
    key: K,
    socket: Arc<UdpSocket>,
    replies: tokio::sync::mpsc::Sender<UdpReply<K>>,
    epoch: tokio::time::Instant,
    last_active: Arc<AtomicU64>,
    activity: Arc<AtomicU64>,
    restored: Arc<std::sync::atomic::AtomicBool>,
) {
    loop {
        match timeout(UDP_FLOW_IDLE, socket.readable()).await {
            Ok(Ok(())) => {}
            Ok(Err(error)) => {
                debug!(%error, "direct UDP flow closed");
                return;
            }
            Err(_) => {
                let idle = millis_since(epoch).saturating_sub(last_active.load(Ordering::Relaxed));
                if idle >= UDP_FLOW_IDLE.as_millis() as u64 {
                    return;
                }
                continue;
            }
        }
        // Receive into a per-thread scratch buffer and copy out exactly the
        // datagram: the answer has to be an owned buffer anyway, and a
        // 64 KiB buffer per idle flow would dwarf everything else it holds.
        let received = UDP_SCRATCH.with(|scratch| {
            let mut scratch = scratch.borrow_mut();
            socket
                .try_recv_from(&mut scratch[..])
                .map(|(length, from)| (scratch[..length].to_vec(), from))
        });
        let (payload, from) = match received {
            Ok(value) => value,
            Err(error) if error.kind() == std::io::ErrorKind::WouldBlock => continue,
            // An ICMP unreachable for an earlier datagram surfaces here on some
            // platforms; it concerns one peer, not the flow.
            Err(error)
                if matches!(
                    error.kind(),
                    std::io::ErrorKind::ConnectionReset | std::io::ErrorKind::ConnectionRefused
                ) =>
            {
                continue
            }
            Err(error) => {
                debug!(%error, "direct UDP flow receive failed");
                return;
            }
        };
        last_active.store(millis_since(epoch), Ordering::Relaxed);
        activity.fetch_add(1, Ordering::Relaxed);
        let reply = UdpReply {
            key,
            source: Destination::udp(Address::Ip(from.ip()), from.port()),
            payload,
            restored: restored.load(Ordering::Relaxed),
        };
        if replies.send(reply).await.is_err() {
            return;
        }
    }
}

thread_local! {
    static UDP_SCRATCH: std::cell::RefCell<Box<[u8]>> =
        std::cell::RefCell::new(vec![0u8; 65_535].into_boxed_slice());
}

/// Write replies to a stream-carried UDP session, flushing once per burst
/// rather than once per datagram.
async fn write_udp_replies<W, K, F>(
    mut writer: W,
    mut replies: tokio::sync::mpsc::Receiver<UdpReply<K>>,
    stats: Arc<Stats>,
    encode: F,
) where
    W: tokio::io::AsyncWrite + Unpin,
    F: Fn(&UdpReply<K>) -> Result<Vec<u8>, String>,
{
    while let Some(first) = replies.recv().await {
        let mut next = Some(first);
        while let Some(reply) = next.take() {
            match encode(&reply) {
                Ok(frame) => {
                    if let Err(error) = writer.write_all(&frame).await {
                        debug!(%error, "writing UDP reply to the client failed");
                        return;
                    }
                    stats
                        .downloaded
                        .fetch_add(reply.payload.len() as u64, Ordering::Relaxed);
                    stats.succeeded.fetch_add(1, Ordering::Relaxed);
                }
                Err(error) => debug!(%error, "UDP reply cannot be framed; dropped"),
            }
            next = replies.try_recv().ok();
        }
        if let Err(error) = writer.flush().await {
            debug!(%error, "flushing UDP replies to the client failed");
            return;
        }
    }
}

/// Drop the Psiphon client belonging to an outbound that is going away or
/// changing.
///
/// The client is shared by every connection that uses the same configuration,
/// so this is what ends its tunnel: the last stream through it closes, the
/// client is released, and the SSH session ends with it.
#[cfg(feature = "psiphon")]
fn forget_psiphon(outbound: &zero_config::Outbound) {
    let zero_config::OutboundProtocol::Psiphon(psiphon) = &outbound.protocol else {
        return;
    };
    let Ok(config) = zero_psiphon::ClientConfig::from_value(psiphon.to_settings()) else {
        return;
    };
    zero_psiphon::shared::forget(&config);
}

#[cfg(not(feature = "psiphon"))]
fn forget_psiphon(_outbound: &zero_config::Outbound) {}

fn replace_outbound_endpoint(outbound: &mut zero_config::Outbound, address: Address, port: u16) {
    match &mut outbound.protocol {
        OutboundProtocol::Vless(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Trojan(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Shadowsocks(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Vmess(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::AnyTls(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Naive(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Tide(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Hysteria2(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Tuic(config) => {
            config.address = address;
            config.port = port;
        }
        OutboundProtocol::Juicity(config) => {
            config.address = address;
            config.port = port;
        }
        // AmneziaWG is a UDP peer configuration. Clean-IP substitution is a
        // CDN/TCP optimization and must not rewrite its authenticated peer
        // endpoint behind the caller's back. A SOCKS5 upstream is the user's
        // own client (often loopback), not a CDN edge, so it is left alone too.
        // Psiphon chooses its own servers from its signed entry list; a
        // clean-IP rewrite would point it at an address it has no entry for.
        OutboundProtocol::AmneziaWireguard(_)
        | OutboundProtocol::Socks(_)
        | OutboundProtocol::Tor(_)
        | OutboundProtocol::Psiphon(_)
        | OutboundProtocol::MasterDns(_)
        | OutboundProtocol::Freedom { .. }
        | OutboundProtocol::Blackhole { .. }
        | OutboundProtocol::Loopback { .. }
        | OutboundProtocol::Portal { .. }
        | OutboundProtocol::Dns { .. } => {}
    }
}

fn preserve_stream_host(stream: &mut zero_config::StreamSettings, host: &str) {
    if let zero_config::Security::Tls(tls) = &mut stream.security {
        if tls.server_name.is_none() {
            tls.server_name = Some(Arc::from(host));
        }
    }
    match &mut stream.transport {
        zero_config::Transport::Raw => {}
        zero_config::Transport::WebSocket(config)
        | zero_config::Transport::HttpUpgrade(config)
        | zero_config::Transport::Grpc(config)
        | zero_config::Transport::Xhttp(config) => {
            if config.host.is_none() {
                config.host = Some(Arc::from(host));
            }
        }
    }
}

fn choose_balancer_index(
    strategy: zero_config::routing::BalancerStrategy,
    ticket: u64,
    member_count: usize,
) -> usize {
    debug_assert!(member_count > 0);
    match strategy {
        zero_config::routing::BalancerStrategy::RoundRobin
        | zero_config::routing::BalancerStrategy::LeastPing
        | zero_config::routing::BalancerStrategy::LeastLoad => {
            // Least-* is deliberately fair until the observatory has a
            // per-outbound sample. Choosing the first member here would
            // silently turn a health-aware config into a single-server
            // config; rotation is the safe neutral prior.
            ticket as usize % member_count
        }
        zero_config::routing::BalancerStrategy::Random => {
            // SplitMix64 gives a cheap, deterministic and unbiased sequence
            // without pulling a lock or OS randomness into every selection.
            let mut value = ticket.wrapping_add(0x9E37_79B9_7F4A_7C15);
            value ^= value >> 30;
            value = value.wrapping_mul(0xBF58_476D_1CE4_E5B9);
            value ^= value >> 27;
            value = value.wrapping_mul(0x94D0_49BB_1331_11EB);
            value ^= value >> 31;
            value as usize % member_count
        }
    }
}

struct ProbeTarget {
    destination: Destination,
    path: String,
    /// `https://`: the request goes over verified TLS.
    tls: bool,
}

/// Send one `GET` and accept a 2xx/3xx status line.
async fn http_probe_status<S>(stream: &mut S, host: &str, path: &str) -> Result<u16, String>
where
    S: tokio::io::AsyncRead + tokio::io::AsyncWrite + Unpin,
{
    let request = format!(
        "GET {path} HTTP/1.1\r\nHost: {host}\r\nConnection: close\r\nUser-Agent: zray-observatory/1\r\n\r\n"
    );
    stream
        .write_all(request.as_bytes())
        .await
        .map_err(|error| error.to_string())?;
    stream.flush().await.map_err(|error| error.to_string())?;
    let mut response = [0u8; 256];
    let n = stream
        .read(&mut response)
        .await
        .map_err(|error| error.to_string())?;
    if n == 0 {
        return Err("probe closed before a response".into());
    }
    let line = std::str::from_utf8(&response[..n]).unwrap_or_default();
    let status = line
        .split_whitespace()
        .nth(1)
        .and_then(|value| value.parse::<u16>().ok())
        .ok_or_else(|| "probe returned a malformed HTTP status".to_string())?;
    if !(200..=399).contains(&status) {
        return Err(format!("probe returned HTTP {status}"));
    }
    Ok(status)
}

fn parse_probe_target(value: &str) -> Result<ProbeTarget, String> {
    let url = url::Url::parse(value).map_err(|error| error.to_string())?;
    let host = url
        .host_str()
        .ok_or_else(|| "probe URL has no host".to_string())?;
    let port = url
        .port_or_known_default()
        .ok_or_else(|| "probe URL has no known port".to_string())?;
    let mut path = url.path().to_string();
    if path.is_empty() {
        path.push('/');
    }
    if let Some(query) = url.query() {
        path.push('?');
        path.push_str(query);
    }
    Ok(ProbeTarget {
        destination: Destination::tcp(Address::parse_host(host), port),
        path,
        tls: url.scheme() == "https",
    })
}

fn noise_policy(configs: &[NoiseConfig]) -> zero_evasion::NoisePolicy {
    let entries = configs
        .iter()
        .map(|config| {
            let packet = match &config.kind {
                NoiseKind::Rand { length, byte_range } => zero_evasion::NoisePacket::Rand {
                    length_min: length.min as i64,
                    length_max: length.max as i64,
                    byte_min: byte_range.0,
                    byte_max: byte_range.1,
                },
                NoiseKind::Str(value) => {
                    zero_evasion::NoisePacket::Fixed(value.as_bytes().to_vec())
                }
                NoiseKind::Hex(value) | NoiseKind::Base64(value) | NoiseKind::Array(value) => {
                    zero_evasion::NoisePacket::Fixed(value.clone())
                }
                NoiseKind::Quic { length } => zero_evasion::NoisePacket::Quic {
                    length_min: length.min as i64,
                    length_max: length.max as i64,
                },
            };
            zero_evasion::NoiseEntry {
                packet,
                delay_min_ms: config.delay.min.as_millis() as i64,
                delay_max_ms: config.delay.max.as_millis() as i64,
                count: config.count,
            }
        })
        .collect();
    zero_evasion::NoisePolicy { entries }
}

fn shadowsocks_method(
    method: zero_config::ShadowsocksMethod,
) -> zero_protocol::shadowsocks::Method {
    match method {
        zero_config::ShadowsocksMethod::Aes128Gcm => zero_protocol::shadowsocks::Method::Aes128Gcm,
        zero_config::ShadowsocksMethod::Aes256Gcm => zero_protocol::shadowsocks::Method::Aes256Gcm,
        zero_config::ShadowsocksMethod::Chacha20Poly1305 => {
            zero_protocol::shadowsocks::Method::Chacha20Poly1305
        }
        zero_config::ShadowsocksMethod::Blake3Aes128Gcm
        | zero_config::ShadowsocksMethod::Blake3Aes256Gcm
        | zero_config::ShadowsocksMethod::Blake3Chacha20Poly1305 => {
            unreachable!("2022 methods use ss2022_method")
        }
    }
}
fn ss2022_method(method: zero_config::ShadowsocksMethod) -> zero_protocol::shadowsocks2022::Method {
    match method {
        zero_config::ShadowsocksMethod::Blake3Aes128Gcm => {
            zero_protocol::shadowsocks2022::Method::Aes128Gcm
        }
        zero_config::ShadowsocksMethod::Blake3Aes256Gcm => {
            zero_protocol::shadowsocks2022::Method::Aes256Gcm
        }
        zero_config::ShadowsocksMethod::Blake3Chacha20Poly1305 => {
            zero_protocol::shadowsocks2022::Method::Chacha20Poly1305
        }
        _ => unreachable!("legacy methods use shadowsocks_method"),
    }
}

/// Read a VLESS request header. On failure the bytes read so far come back
/// with the reason, so a fallback can replay them.
///
/// `first_read_decides` is for an inbound with a fallback: a real client
/// sends its whole header at once, so a first read that does not hold one is
/// treated as a visitor straight away (Xray does the same) rather than waited
/// on, which would leave a browser's request hanging.
async fn read_vless_request<S: tokio::io::AsyncRead + Unpin>(
    stream: &mut S,
    first_read_decides: bool,
) -> Result<(zero_protocol::vless::Request, usize, Vec<u8>), (String, Vec<u8>)> {
    let mut buffered = Vec::with_capacity(256);
    let mut scratch = [0u8; 2048];
    loop {
        let n = match stream.read(&mut scratch).await {
            Ok(n) => n,
            Err(error) => return Err((format!("reading VLESS request: {error}"), buffered)),
        };
        if n == 0 {
            return Err((
                "VLESS client closed before the request header".into(),
                buffered,
            ));
        }
        buffered.extend_from_slice(&scratch[..n]);
        let parsed = match zero_protocol::vless::parse_request(&buffered) {
            Ok(parsed) => parsed,
            Err(reason) => return Err((reason, buffered)),
        };
        match parsed {
            zero_protocol::vless::RequestParse::Incomplete => {
                if first_read_decides {
                    return Err(("VLESS request header is incomplete".into(), buffered));
                }
                if buffered.len() > 8192 {
                    return Err(("VLESS request header exceeds the limit".into(), buffered));
                }
            }
            zero_protocol::vless::RequestParse::Complete { request, consumed } => {
                return Ok((request, consumed, buffered));
            }
        }
    }
}

/// Read a Trojan request header. On failure the bytes read so far come back
/// with the reason, so a fallback can replay them.
///
/// `first_read_decides` is for an inbound with a fallback: a real client
/// sends its whole header at once, so a first read that does not hold one is
/// treated as a visitor straight away (Xray does the same) rather than waited
/// on, which would leave a browser's request hanging.
async fn read_trojan_request<S: tokio::io::AsyncRead + Unpin>(
    stream: &mut S,
    first_read_decides: bool,
) -> Result<(zero_protocol::trojan::Request, usize, Vec<u8>), (String, Vec<u8>)> {
    let mut buffered = Vec::with_capacity(256);
    let mut scratch = [0u8; 2048];
    loop {
        let n = match stream.read(&mut scratch).await {
            Ok(n) => n,
            Err(error) => return Err((format!("reading Trojan request: {error}"), buffered)),
        };
        if n == 0 {
            return Err((
                "Trojan client closed before the request header".into(),
                buffered,
            ));
        }
        buffered.extend_from_slice(&scratch[..n]);
        let parsed = match zero_protocol::trojan::parse_request(&buffered) {
            Ok(parsed) => parsed,
            Err(reason) => return Err((reason, buffered)),
        };
        match parsed {
            zero_protocol::trojan::RequestParse::Incomplete => {
                if first_read_decides {
                    return Err(("Trojan request header is incomplete".into(), buffered));
                }
                if buffered.len() > 8192 {
                    return Err(("Trojan request header exceeds the limit".into(), buffered));
                }
            }
            zero_protocol::trojan::RequestParse::Complete { request, consumed } => {
                return Ok((request, consumed, buffered));
            }
        }
    }
}

async fn read_vless_udp_frame<S: tokio::io::AsyncRead + Unpin>(
    stream: &mut S,
    pending: &mut Vec<u8>,
) -> Result<Option<Vec<u8>>, String> {
    let mut scratch = [0u8; 8192];
    loop {
        if pending.len() >= 2 {
            let length = u16::from_be_bytes([pending[0], pending[1]]) as usize;
            if length == 0 {
                return Err("empty VLESS UDP frame".into());
            }
            if length > 65_535 {
                return Err("VLESS UDP frame exceeds the limit".into());
            }
            if pending.len() >= length + 2 {
                let payload = pending[2..length + 2].to_vec();
                pending.drain(..length + 2);
                return Ok(Some(payload));
            }
        }
        let n = stream
            .read(&mut scratch)
            .await
            .map_err(|error| format!("reading VLESS UDP frame: {error}"))?;
        if n == 0 {
            if pending.is_empty() {
                return Ok(None);
            }
            return Err("VLESS UDP stream ended in a partial frame".into());
        }
        pending.extend_from_slice(&scratch[..n]);
        // An incomplete frame is at most 65,536 bytes; the read that completes
        // it may legitimately carry the start of the next one as well.
        if pending.len() > 65_537 + scratch.len() {
            return Err("VLESS UDP pending frame exceeds the limit".into());
        }
    }
}

/// Read the next Trojan UDP packet, keeping partial frames in `pending`.
/// `Ok(None)` is a clean end of stream between packets. Every mutation of
/// `pending` happens right after a completed read, so dropping this future
/// between reads (an idle timeout) loses nothing.
async fn read_trojan_udp_packet<S: tokio::io::AsyncRead + Unpin>(
    stream: &mut S,
    pending: &mut Vec<u8>,
    scratch: &mut [u8],
) -> Result<Option<(Destination, Vec<u8>)>, String> {
    loop {
        match zero_protocol::trojan::parse_udp_packet(pending)? {
            zero_protocol::trojan::UdpPacketParse::Complete {
                destination,
                payload,
                consumed,
            } => {
                pending.drain(..consumed);
                return Ok(Some((destination, payload)));
            }
            zero_protocol::trojan::UdpPacketParse::Incomplete => {
                let n = stream
                    .read(scratch)
                    .await
                    .map_err(|error| format!("reading Trojan UDP frame: {error}"))?;
                if n == 0 {
                    if pending.is_empty() {
                        return Ok(None);
                    }
                    return Err("Trojan UDP stream ended in a partial frame".into());
                }
                pending.extend_from_slice(&scratch[..n]);
                // One maximal frame (a 255-byte domain and a 65,535-byte
                // payload) plus whatever of the next frame the same read
                // brought along.
                if pending.len() > 65_800 + scratch.len() {
                    return Err("Trojan UDP pending frame exceeds the limit".into());
                }
            }
        }
    }
}

/// A reader that replays already-consumed bytes before the live stream.
struct ChainedStream {
    prefix: Vec<u8>,
    offset: usize,
    inner: zero_core::BoxStream,
}

impl ChainedStream {
    fn new(prefix: Vec<u8>, inner: zero_core::BoxStream) -> Self {
        Self {
            prefix,
            offset: 0,
            inner,
        }
    }
}

impl tokio::io::AsyncRead for ChainedStream {
    fn poll_read(
        mut self: std::pin::Pin<&mut Self>,
        cx: &mut std::task::Context<'_>,
        buf: &mut tokio::io::ReadBuf<'_>,
    ) -> std::task::Poll<std::io::Result<()>> {
        if self.offset < self.prefix.len() {
            let n = (self.prefix.len() - self.offset).min(buf.remaining());
            let start = self.offset;
            buf.put_slice(&self.prefix[start..start + n]);
            self.offset += n;
            return std::task::Poll::Ready(Ok(()));
        }
        std::pin::Pin::new(&mut self.inner).poll_read(cx, buf)
    }
}

impl tokio::io::AsyncWrite for ChainedStream {
    fn poll_write(
        mut self: std::pin::Pin<&mut Self>,
        cx: &mut std::task::Context<'_>,
        buf: &[u8],
    ) -> std::task::Poll<std::io::Result<usize>> {
        std::pin::Pin::new(&mut self.inner).poll_write(cx, buf)
    }
    fn poll_flush(
        mut self: std::pin::Pin<&mut Self>,
        cx: &mut std::task::Context<'_>,
    ) -> std::task::Poll<std::io::Result<()>> {
        std::pin::Pin::new(&mut self.inner).poll_flush(cx)
    }
    fn poll_shutdown(
        mut self: std::pin::Pin<&mut Self>,
        cx: &mut std::task::Context<'_>,
    ) -> std::task::Poll<std::io::Result<()>> {
        std::pin::Pin::new(&mut self.inner).poll_shutdown(cx)
    }
}

/// Build the cache handle described by configuration.
pub fn asset_store_for(assets: &zero_config::AssetsConfig) -> zero_router::AssetStore {
    asset_store(assets)
}

/// Translate configured asset files into store specs.
pub fn asset_specs_for(assets: &zero_config::AssetsConfig) -> Vec<zero_router::AssetSpec> {
    asset_specs(assets)
}

fn asset_store(assets: &zero_config::AssetsConfig) -> zero_router::AssetStore {
    let dir = assets
        .directory
        .as_deref()
        .map(std::path::PathBuf::from)
        .unwrap_or_else(zero_router::AssetStore::default_dir);
    zero_router::AssetStore::new(
        dir,
        zero_router::AssetPolicy {
            refresh_interval: assets.refresh_interval,
            retry_interval: assets.retry_interval,
            limits: zero_net::fetch::FetchLimits {
                max_bytes: assets.max_bytes,
                timeout: assets.timeout,
                max_redirects: 5,
            },
        },
    )
}

/// Translate configured asset files into store specs. A malformed sha256 pin
/// was already rejected at parse time, so a failure here can only mean the
/// configuration was built programmatically; such an entry is dropped rather
/// than silently downgraded to an unpinned download.
fn asset_specs(assets: &zero_config::AssetsConfig) -> Vec<zero_router::AssetSpec> {
    assets
        .files
        .iter()
        .filter_map(|file| {
            let kind = match file.kind {
                zero_config::AssetFileKind::Geosite => zero_router::AssetKind::Geosite,
                zero_config::AssetFileKind::Geoip => zero_router::AssetKind::Geoip,
            };
            let spec = zero_router::AssetSpec::new(
                file.name.to_string(),
                kind,
                file.urls.iter().map(|url| url.to_string()).collect(),
            );
            match file.sha256.as_deref() {
                None => Some(spec),
                Some(pin) => match zero_router::assets::parse_sha256(pin) {
                    Ok(digest) => Some(spec.with_sha256(digest)),
                    Err(error) => {
                        warn!(asset = %file.name, %error, "dropping rule set with an invalid sha256 pin");
                        None
                    }
                },
            }
        })
        .collect()
}

/// Bind a UDP socket for traffic leaving the machine, protected first.
///
/// Only *outbound* sockets take this path. The SOCKS5 UDP association is
/// deliberately not protected: it listens for datagrams from applications on
/// this device, and exempting it from the tunnel would move it off the
/// interface those applications reach it on.
/// REALITY server names looked up per inbound. A config lists a handful; this
/// keeps a pathological one from opening a connection per name at start.
const POST_HANDSHAKE_NAMES: usize = 8;

/// Ask each REALITY inbound's camouflage site what its handshake looks like,
/// in the background, and file the answer where the inbound's handshakes will
/// find it (see [`zero_security::tls13::post_handshake`]).
///
/// Both halves are learned in the one connection: the sizes of the records in
/// the site's first flight, which the inbound then writes its own flight in,
/// and the sizes of what the site sends after the handshake, which the inbound
/// replays as empty records.
///
/// Nothing waits on this. Until a site has answered, and for good if it never
/// does, the inbound sends a flight of its own sizes and no extra records
/// after a handshake, which is how every inbound behaved before.
/// The three ways the camouflage site is asked about its handshake, and the
/// key each answer is filed under.
///
/// Go probes the site three times per name — with no ALPN, with http/1.1, and
/// with h2 and http/1.1 (`RL/record_detect.go:21-62`) — and files what it
/// learned under `dest + " " + sni + " " + alpn`, where the last part is
/// 0 for a client that offered no ALPN, 2 for one that offered h2 first, and
/// 1 for anything else (`RL/tls.go:396-403`). The accepting connection picks
/// the entry by the ALPN *it* offered, so a site that answers an h2 client
/// differently from an http/1.1 one is copied per protocol.
fn alpn_probes() -> [AlpnProbe; 3] {
    [
        AlpnProbe {
            index: 0,
            protocols: Vec::new(),
        },
        AlpnProbe {
            index: 1,
            protocols: vec!["http/1.1"],
        },
        AlpnProbe {
            index: 2,
            protocols: vec!["h2", "http/1.1"],
        },
    ]
}

/// The three probes are Go's three, filed under Go's three keys.
///
/// Go asks the site with no ALPN, with http/1.1, and with h2 and http/1.1
/// (`RL/record_detect.go:21-62`), and files the answers under the ALPN
/// *index* — 0 for a client that offered none, 2 for one that offered h2
/// first, 1 for anything else (`RL/tls.go:396-403`).
///
/// The indexes and the protocols have to agree: a probe filed under one
/// index and offering another's protocols would hand a client the answer
/// to a question it did not ask.
#[test]
fn the_three_probes_are_go_s_three() {
    let probes = alpn_probes();
    assert_eq!(probes.len(), 3, "Go probes the site three ways");
    assert_eq!(probes[0].index, 0, "no ALPN is index 0");
    assert!(
        probes[0].protocols.is_empty(),
        "index 0 offers no protocol at all"
    );
    assert_eq!(probes[1].index, 1, "http/1.1 is index 1");
    assert_eq!(probes[1].protocols, vec!["http/1.1"]);
    assert_eq!(probes[2].index, 2, "h2 and http/1.1 is index 2");
    assert_eq!(probes[2].protocols, vec!["h2", "http/1.1"]);

    // And each probe's protocols must produce the index it is filed under,
    // by the same rule the accepting connection uses.
    for probe in &probes {
        let offered: Vec<String> = probe.protocols.iter().map(|p| p.to_string()).collect();
        let index = match offered.split_first() {
            None => 0,
            Some((first, _)) if first == "h2" => 2,
            Some(_) => 1,
        };
        assert_eq!(
            index, probe.index,
            "the probe offering {:?} must be filed under the index the \
             client with those protocols would look up",
            probe.protocols
        );
    }
}

/// One way of asking the site, and the key its answer is filed under.
struct AlpnProbe {
    /// The key the answer is filed under: Go's ALPN index, which is 0 for a
    /// client that offered no ALPN, 2 for one that offered h2 first, and 1
    /// for anything else (`RL/tls.go:396-403`).
    ///
    /// An *index* and not the list of protocols, because Go files a bucket:
    /// a client that offered `http/1.1` first gets the http/1.1 answer
    /// whichever else it offered.
    index: u8,
    /// The protocols the probe offers the site.
    protocols: Vec<&'static str>,
}

fn learn_post_handshake(
    config: &RuntimeConfig,
    inbounds: &[InboundRuntime],
    resolver: &Arc<zero_dns::Resolver>,
) {
    // Built outside a runtime (some tests do): there is nowhere to run it.
    let Ok(runtime) = tokio::runtime::Handle::try_current() else {
        return;
    };
    for (inbound, compiled) in config.inbounds.iter().zip(inbounds) {
        let (zero_config::InboundSecurity::Reality(reality), Some(params)) =
            (&inbound.security, &compiled.reality)
        else {
            continue;
        };
        // The site is asked about its shapes over a TCP connection, so a unix
        // target is not asked: the shapes would come from a socket the
        // operator's own site serves, which is the same place the fallback
        // goes, but the shapes are learned over TLS and a unix socket carries
        // no certificate to speak of.
        let Some(zero_config::RealityTarget::Host(address, port)) = reality.target.clone() else {
            continue;
        };
        let names = reality.server_names.iter().filter(|name| !name.is_empty());
        for name in names.take(POST_HANDSHAKE_NAMES) {
            let name = name.clone();
            let shapes = Arc::clone(&params.post_handshake);
            let resolver = Arc::clone(resolver);
            let destination = Destination::tcp(address.clone(), port);
            // Go prefixes *every* dial to the site with the PROXY header when
            // `xver` asks for one, the start-up probes included
            // (`RL/tls.go:174-180`, `RL/record_detect.go:37,71`): a site behind
            // a PROXY-aware front must see the listener as a client that
            // announces itself, or it refuses the probes and the listener ends
            // up with its own flight and budget instead of the site's.
            let probe_stream = {
                let mut stream = zero_config::StreamSettings::default();
                if reality.fallback_xver != 0 {
                    stream.direct = Some(Arc::new(zero_config::DirectPolicy {
                        proxy_protocol: reality.fallback_xver,
                        ..Default::default()
                    }));
                }
                stream
            };
            runtime.spawn(async move {
                // The site is asked three ways, as Go asks it
                // (`RL/record_detect.go:21-62`): with no ALPN, with http/1.1,
                // and with h2 and http/1.1. A site can answer an h2 client
                // differently from an http/1.1 one, and the answer is filed
                // under the protocol the *client* used
                // (`RL/tls.go:396-403`).
                for alpn in alpn_probes() {
                    let learned = timeout(Duration::from_secs(15), async {
                        let site = outbound::connect_direct_with_resolver(
                            &destination,
                            &probe_stream,
                            &resolver,
                        )
                        .await?;
                        // Unverified on purpose: this connection carries no
                        // application data, the site is the operator's own choice
                        // of camouflage, and requiring a public chain would leave
                        // every private-CA or self-signed decoy unshaped — which
                        // Go's REALITY handles, since it reads these sizes off the
                        // live connection without verifying anything.
                        zero_security::tls13::post_handshake::observe_all_with_alpn(
                            site,
                            &name,
                            zero_security::tls13::post_handshake::SiteTrust::Unverified,
                            &alpn.protocols,
                        )
                        .await
                    })
                    .await;
                    match learned {
                        Ok(Ok(learned)) => {
                            debug!(
                                %name,
                                alpn = ?alpn.protocols,
                                flight = ?learned.flight,
                                post_handshake = ?learned.post_handshake,
                                "REALITY target's handshake shapes learned"
                            );
                            shapes.set_flight(&name, alpn.index, &learned.flight);
                            shapes.set(&name, alpn.index, &learned.post_handshake);
                        }
                        Ok(Err(error)) => warn!(
                            %name, %error,
                            "REALITY target did not complete a handshake; this inbound will copy neither its flight nor its session tickets. Check that the target serves this name."
                        ),
                        Err(_) => warn!(
                            %name,
                            "REALITY target did not answer in time; this inbound will copy neither its flight nor its session tickets. Check that the server can reach the target."
                        ),
                    }

                    // How many records that advance nothing the target
                    // tolerates. The server answers with the same number, so
                    // that it cannot be told apart from the target by how long
                    // it puts up with a run of them
                    // (`RL/record_detect.go:137-185`). The probe asks the
                    // site the same way Go does, with the protocol the client
                    // would have used.
                    let budget = timeout(Duration::from_secs(30), async {
                        zero_security::tls13::ccs_probe::probe_budget(
                            || async {
                                outbound::connect_direct_with_resolver(
                                    &destination,
                                    &probe_stream,
                                    &resolver,
                                )
                                .await
                                .map_err(|error| {
                                    zero_core::Failure::new(
                                        zero_core::FailureKind::TcpRefused,
                                        zero_core::Stage::SocketConnected,
                                    )
                                    .with_detail(error.to_string())
                                })
                            },
                            &name,
                        )
                        .await
                    })
                    .await;
                    match budget {
                        Ok(Some(budget)) => {
                            debug!(
                                %name,
                                alpn = ?alpn.protocols,
                                budget,
                                "REALITY target's record budget learned"
                            );
                            shapes.set_budget(&name, alpn.index, budget);
                        }
                        Ok(None) => debug!(
                            %name,
                            "REALITY target's record budget could not be learned; this inbound will use the default"
                        ),
                        Err(_) => debug!(
                            %name,
                            "REALITY target did not answer in time about its record budget; this inbound will use the default"
                        ),
                    }
                }
            });
        }
    }
}

/// Put the two-byte VLESS response header in front of the first thing sent
/// back on `stream`, instead of sending it as a tiny packet of its own. The
/// client cannot use the header before that payload arrives anyway. See
/// [`zero_protocol::first_flight`].
fn with_vless_response(stream: zero_core::BoxStream) -> zero_core::BoxStream {
    boxed(zero_protocol::first_flight::HeaderFirst::hold(
        stream,
        vec![0, 0],
    ))
}

/// A UDP socket for one outbound flow, carrying what its `sockopt` asks of a
/// direct connection: the routing mark, the interface, and the address to
/// leave from (`sendThrough`, used when it is of the destination's family).
/// Without the mark, a gateway's own traffic is caught again by the very
/// rule that sent the client's here.
async fn bind_outbound_udp(
    ipv4: bool,
    sockopt: Option<&zero_config::Sockopt>,
) -> Result<UdpSocket, String> {
    let source = sockopt
        .and_then(|sockopt| sockopt.bind_address)
        .filter(|ip| ip.is_ipv4() == ipv4);
    let bind: SocketAddr = match (source, ipv4) {
        (Some(ip), _) => SocketAddr::new(ip, 0),
        (None, true) => "0.0.0.0:0".parse().expect("a literal bind address"),
        (None, false) => "[::]:0".parse().expect("a literal bind address"),
    };
    let socket =
        zero_core::platform::bind_protected_udp(bind).map_err(|error| error.to_string())?;
    #[cfg(any(target_os = "linux", target_os = "android"))]
    if let Some(sockopt) = sockopt {
        if !sockopt.custom.is_empty() {
            use std::os::fd::AsRawFd;
            let network = if ipv4 { "udp4" } else { "udp6" };
            zero_core::custom_sockopt::apply(socket.as_raw_fd(), network, &sockopt.custom)
                .map_err(|error| error.to_string())?;
        }
        let socket = socket2::SockRef::from(&socket);
        if let Some(mark) = sockopt.mark {
            let _ = socket.set_mark(mark);
        }
        if let Some(interface) = &sockopt.bind_interface {
            let _ = socket.bind_device(Some(interface.as_bytes()));
        }
    }
    socket
        .set_nonblocking(true)
        .map_err(|error| error.to_string())?;
    UdpSocket::from_std(socket).map_err(|error| error.to_string())
}

#[cfg(test)]
mod tests {
    use super::lend_direct_dial;

    #[test]
    fn a_direct_dialer_lends_its_fragmentation_where_it_fits() {
        let fragmenting =
            zero_config::parse_link("trojan://pw@203.0.113.9:443?security=tls&sni=a.example#d")
                .unwrap()
                .outbound;
        let mut dialer = fragmenting.clone();
        dialer.stream.evasion.tcp_fragment = Some(zero_config::FragmentConfig::default());
        let link = |text: &str| zero_config::parse_link(text).unwrap().outbound;

        // A certificate-TLS outbound takes it.
        let mut tls = link("trojan://pw@203.0.113.9:443?security=tls&sni=a.example#t");
        lend_direct_dial(&mut tls, &dialer);
        assert!(tls.stream.evasion.tcp_fragment.is_some());

        // Its own shaping is kept.
        let mut shaped = link("trojan://pw@203.0.113.9:443?security=tls&sni=a.example#t");
        shaped.stream.evasion.tcp_fragment = Some(zero_config::FragmentConfig::empty_record());
        lend_direct_dial(&mut shaped, &dialer);
        assert_eq!(
            shaped.stream.evasion.tcp_fragment,
            Some(zero_config::FragmentConfig::empty_record())
        );

        // REALITY breaks when its hello is cut up, so it is left whole.
        let mut reality = link(
            "vless://00000000-0000-0000-0000-000000000001@203.0.113.10:443\
             ?security=reality&sni=www.example.com&pbk=AAECAwQFBgcICQoLDA0ODxAREhMUFRYXGBkaGxwdHh8\
             &sid=0123456789abcdef&type=tcp&encryption=none#r",
        );
        lend_direct_dial(&mut reality, &dialer);
        assert!(reality.stream.evasion.tcp_fragment.is_none());

        // Nor does one that already hides its name with ECH.
        let mut sealed = link(
            "trojan://pw@203.0.113.9:443?security=tls&sni=a.example&ech=udp%3A%2F%2F1.1.1.1#e",
        );
        lend_direct_dial(&mut sealed, &dialer);
        assert!(sealed.stream.evasion.tcp_fragment.is_none());
    }

    use super::choose_balancer_index;
    use super::{preserve_stream_host, replace_outbound_endpoint};
    use super::{Server, ServerConfig};
    use std::sync::atomic::Ordering;
    use std::sync::Arc;
    use zero_config::routing::BalancerStrategy;

    /// A minimal server whose only job is to exercise the planner's
    /// materialisation of a rung onto an outbound.
    #[tokio::test(start_paused = true)]
    async fn a_client_that_never_finishes_its_handshake_is_dropped() {
        // A slow-loris: connected, one byte of a SOCKS greeting, then nothing.
        let server = planner_test_server();
        let (client, mut peer) = tokio::io::duplex(64);
        tokio::io::AsyncWriteExt::write_all(&mut peer, &[0x05])
            .await
            .unwrap();
        let session = super::InboundSession {
            state: server.state.load_full(),
            conn: super::ConnInfo::default(),
        };
        let started = tokio::time::Instant::now();
        let result = Arc::clone(&server)
            .handle(
                zero_core::boxed(client),
                "127.0.0.1:40000".parse().unwrap(),
                zero_core::InboundId(0),
                session,
            )
            .await;
        let error = result.expect_err("a stalled handshake must fail");
        assert!(error.contains("timed out"), "{error}");
        assert!(started.elapsed() >= super::handshake_timeout());
        drop(peer);
    }

    #[test]
    fn inbound_material_is_compiled_once_per_generation() {
        let server = planner_test_server();
        let state = server.state.load_full();
        assert_eq!(state.inbounds.len(), state.config.inbounds.len());
        // A plain SOCKS inbound needs neither TLS nor a transport config.
        assert!(state.inbounds[0].tls.is_none());
        assert!(state.inbounds[0].transport.is_none());
    }

    #[test]
    fn an_https_probe_url_is_probed_over_tls() {
        let https = super::parse_probe_target("https://www.gstatic.com/generate_204").unwrap();
        assert!(https.tls);
        assert_eq!(https.destination.port, 443);
        let http = super::parse_probe_target("http://www.gstatic.com/generate_204").unwrap();
        assert!(!http.tls);
        assert_eq!(http.destination.port, 80);
    }

    /// Live: the balancer's real probe target. Plain HTTP to port 443 (the
    /// old behaviour) gets no answer; the verified TLS probe gets its 204.
    /// `cargo test -p zero-runtime https_probe_live -- --ignored`
    #[tokio::test]
    #[ignore]
    async fn https_probe_live_reaches_gstatic_only_over_tls() {
        let target = super::parse_probe_target("https://www.gstatic.com/generate_204").unwrap();
        let mut raw = tokio::net::TcpStream::connect(("www.gstatic.com", 443))
            .await
            .unwrap();
        assert!(
            super::http_probe_status(&mut raw, "www.gstatic.com", &target.path)
                .await
                .is_err(),
            "plain HTTP on 443 unexpectedly answered"
        );
        let config = serde_json::json!({
            "inbounds": [{"tag": "socks", "listen": "127.0.0.1", "port": 1080, "protocol": "socks"}],
            "outbounds": [{"tag": "direct", "protocol": "freedom"}],
            "dns": {"servers": ["8.8.8.8"]},
        });
        let (generation, _) =
            zero_config::compile_config(&config, zero_core::GenerationId(1)).unwrap();
        let server = Arc::new(Server::new(ServerConfig {
            config: Arc::clone(&generation.config),
            generation: generation.id,
        }));
        let direct = server.config().outbound_by_tag("direct").unwrap().clone();
        let elapsed = server
            .probe_outbound(&direct, &target)
            .await
            .expect("verified TLS probe succeeds");
        println!("https probe answered in {elapsed:?}");
    }

    fn planner_test_server() -> Arc<Server> {
        let config = serde_json::json!({
            "inbounds": [{
                "tag": "socks",
                "listen": "127.0.0.1",
                "port": 1080,
                "protocol": "socks",
            }],
            "outbounds": [{
                "tag": "proxy",
                "protocol": "vless",
                "settings": {"vnext": [{
                    "address": "edge.example",
                    "port": 443,
                    "users": [{"id": "b831381d-6324-4d53-ad4f-8cda48b30811",
                               "encryption": "none"}],
                }]},
                "streamSettings": {
                    "network": "ws",
                    "wsSettings": {"path": "/tunnel"},
                    "security": "tls",
                },
            }],
        });
        let (generation, _) =
            zero_config::compile_config(&config, zero_core::GenerationId(1)).expect("config");
        Arc::new(Server::new(ServerConfig {
            config: Arc::clone(&generation.config),
            generation: generation.id,
        }))
    }

    /// FakeDNS answers the applications, never the runtime itself, and a
    /// reload — which is also how a network change resets DNS — keeps every
    /// synthetic address an application already holds.
    #[tokio::test]
    async fn fake_addresses_survive_a_reload_and_never_reach_the_dialer() {
        let config = serde_json::json!({
            "inbounds": [{"tag": "socks", "listen": "127.0.0.1", "port": 1080, "protocol": "socks"}],
            "outbounds": [{"tag": "direct", "protocol": "freedom"}],
            "dns": {
                "servers": [
                    "fakedns",
                    {"address": "127.0.0.1", "port": 9, "tag": "real"},
                ],
                "hosts": {"pinned.example": "203.0.113.7"},
            },
        });
        let (generation, _) =
            zero_config::compile_config(&config, zero_core::GenerationId(1)).expect("config");
        let server = Server::new(ServerConfig {
            config: Arc::clone(&generation.config),
            generation: generation.id,
        });
        let strategy = zero_config::dns::QueryStrategy::UseIpv4;
        let fake = server
            .client_resolver()
            .lookup("app.example", strategy)
            .await
            .expect("fake answer");
        assert!(matches!(fake[0], std::net::IpAddr::V4(v4) if v4.octets()[..2] == [198, 18]));
        // The runtime's own view has no FakeDNS: hosts still answer, and a
        // name nobody pins goes to the (unreachable) real resolver, never to
        // a synthetic address.
        assert!(!server.resolver().has_fake());
        assert_eq!(
            server
                .resolver()
                .lookup("pinned.example", strategy)
                .await
                .unwrap(),
            vec!["203.0.113.7".parse::<std::net::IpAddr>().unwrap()]
        );

        let restored = server
            .restore_fake_destination(&zero_core::Destination::tcp(
                zero_core::Address::Ip(fake[0]),
                443,
            ))
            .await;
        assert_eq!(restored.address, zero_core::Address::domain("app.example"));

        server
            .reload(Arc::clone(&generation.config), zero_core::GenerationId(2))
            .expect("reload");
        let after = server
            .restore_fake_destination(&zero_core::Destination::tcp(
                zero_core::Address::Ip(fake[0]),
                443,
            ))
            .await;
        assert_eq!(
            after.address,
            zero_core::Address::domain("app.example"),
            "the mapping was lost on reload"
        );
        assert!(!server.resolver().has_fake());
    }

    /// The idle background tasks wait on `config_changed` instead of polling
    /// while no observatory or asset block is configured. A reload must wake
    /// that wait, and the task must see the new config when it does — so the
    /// signal has to fire *after* the new state is stored. This checks the
    /// contract `run_observatory` and `run_asset_refresh` depend on: a
    /// receiver that marked the current version unchanged, then saw a reload,
    /// observes the change and reads the generation that caused it.
    #[tokio::test]
    async fn a_reload_wakes_the_idle_background_tasks() {
        let plain = serde_json::json!({
            "inbounds": [{"tag": "socks", "listen": "127.0.0.1", "port": 1080, "protocol": "socks"}],
            "outbounds": [{"tag": "direct", "protocol": "freedom"}],
        });
        let (generation, _) =
            zero_config::compile_config(&plain, zero_core::GenerationId(1)).expect("config");
        let server = Server::new(ServerConfig {
            config: Arc::clone(&generation.config),
            generation: generation.id,
        });
        assert!(server.config().observatory.is_none());

        // Mimic the loop: snapshot the version, confirm nothing has changed.
        let mut rx = server.config_changed.subscribe();
        rx.mark_unchanged();
        assert!(!rx.has_changed().expect("sender alive"));

        // A reload that turns the observatory on must both wake the wait and
        // leave the new block visible to the woken reader.
        let with_observatory = serde_json::json!({
            "inbounds": [{"tag": "socks", "listen": "127.0.0.1", "port": 1080, "protocol": "socks"}],
            "outbounds": [{"tag": "direct", "protocol": "freedom"}],
            "observatory": {
                "probeUrl": "https://example.com/health",
                "probeInterval": "300s",
            },
        });
        let (next, _) = zero_config::compile_config(&with_observatory, zero_core::GenerationId(2))
            .expect("config");
        server
            .reload(next.config, zero_core::GenerationId(2))
            .expect("reload");

        tokio::time::timeout(Duration::from_secs(1), rx.changed())
            .await
            .expect("the reload did not wake the idle wait")
            .expect("sender alive");
        assert!(
            server.config().observatory.is_some(),
            "a woken task must see the config the reload installed"
        );
    }

    use std::net::SocketAddr;
    use std::time::Duration;
    use tokio::io::{AsyncReadExt as _, AsyncWriteExt as _};
    use tokio::time::timeout;
    use zero_core::boxed;
    use zero_core::{Address, Destination, GenerationId, InboundId, SessionContext};

    use super::{Dispatch, UdpRelay};
    use zero_router::Decision;

    /// A ClientHello carrying only an SNI, enough for the sniffer.
    fn hello_for(name: &str) -> Vec<u8> {
        let mut sni = Vec::new();
        sni.extend_from_slice(&((name.len() + 3) as u16).to_be_bytes());
        sni.push(0);
        sni.extend_from_slice(&(name.len() as u16).to_be_bytes());
        sni.extend_from_slice(name.as_bytes());
        let mut extensions = vec![0, 0];
        extensions.extend_from_slice(&(sni.len() as u16).to_be_bytes());
        extensions.extend_from_slice(&sni);
        let mut hello = vec![3, 3];
        hello.extend_from_slice(&[0; 32]);
        hello.push(0);
        hello.extend_from_slice(&[0, 2, 0x13, 0x01]);
        hello.extend_from_slice(&[1, 0]);
        hello.extend_from_slice(&(extensions.len() as u16).to_be_bytes());
        hello.extend_from_slice(&extensions);
        let mut record = vec![0x16, 3, 1];
        record.extend_from_slice(&(hello.len() as u16 + 4).to_be_bytes());
        record.extend_from_slice(&[
            1,
            (hello.len() >> 16) as u8,
            (hello.len() >> 8) as u8,
            hello.len() as u8,
        ]);
        record.extend_from_slice(&hello);
        record
    }

    /// A sink that answers the first four bytes it receives with themselves.
    async fn echo_sink() -> u16 {
        let sink = tokio::net::TcpListener::bind("127.0.0.1:0").await.unwrap();
        let port = sink.local_addr().unwrap().port();
        tokio::spawn(async move {
            while let Ok((mut socket, _)) = sink.accept().await {
                tokio::spawn(async move {
                    let mut buffer = [0u8; 4096];
                    if let Ok(read) = socket.read(&mut buffer).await {
                        let _ = socket.write_all(&buffer[..read.min(4)]).await;
                    }
                });
            }
        });
        port
    }

    fn tun_style_server(config: serde_json::Value) -> Server {
        let (generation, _) =
            zero_config::compile_config(&config, zero_core::GenerationId(1)).expect("config");
        Server::new(ServerConfig {
            config: Arc::clone(&generation.config),
            generation: generation.id,
        })
    }

    /// A DNS server that answers every A query with 127.0.0.1.
    async fn loopback_dns() -> u16 {
        let socket = tokio::net::UdpSocket::bind("127.0.0.1:0").await.unwrap();
        let port = socket.local_addr().unwrap().port();
        tokio::spawn(async move {
            let mut query = [0u8; 512];
            while let Ok((read, peer)) = socket.recv_from(&mut query).await {
                let mut reply = query[..read].to_vec();
                reply[2] = 0x81;
                reply[3] = 0x80;
                reply[6] = 0;
                reply[7] = 1;
                reply.extend_from_slice(&[0xC0, 0x0C, 0, 1, 0, 1, 0, 0, 0, 60, 0, 4, 127, 0, 0, 1]);
                let _ = socket.send_to(&reply, peer).await;
            }
        });
        port
    }

    /// The TUN hands over the address the application dialled. With FakeDNS
    /// that is a local handle, and dialling it literally sent every TCP flow
    /// of a phone to a benchmark address.
    #[tokio::test]
    async fn tun_tcp_flows_to_fake_addresses_reach_the_real_name() {
        let sink_port = echo_sink().await;
        let dns_port = loopback_dns().await;
        let server = tun_style_server(serde_json::json!({
            "inbounds": [{"tag": "tun", "listen": "127.0.0.1", "port": 1080, "protocol": "socks"}],
            "outbounds": [{"tag": "direct", "protocol": "freedom"}],
            "dns": {
                "servers": ["fakedns", {"address": "127.0.0.1", "port": dns_port, "tag": "real"}],
                "queryStrategy": "UseIPv4",
            },
        }));
        let fake = server
            .client_resolver()
            .lookup("app.test", zero_config::dns::QueryStrategy::UseIpv4)
            .await
            .expect("fake answer");
        assert!(matches!(fake[0], std::net::IpAddr::V4(v4) if v4.octets()[..2] == [198, 18]));
        let server = Arc::new(server);
        let (mut app, netstack) = tokio::io::duplex(4096);
        let session = tokio::spawn(Arc::clone(&server).handle_dokodemo_tcp(
            boxed(netstack),
            "10.0.0.2:40000".parse().unwrap(),
            InboundId(0),
            Arc::from("tun"),
            (Address::Ip(fake[0]), sink_port),
        ));
        app.write_all(b"ping").await.unwrap();
        let mut answer = [0u8; 4];
        timeout(Duration::from_secs(3), app.read_exact(&mut answer))
            .await
            .expect("the flow reached the sink")
            .unwrap();
        assert_eq!(&answer, b"ping");
        drop(app);
        let _ = session.await;
    }

    /// A TUN flow to a bare IP is named by its ClientHello, so a domain rule
    /// still applies to it.
    #[tokio::test]
    async fn tun_tcp_flows_are_sniffed_for_routing() {
        let sink_port = echo_sink().await;
        let server = Arc::new(tun_style_server(serde_json::json!({
            "inbounds": [{
                "tag": "tun", "listen": "127.0.0.1", "port": 1080, "protocol": "socks",
                "sniffing": {"enabled": true, "destOverride": ["http", "tls"]},
            }],
            "outbounds": [
                {"tag": "direct", "protocol": "freedom"},
                {"tag": "block", "protocol": "blackhole"},
            ],
            "routing": {"rules": [
                {"type": "field", "domain": ["full:blocked.example"], "outboundTag": "block"},
            ]},
            "dns": {"hosts": {"allowed.example": "127.0.0.1"}},
        })));
        let mut reached = Vec::new();
        for name in ["blocked.example", "allowed.example"] {
            let (mut app, netstack) = tokio::io::duplex(8192);
            let session = tokio::spawn(Arc::clone(&server).handle_dokodemo_tcp(
                boxed(netstack),
                "10.0.0.2:40000".parse().unwrap(),
                InboundId(0),
                Arc::from("tun"),
                (Address::Ip("127.0.0.1".parse().unwrap()), sink_port),
            ));
            app.write_all(&hello_for(name)).await.unwrap();
            let mut answer = [0u8; 4];
            let got = timeout(Duration::from_secs(2), app.read_exact(&mut answer)).await;
            reached.push(matches!(got, Ok(Ok(_))));
            drop(app);
            let _ = session.await;
        }
        assert_eq!(
            reached,
            [false, true],
            "blocked name leaked / allowed name blocked"
        );
    }

    /// With IPv6 off the TUN is given IPv4 addresses only: an IPv6 flow that
    /// still reaches it is closed at once, so an app that tries IPv6 first
    /// falls back to IPv4 without waiting for its own timeout.
    #[tokio::test]
    async fn tun_ipv6_flows_are_closed_at_once_when_ipv6_is_off() {
        let config = |addresses: serde_json::Value| {
            tun_style_server(serde_json::json!({
                "inbounds": [{
                    "tag": "tun", "protocol": "tun",
                    "settings": {"addresses": addresses},
                }],
                "outbounds": [{"tag": "direct", "protocol": "freedom"}],
            }))
        };
        let v4_only = Arc::new(config(serde_json::json!(["198.18.0.1/15"])));
        assert!(v4_only.tun_is_ipv4_only(InboundId(0)));
        assert!(!config(serde_json::json!([
            "198.18.0.1/15",
            "fdfe:dcba:9876::1/126"
        ]))
        .tun_is_ipv4_only(InboundId(0)));

        let (mut app, netstack) = tokio::io::duplex(1024);
        let session = tokio::spawn(Arc::clone(&v4_only).handle_dokodemo_tcp(
            boxed(netstack),
            "[fdfe:dcba:9876::2]:40000".parse().unwrap(),
            InboundId(0),
            Arc::from("tun"),
            (Address::Ip("2001:db8::1".parse().unwrap()), 443),
        ));
        let mut byte = [0u8; 1];
        let closed = timeout(Duration::from_millis(500), app.read(&mut byte)).await;
        assert!(
            matches!(closed, Ok(Ok(0))),
            "the IPv6 flow was not closed at once: {closed:?}"
        );
        // Ended by the early return, not by a failed dial.
        let ended = timeout(Duration::from_millis(500), session).await;
        assert!(matches!(ended, Ok(Ok(Ok(())))), "{ended:?}");
    }

    /// A TUN flow to a bare IP still goes to that IP when its hello names
    /// something else: the name decides the route, not the address.
    #[tokio::test]
    async fn tun_tcp_flows_keep_the_address_the_app_chose() {
        let sink_port = echo_sink().await;
        let server = Arc::new(tun_style_server(serde_json::json!({
            "inbounds": [{
                "tag": "tun", "listen": "127.0.0.1", "port": 1080, "protocol": "socks",
                "sniffing": {"enabled": true, "destOverride": ["http", "tls"]},
            }],
            "outbounds": [{"tag": "direct", "protocol": "freedom"}],
            // The name points somewhere nothing listens; the app dialled the sink.
            "dns": {"hosts": {"moved.example": "127.0.0.2"}},
        })));
        let (mut app, netstack) = tokio::io::duplex(8192);
        let session = tokio::spawn(Arc::clone(&server).handle_dokodemo_tcp(
            boxed(netstack),
            "10.0.0.2:40000".parse().unwrap(),
            InboundId(0),
            Arc::from("tun"),
            (Address::Ip("127.0.0.1".parse().unwrap()), sink_port),
        ));
        app.write_all(&hello_for("moved.example")).await.unwrap();
        let mut answer = [0u8; 4];
        let got = timeout(Duration::from_secs(2), app.read_exact(&mut answer)).await;
        assert!(
            matches!(got, Ok(Ok(_))),
            "the flow went to the name's address instead of the one the app dialled"
        );
        drop(app);
        let _ = session.await;
    }

    /// A UDP flow that only ever knew the address it dialled must still follow
    /// the rule written for the name in its QUIC Initial, the way its TCP twin
    /// already follows the name in its ClientHello.
    #[tokio::test]
    async fn quic_initials_route_by_the_name_they_carry() {
        let outcomes = quic_route_outcomes(&["http", "tls", "quic"]).await;
        assert_eq!(
            outcomes,
            [true, false],
            "the name in the Initial did not decide where its flow went"
        );
    }

    /// The control for the test above: with QUIC sniffing off, the same
    /// datagram routes on its address alone and the domain rule never sees it.
    #[tokio::test]
    async fn quic_initials_are_ignored_without_quic_sniffing() {
        let outcomes = quic_route_outcomes(&["http", "tls"]).await;
        assert_eq!(
            outcomes,
            [false, false],
            "a flow was sniffed that should not be"
        );
    }

    /// Send one QUIC Initial for a blocked name and one for an allowed name to
    /// a loopback sink, and say which of them routing refused.
    async fn quic_route_outcomes(dest_override: &[&str]) -> [bool; 2] {
        // The sink stands in for the site: the destination is what the client
        // dialled, and only the name inside the datagram can identify it.
        let sink = tokio::net::UdpSocket::bind("127.0.0.1:0").await.unwrap();
        let target = sink.local_addr().unwrap();
        let server = Arc::new(tun_style_server(serde_json::json!({
            "inbounds": [{
                "tag": "tun", "listen": "127.0.0.1", "port": 1080, "protocol": "socks",
                "sniffing": {"enabled": true, "destOverride": dest_override},
            }],
            "outbounds": [
                {"tag": "direct", "protocol": "freedom"},
                {"tag": "block", "protocol": "blackhole"},
            ],
            "routing": {"rules": [
                {"type": "field", "domain": ["full:blocked.example"], "outboundTag": "block"},
            ]},
            "dns": {"hosts": {"allowed.example": "127.0.0.1"}},
        })));
        let source: SocketAddr = "10.0.0.2:40000".parse().unwrap();
        let mut outcomes = [false; 2];
        for (index, name) in ["blocked.example", "allowed.example"]
            .into_iter()
            .enumerate()
        {
            // A fresh relay per name: one relay would keep the flow open and
            // the second Initial would join it rather than route again.
            let (mut relay, _replies) = UdpRelay::<(SocketAddr, SocketAddr)>::new(
                Arc::clone(&server),
                InboundId(0),
                Arc::from("tun"),
                4096,
                server.sniff_policy(InboundId(0)),
            );
            let outcome = relay
                .dispatch(
                    (source, target),
                    source,
                    Destination::udp(Address::Ip(target.ip()), target.port()),
                    crate::quic_sniff::test_initial(name),
                )
                .await;
            outcomes[index] = matches!(outcome, Dispatch::Rejected(_));
        }
        outcomes
    }

    /// A datagram routing refuses comes back to the ingress, so the TUN path
    /// can quote it in a port-unreachable instead of leaving a QUIC client to
    /// wait out its own timer.
    #[tokio::test]
    async fn a_refused_datagram_comes_back_to_be_quoted() {
        let server = Arc::new(tun_style_server(serde_json::json!({
            "inbounds": [{"tag": "tun", "listen": "127.0.0.1", "port": 1080, "protocol": "socks"}],
            "outbounds": [
                {"tag": "direct", "protocol": "freedom"},
                {"tag": "block", "protocol": "blackhole"},
            ],
            "routing": {"rules": [
                {"type": "field", "domain": ["full:blocked.example"], "outboundTag": "block"},
            ]},
        })));
        let (mut relay, _replies) = UdpRelay::<()>::new(
            Arc::clone(&server),
            InboundId(0),
            Arc::from("tun"),
            64,
            server.sniff_policy(InboundId(0)),
        );
        let query = b"\x12\x34\x01\x00\x00\x01".to_vec();
        let outcome = relay
            .dispatch(
                (),
                "10.0.0.2:40000".parse().unwrap(),
                Destination::udp(Address::domain("blocked.example"), 443),
                query.clone(),
            )
            .await;
        match outcome {
            Dispatch::Rejected(payload) => assert_eq!(payload, query, "the quote lost its bytes"),
            Dispatch::Sent => panic!("a blocked datagram was sent anyway"),
        }
    }

    fn sanction_server() -> Server {
        tun_style_server(serde_json::json!({
            "inbounds": [{"tag": "socks", "listen": "127.0.0.1", "port": 1080, "protocol": "socks"}],
            "outbounds": [
                {"tag": "proxy", "protocol": "freedom"},
                {"tag": "direct", "protocol": "freedom"},
            ],
            "dns": {"servers": [{"address": "193.186.32.32", "tag": "anti-sanction"}]},
        }))
    }

    fn sanctioned_ctx(destination: zero_core::Destination) -> SessionContext {
        SessionContext::new(
            GenerationId(1),
            InboundId(0),
            Arc::from("socks"),
            destination,
        )
    }

    /// Until the first measurement, and for a destination that has no name,
    /// the relay's certificate cannot have been checked: go through the
    /// tunnel rather than to a relay that may break HSTS sites.
    #[tokio::test]
    async fn sanctioned_names_wait_for_a_measurement_and_a_name() {
        let server = sanction_server();
        let direct_via = || Decision::DirectVia {
            resolver: crate::sanction_dns::TAG.into(),
        };
        let named = sanctioned_ctx(Destination::tcp(Address::domain("azure.com"), 443));
        assert_eq!(
            server.adapt_sanctioned(&named, direct_via()).await,
            Decision::Outbound("proxy".into()),
            "unmeasured: must not go direct"
        );

        *server.sanction.lock().unwrap() = Some(crate::sanction_dns::SanctionState {
            chosen: Some("193.186.32.32".parse().unwrap()),
            relay: vec!["203.0.113.9".parse().unwrap()],
        });
        let bare = sanctioned_ctx(Destination::tcp(
            Address::Ip("203.0.113.9".parse().unwrap()),
            443,
        ));
        assert_eq!(
            server.adapt_sanctioned(&bare, direct_via()).await,
            Decision::Outbound("proxy".into()),
            "no name to check the relay against: must not go direct"
        );
    }

    fn sample_outbound(server: &Server) -> zero_config::Outbound {
        server.config().outbounds[0].clone()
    }

    #[test]
    fn round_robin_and_health_fallbacks_visit_every_member() {
        for strategy in [
            BalancerStrategy::RoundRobin,
            BalancerStrategy::LeastPing,
            BalancerStrategy::LeastLoad,
        ] {
            let chosen: Vec<_> = (0..6)
                .map(|ticket| choose_balancer_index(strategy, ticket, 3))
                .collect();
            assert_eq!(chosen, [0, 1, 2, 0, 1, 2]);
        }
    }

    #[test]
    fn random_selection_is_not_pinned_to_the_first_member() {
        let chosen: Vec<_> = (0..32)
            .map(|ticket| choose_balancer_index(BalancerStrategy::Random, ticket, 4))
            .collect();
        assert!(chosen.iter().any(|index| *index != 0));
        assert!(chosen.iter().all(|index| *index < 4));
    }

    #[test]
    fn clean_ip_rewrite_keeps_the_fronted_tls_name() {
        let mut outbound = zero_config::Outbound {
            tag: "cdn".into(),
            protocol: zero_config::OutboundProtocol::Vless(zero_config::VlessConfig {
                address: zero_core::Address::domain("edge.example"),
                port: 443,
                uuid: [0; 16],
                flow: zero_config::Flow::None,
                encryption: "none".into(),
                vision_seed: None,
            }),
            stream: zero_config::StreamSettings {
                transport: zero_config::Transport::WebSocket(
                    zero_config::WebSocketConfig::default(),
                ),
                security: zero_config::Security::Tls(zero_config::TlsConfig::default()),
                ..zero_config::StreamSettings::default()
            },
            mux: zero_config::MuxConfig::default(),
        };
        replace_outbound_endpoint(
            &mut outbound,
            zero_core::Address::Ip("203.0.113.7".parse().unwrap()),
            2053,
        );
        preserve_stream_host(&mut outbound.stream, "edge.example");
        assert_eq!(outbound.endpoint().unwrap().1, 2053);
        assert_eq!(outbound.endpoint().unwrap().0.host_string(), "203.0.113.7");
        let zero_config::Security::Tls(tls) = outbound.stream.security else {
            panic!("expected TLS");
        };
        assert_eq!(tls.server_name.as_deref(), Some("edge.example"));
        let zero_config::Transport::WebSocket(ws) = outbound.stream.transport else {
            panic!("expected WebSocket");
        };
        assert_eq!(ws.host.as_deref(), Some("edge.example"));
    }

    #[test]
    fn the_keepalive_rung_puts_a_usable_shape_on_the_outbound() {
        // Deciding to shape and actually shaping are different things: the
        // rung has to arrive on the outbound as concrete numbers, or the
        // planner has climbed to a strategy that does nothing.
        let server = planner_test_server();
        let mut outbound = sample_outbound(&server);
        assert!(outbound.stream.evasion.keepalive.is_none());

        server.apply_strategy_to(
            &mut outbound,
            zero_observatory::PathStrategy::KeepaliveShaping,
        );
        let shape = outbound
            .stream
            .evasion
            .keepalive
            .expect("the keepalive rung must configure keepalive shaping");
        assert!(!shape.idle_after.is_zero());
        assert!(shape
            .max_flow_lifetime
            .is_some_and(|limit| limit > shape.idle_after));
    }

    #[test]
    fn the_keepalive_shape_is_sized_from_the_measured_reset_not_a_guess() {
        let server = planner_test_server();
        // 200s is what the planner measured; the default prior is 120s, so a
        // shape that ignored the measurement would be visibly wrong here.
        server
            .planner_flow_lifetime_ms
            .store(200_000, Ordering::Relaxed);

        let mut outbound = sample_outbound(&server);
        server.apply_strategy_to(
            &mut outbound,
            zero_observatory::PathStrategy::KeepaliveShaping,
        );
        let shape = outbound.stream.evasion.keepalive.expect("shaping applied");
        let lifetime = shape
            .max_flow_lifetime
            .expect("a measured reset sets a lifetime");
        assert!(
            lifetime < std::time::Duration::from_secs(200),
            "retiring at {lifetime:?} would still reach the observed deadline"
        );
        assert_ne!(
            shape,
            zero_config::KeepaliveConfig::default(),
            "the shape is the default prior, so the measurement was ignored"
        );
    }

    #[test]
    fn a_rung_below_keepalive_leaves_the_outbound_unshaped() {
        // The rungs are ordered by cost; applying an expensive one before the
        // evidence asks for it is exactly what the ladder exists to prevent.
        let server = planner_test_server();
        let mut outbound = sample_outbound(&server);
        server.apply_strategy_to(&mut outbound, zero_observatory::PathStrategy::DirectReality);
        assert!(outbound.stream.evasion.keepalive.is_none());
        assert!(outbound.stream.evasion.tcp_fragment.is_none());
    }

    #[test]
    fn an_operator_configured_keepalive_shape_is_not_overwritten_by_the_rung() {
        let server = planner_test_server();
        let mut outbound = sample_outbound(&server);
        let chosen = zero_config::KeepaliveConfig {
            idle_after: std::time::Duration::from_secs(7),
            max_flow_lifetime: Some(std::time::Duration::from_secs(70)),
        };
        outbound.stream.evasion.keepalive = Some(chosen);
        server.apply_strategy_to(
            &mut outbound,
            zero_observatory::PathStrategy::KeepaliveShaping,
        );
        assert_eq!(outbound.stream.evasion.keepalive, Some(chosen));
    }

    #[test]
    fn fingerprint_rotation_never_selects_a_profile_reality_cannot_use() {
        // Rotating a REALITY outbound into a shape with no X25519 key share
        // turns a working connection into a silent fallback to the decoy site,
        // which is indistinguishable from success at the socket layer.
        let server = planner_test_server();
        let mut outbound = sample_outbound(&server);
        outbound.stream.transport = zero_config::Transport::Raw;
        outbound.stream.security = zero_config::Security::Reality(zero_config::RealityConfig {
            server_name: "www.googletagmanager.com".into(),
            public_key: [7u8; 32],
            short_id: vec![1, 2, 3, 4],
            fingerprint: zero_config::Fingerprint::Chrome,
            spider_x: None,
            mldsa65_verify: None,
        });

        for _ in 0..24 {
            server.apply_strategy_to(
                &mut outbound,
                zero_observatory::PathStrategy::FingerprintRotation,
            );
            let zero_config::Security::Reality(reality) = &outbound.stream.security else {
                panic!("expected REALITY");
            };
            assert!(
                reality.fingerprint.supports_reality(),
                "rotation selected {:?}, which carries no X25519 key share",
                reality.fingerprint
            );
        }
    }
}

/// Xray's `limitFallbackUpload` / `limitFallbackDownload` as the fallback relay
/// Dial a Linux abstract socket, whose name is the leading NUL byte and the
/// name itself.
///
/// Neither Tokio nor socket2 has a call for one, so the socket is made
/// directly: `connect(2)` on an `AF_UNIX` address whose first byte is NUL
/// names the abstract namespace.
#[cfg(unix)]
fn connect_abstract(name: &str) -> std::io::Result<tokio::net::UnixStream> {
    let mut address = Vec::with_capacity(name.len() + 1);
    address.push(0u8);
    address.extend_from_slice(name.as_bytes());
    // `sockaddr_un` is a family byte followed by the path.
    let mut sockaddr: libc::sockaddr_un = unsafe { std::mem::zeroed() };
    sockaddr.sun_family = libc::AF_UNIX as libc::sa_family_t;
    if address.len() > sockaddr.sun_path.len() {
        return Err(std::io::Error::new(
            std::io::ErrorKind::InvalidInput,
            "the abstract socket name is too long",
        ));
    }
    for (slot, byte) in sockaddr.sun_path.iter_mut().zip(address.iter()) {
        *slot = *byte as libc::c_char;
    }
    let fd = unsafe { libc::socket(libc::AF_UNIX, libc::SOCK_STREAM | libc::SOCK_CLOEXEC, 0) };
    if fd < 0 {
        return Err(std::io::Error::last_os_error());
    }
    let connected = unsafe {
        libc::connect(
            fd,
            &sockaddr as *const libc::sockaddr_un as *const libc::sockaddr,
            std::mem::size_of::<libc::sockaddr_un>() as libc::socklen_t,
        )
    };
    if connected < 0 {
        let error = std::io::Error::last_os_error();
        unsafe { libc::close(fd) };
        return Err(error);
    }
    // The socket is already connected; it is handed to Tokio, which wants it
    // non-blocking.
    use std::os::fd::FromRawFd;
    let std_stream = unsafe { std::os::unix::net::UnixStream::from_raw_fd(fd) };
    std_stream
        .set_nonblocking(true)
        .map_err(|_| std::io::Error::last_os_error())?;
    tokio::net::UnixStream::from_std(std_stream).map_err(|_| std::io::Error::last_os_error())
}

/// Dial a unix socket, as Xray's `type: "unix"` target is dialled.
///
/// The path is used as written: a leading `@` is Linux's abstract socket
/// namespace (`infra/conf/transport_internet.go:826-831`), and anything else
/// is a filesystem path.
async fn connect_unix(path: &str) -> Result<zero_core::BoxStream, String> {
    #[cfg(unix)]
    {
        use tokio::net::UnixStream;
        let stream = if let Some(name) = path.strip_prefix('@') {
            // An abstract socket has no path on the filesystem: its name is
            // the leading NUL byte and the name itself. Neither Tokio nor
            // socket2 has a call for one, so the socket is made directly.
            match connect_abstract(name) {
                Ok(stream) => stream,
                Err(error) => return Err(format!("connecting to {path:?}: {error}")),
            }
        } else {
            match UnixStream::connect(path).await {
                Ok(stream) => stream,
                Err(error) => return Err(format!("connecting to {path:?}: {error}")),
            }
        };
        Ok(boxed(stream))
    }
    #[cfg(not(unix))]
    {
        let _ = path;
        Err("this platform has no unix sockets, so the target cannot be dialled".to_string())
    }
}

/// in `reality` takes them: the same three numbers, in the type the relay and
/// the settings reader share, so neither side can pass the upload limit where
/// the download limit belongs without the compiler noticing.
fn fallback_limit(limit: zero_config::FallbackLimit) -> reality::fallback::FallbackLimit {
    reality::fallback::FallbackLimit::new(
        limit.after_bytes,
        limit.bytes_per_sec,
        limit.burst_bytes_per_sec,
    )
}

#[cfg(test)]
mod tun_state_tests {
    use super::*;

    #[test]
    fn the_tun_counts_as_lost_only_after_it_was_served_and_ended() {
        let stats = Stats::default();
        assert!(!stats.tun_lost(), "a runtime with no TUN has lost nothing");
        stats.tun.store(TUN_UP, Ordering::Relaxed);
        assert!(!stats.tun_lost());
        stats.tun.store(TUN_LOST, Ordering::Relaxed);
        assert!(stats.tun_lost());
    }
}
