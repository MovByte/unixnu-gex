//! Signals.
//!
//! Delivery works because of the tail-call design: every host call flushes the
//! guest's registers to the thread context first, so at any syscall or safepoint
//! the architectural state is complete and a handler frame can be built from it.
//! Resuming is just re-entering translated code at a different PC -- there is no
//! wasm stack to unwind.
//!
//! Returning from a handler: a libc that sets `SA_RESTORER` returns to its own
//! trampoline, which issues `rt_sigreturn`. Otherwise the return address is
//! [`SIGRETURN_TRAMPOLINE`], a reserved address with no translation, so
//! branching to it lands in the dispatch-miss handler, which restores the frame.

use crate::errno::Errno;
use crate::GuestMem;
use gex_abi::ctx;
use crate::sync::{Mutex, RwLock};
use std::sync::atomic::{AtomicU64, Ordering};
use std::sync::Arc;

/// Signal numbers.
pub mod sig {
    pub const SIGHUP: u32 = 1;
    pub const SIGINT: u32 = 2;
    pub const SIGQUIT: u32 = 3;
    pub const SIGILL: u32 = 4;
    pub const SIGTRAP: u32 = 5;
    pub const SIGABRT: u32 = 6;
    pub const SIGBUS: u32 = 7;
    pub const SIGFPE: u32 = 8;
    pub const SIGKILL: u32 = 9;
    pub const SIGUSR1: u32 = 10;
    pub const SIGSEGV: u32 = 11;
    pub const SIGUSR2: u32 = 12;
    pub const SIGPIPE: u32 = 13;
    pub const SIGALRM: u32 = 14;
    pub const SIGTERM: u32 = 15;
    pub const SIGCHLD: u32 = 17;
    pub const SIGCONT: u32 = 18;
    pub const SIGSTOP: u32 = 19;
    pub const SIGTSTP: u32 = 20;
    pub const SIGVTALRM: u32 = 26;
    pub const SIGPROF: u32 = 27;
    pub const SIGWINCH: u32 = 28;
    pub const SIGSYS: u32 = 31;
    /// Signals 1..=64 exist; 0 is "no signal".
    pub const MAX: u32 = 64;
}

/// `sa_flags` bits.
pub mod sa {
    pub const NOCLDSTOP: u64 = 0x0000_0001;
    pub const NOCLDWAIT: u64 = 0x0000_0002;
    pub const SIGINFO: u64 = 0x0000_0004;
    pub const RESTORER: u64 = 0x0400_0000;
    pub const ONSTACK: u64 = 0x0800_0000;
    pub const RESTART: u64 = 0x1000_0000;
    pub const NODEFER: u64 = 0x4000_0000;
    pub const RESETHAND: u64 = 0x8000_0000;
}

/// `SIG_DFL`.
pub const SIG_DFL: u64 = 0;
/// `SIG_IGN`.
pub const SIG_IGN: u64 = 1;

/// Return address installed when the guest supplies no `sa_restorer`. In the
/// reserved region and deliberately without a translation, so returning to it
/// reaches the dispatch-miss handler.
pub const SIGRETURN_TRAMPOLINE: u64 = gex_abi::RESERVED_END - 16;

/// What the kernel should do when a signal has no handler.
#[derive(Copy, Clone, PartialEq, Eq, Debug)]
pub enum DefaultAction {
    /// Terminate the process.
    Terminate,
    /// Terminate and note that a core would have been written.
    Core,
    /// Discard the signal.
    Ignore,
    /// Stop the process.
    Stop,
    /// Continue a stopped process.
    Continue,
}

/// The default disposition of a signal.
pub fn default_action(signal: u32) -> DefaultAction {
    match signal {
        sig::SIGCHLD | sig::SIGCONT | sig::SIGWINCH | 29 => DefaultAction::Ignore,
        sig::SIGSTOP | sig::SIGTSTP | 21 | 22 => DefaultAction::Stop,
        sig::SIGQUIT
        | sig::SIGILL
        | sig::SIGTRAP
        | sig::SIGABRT
        | sig::SIGBUS
        | sig::SIGFPE
        | sig::SIGSEGV
        | sig::SIGSYS => DefaultAction::Core,
        _ => DefaultAction::Terminate,
    }
}

/// One installed disposition.
#[derive(Copy, Clone, Debug, Default)]
pub struct SigAction {
    pub handler: u64,
    pub flags: u64,
    pub restorer: u64,
    pub mask: u64,
}

/// An alternate signal stack.
#[derive(Copy, Clone, Debug, Default)]
pub struct SigAltStack {
    pub sp: u64,
    pub flags: u32,
    pub size: u64,
}

/// What the caller should do after the kernel considered a pending signal.
#[derive(Clone, Debug, PartialEq, Eq)]
pub enum Delivery {
    /// Nothing to deliver; carry on.
    None,
    /// A handler frame is set up; resume translated code at this address.
    Resume(u64),
    /// No handler, and the default disposition ends the process.
    Terminate { signal: u32, core: bool },
}

/// Slots in a per-signal table: index 0 is unused, as in a `sigset_t`.
const NSIG: usize = sig::MAX as usize + 1;

/// One armed interval timer.
///
/// Times are absolute nanoseconds on the same clock the guest reads, because
/// a deadline compared against a clock that can be replaced per host has to
/// be in that clock's terms.
#[derive(Copy, Clone, Debug, PartialEq, Eq)]
pub struct Itimer {
    /// When it next fires.
    pub next: u128,
    /// What to reload on firing. Zero is a one-shot timer, which disarms.
    pub interval: u128,
}

/// No timer armed, in [`ProcSig`]'s `timer_next`.
const NO_TIMER: u64 = u64::MAX;

/// The process's part of the signal state, shared by its threads and read
/// without the kernel lock: dispositions behind
/// an `RwLock`, the process-directed pending set as one atomic word (with
/// its senders behind a `Mutex`), and the interval timers, whose earliest
/// deadline is an atomic word so asking "is one due" takes no lock.
pub struct ProcSig {
    actions: RwLock<[SigAction; NSIG]>,
    /// Process-directed signals (another process's `kill`, a timer, a
    /// child's exit): any thread that does not block one may take it. A
    /// thread's own (`tgkill`, faults) are its [`ThreadSig`]'s. Linux keeps
    /// the two sets apart the same way.
    shared: AtomicU64,
    shared_sources: Mutex<[Option<Source>; NSIG]>,
    /// The interval timers, indexed by `which`.
    timers: Mutex<[Option<Itimer>; 3]>,
    /// The earliest armed timer's deadline, clamped to `u64`; [`NO_TIMER`]
    /// when none is armed. Written under `timers`.
    timer_next: AtomicU64,
    /// Held across a [`ProcSig::collect`]'s take of the inbox and its
    /// raise, so a collect that finds the inbox empty because another is
    /// under way waits for that one's signals to be pending.
    collecting: Mutex<()>,
    /// Each process-directed signal as it is posted, for a kernel that
    /// tells its knotes of them (Darwin's `proc_knote(NOTE_SIGNAL)`), and
    /// how it is told; empty and unset for any other.
    posted: Mutex<Vec<u32>>,
    /// The part of `posted` this process raised itself (the rest came
    /// through the process table, which told of them as it posted them).
    local_posted: Mutex<Vec<u32>>,
    /// `posted` again, for the kernel's own work at each post (Darwin's
    /// `psignal`: a thread chosen, a stop or a continue acted on), in
    /// order where the pending set keeps one bit a signal.
    to_assign: Mutex<Vec<(u32, Option<Note>)>>,
    post_hook: std::sync::OnceLock<Box<dyn Fn() + Send + Sync>>,
    /// What each signal does with no handler, for a personality whose
    /// defaults are not Linux's ([`default_action`] when unset).
    defaults: std::sync::OnceLock<fn(u32) -> DefaultAction>,
}

impl std::fmt::Debug for ProcSig {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        f.debug_struct("ProcSig")
            .field("shared", &format_args!("{:#x}", self.shared.load(Ordering::Relaxed)))
            .field("timer_next", &self.timer_next.load(Ordering::Relaxed))
            .finish_non_exhaustive()
    }
}

impl ProcSig {
    fn with_actions(actions: [SigAction; NSIG]) -> ProcSig {
        ProcSig {
            actions: RwLock::new(actions),
            shared: AtomicU64::new(0),
            shared_sources: Mutex::new([None; NSIG]),
            timers: Mutex::new([None; 3]),
            collecting: Mutex::new(()),
            timer_next: AtomicU64::new(NO_TIMER),
            posted: Mutex::new(Vec::new()),
            local_posted: Mutex::new(Vec::new()),
            to_assign: Mutex::new(Vec::new()),
            post_hook: std::sync::OnceLock::new(),
            defaults: std::sync::OnceLock::new(),
        }
    }

    /// Take `f` for what a signal does by default ([`ProcSig::default_of`]).
    pub fn set_defaults(&self, f: fn(u32) -> DefaultAction) {
        let _ = self.defaults.set(f);
    }

    /// What `signal` does with no handler in this process.
    pub fn default_of(&self, signal: u32) -> DefaultAction {
        self.defaults.get().map_or_else(|| default_action(signal), |f| f(signal))
    }

    /// Take `signal` off the process-directed pending set, with its sender;
    /// `None` when it is not there.
    pub fn take_shared(&self, signal: u32) -> Option<Option<Source>> {
        let b = bit(signal);
        if self.shared.fetch_and(!b, Ordering::AcqRel) & b == 0 {
            return None;
        }
        Some(self.shared_sources.lock()[signal as usize].take())
    }

    /// Drop `signal` from the process-directed pending set.
    pub fn discard(&self, signal: u32) {
        self.shared.fetch_and(!bit(signal), Ordering::AcqRel);
    }

    /// Ask to be told of every process-directed signal posted from now on
    /// ([`ProcSig::take_posted`]); `hook` runs after each is recorded.
    pub fn set_post_hook(&self, hook: Box<dyn Fn() + Send + Sync>) {
        let _ = self.post_hook.set(hook);
    }

    /// The process-directed signals posted since the last take, in order.
    pub fn take_posted(&self) -> Vec<u32> {
        std::mem::take(&mut *self.posted.lock())
    }

    /// Those of them the process raised itself.
    pub fn take_local_posted(&self) -> Vec<u32> {
        std::mem::take(&mut *self.local_posted.lock())
    }

    /// The posts since the last take, in order, for the kernel's own work
    /// at each.
    pub fn take_to_assign(&self) -> Vec<(u32, Option<Note>)> {
        std::mem::take(&mut *self.to_assign.lock())
    }

    /// Mark a process-directed signal pending: whichever thread does not
    /// block it takes it.
    pub fn raise(&self, signal: u32, source: Option<Source>) {
        self.raise_noted(signal, source, None);
    }

    /// [`ProcSig::raise`], with what the kernel that hears the post is to
    /// know of it (Darwin's: the reason the signal carries).
    pub fn raise_noted(&self, signal: u32, source: Option<Source>, note: Option<Note>) {
        if signal > 0 && signal <= sig::MAX {
            self.raise_quiet(signal, source);
            if let Some(hook) = self.post_hook.get() {
                self.posted.lock().push(signal);
                self.local_posted.lock().push(signal);
                self.to_assign.lock().push((signal, note));
                hook();
            }
        }
    }

    /// Tell the post hook of a post the kernel gave one thread itself
    /// (Darwin's PSIG_TRY_THREAD): its knotes hear of it as of any.
    pub fn record_post(&self, signal: u32) {
        if let Some(hook) = self.post_hook.get() {
            self.posted.lock().push(signal);
            self.local_posted.lock().push(signal);
            hook();
        }
    }

    /// [`ProcSig::raise`] without telling the post hook: a signal whose
    /// posting was recorded where it was sent.
    fn raise_quiet(&self, signal: u32, source: Option<Source>) {
        if signal > 0 && signal <= sig::MAX {
            self.shared_sources.lock()[signal as usize] = source;
            self.shared.fetch_or(bit(signal), Ordering::AcqRel);
        }
    }

    /// The process-directed pending set.
    pub fn shared(&self) -> u64 {
        self.shared.load(Ordering::Acquire)
    }

    pub fn action(&self, signal: u32) -> SigAction {
        self.actions.read()[(signal as usize).min(sig::MAX as usize)]
    }

    /// Whether a signal that would do something is ready for a thread whose
    /// own pending set and mask are `pending` and `blocked`, counting this
    /// process's shared set. An ignored one, or one whose default is to be
    /// ignored, does not count: see [`Signals::would_deliver`].
    pub fn would_deliver_with(&self, pending: u64, blocked: u64) -> bool {
        let mut ready = (pending | self.shared()) & !blocked;
        if ready == 0 {
            return false;
        }
        let actions = self.actions.read();
        while ready != 0 {
            let signal = ready.trailing_zeros() + 1;
            ready &= ready - 1;
            let action = actions[signal as usize];
            if action.handler == SIG_IGN {
                continue;
            }
            if action.handler == SIG_DFL && self.default_of(signal) == DefaultAction::Ignore {
                continue;
            }
            return true;
        }
        false
    }

    /// Interval timer `which`.
    pub fn timer(&self, which: usize) -> Option<Itimer> {
        self.timers.lock().get(which).copied().flatten()
    }

    /// Arm or disarm interval timer `which`.
    pub fn set_timer(&self, which: usize, t: Option<Itimer>) {
        let mut timers = self.timers.lock();
        if let Some(slot) = timers.get_mut(which) {
            *slot = t;
        }
        self.timer_next.store(earliest(&timers), Ordering::Release);
    }

    /// Whether any interval timer is armed.
    pub fn timers_armed(&self) -> bool {
        self.timer_next.load(Ordering::Acquire) != NO_TIMER
    }

    /// Whether an interval timer has expired at `now` and has yet to raise
    /// its signal.
    pub fn timer_due(&self, now: u128) -> bool {
        let next = self.timer_next.load(Ordering::Acquire);
        next != NO_TIMER && now >= next as u128
    }

    /// How long from `now` until the next interval timer fires, if one is
    /// armed.
    pub fn timer_in_ns(&self, now: u128) -> Option<u64> {
        let next = self.timer_next.load(Ordering::Acquire);
        (next != NO_TIMER).then(|| (next as u128).saturating_sub(now).min(u64::MAX as u128) as u64)
    }

    /// Fire any timer whose deadline has passed at `now`, and reload it if
    /// it repeats.
    ///
    /// `ITIMER_VIRTUAL`/`ITIMER_PROF` should count CPU time but are driven
    /// from the same wall clock as the rest.
    pub fn fire_timers(&self, now: u128) {
        if !self.timer_due(now) {
            return;
        }
        let mut timers = self.timers.lock();
        for which in 0..3 {
            let Some(timer) = timers[which] else {
                continue;
            };
            if now < timer.next {
                continue;
            }
            timers[which] = if timer.interval == 0 {
                None
            } else {
                // Skip whole missed periods rather than firing once per
                // period afterwards: a guest that was away for a second with
                // a millisecond timer does not want a thousand signals.
                let missed = (now - timer.next) / timer.interval + 1;
                Some(Itimer {
                    next: timer.next + missed * timer.interval,
                    interval: timer.interval,
                })
            };
            self.raise(
                match which {
                    1 => sig::SIGVTALRM,
                    2 => sig::SIGPROF,
                    _ => sig::SIGALRM,
                },
                None,
            );
        }
        self.timer_next.store(earliest(&timers), Ordering::Release);
    }

    /// Move signals other processes have sent this one (`pid`) into its
    /// shared pending set, with who sent each that `kill` sent. Returns what
    /// arrived.
    ///
    /// `kill` cannot reach into another process's kernel -- each has its own
    /// -- so it leaves the signal on a shared per-process word and the target
    /// picks it up here. This is what makes `timeout`, job control and every
    /// supervisor work.
    ///
    /// One step to any other collector of this process: a `kill` to its own
    /// process that finds its signal already taken by another thread's
    /// collect waits here until that collect has raised it, so the signal
    /// is pending when the `kill` returns (a `sigtimedwait` after it found
    /// nothing, one time in a few hundred, in the page).
    pub fn collect(&self, procs: &crate::proc::ProcTable, pid: i32, uid: u32) -> u64 {
        let _one = self.collecting.lock();
        let inbox = procs.take_signals(pid);
        if inbox == 0 {
            return 0;
        }
        // Each post, as the table kept them (one a signal where it keeps
        // none), for a kernel that is told of posts.
        let posts = procs.take_posts(pid).unwrap_or_else(|| (1..=64u32).filter(|s| inbox & (1u64 << (s - 1)) != 0).map(|s| (s, None)).collect());
        // Each signal raised once, with its sender: raised twice, a thread
        // delivering between the two (without the kernel lock) would see it
        // pending again after taking it.
        let mut sources = [None; NSIG];
        for (signo, pid) in procs.take_kill_senders(pid, inbox) {
            if let Some(slot) = sources.get_mut(signo as usize) {
                *slot = Some(Source { code: SI_USER, pid, uid });
            }
        }
        for signo in 1..=64u32 {
            if inbox & (1u64 << (signo - 1)) != 0 {
                self.raise_quiet(signo, sources[signo as usize]);
            }
        }
        if let Some(hook) = self.post_hook.get() {
            self.posted.lock().extend(posts.iter().map(|&(s, _)| s));
            self.to_assign.lock().extend(posts);
            hook();
        }
        inbox
    }
}

fn earliest(timers: &[Option<Itimer>; 3]) -> u64 {
    timers
        .iter()
        .flatten()
        .map(|t| t.next.min(NO_TIMER as u128 - 1) as u64)
        .min()
        .unwrap_or(NO_TIMER)
}

/// The handler state of one thread that only that thread reads or writes:
/// its alternate stack and what the frame it is in looks like.
#[derive(Copy, Clone, Debug, Default)]
pub struct Own {
    pub alt_stack: SigAltStack,
    /// Set while a handler runs, so `rt_sigreturn` knows a frame exists.
    pub in_handler: bool,
    /// The i386 frame most recently set up was the non-rt `sigframe` (a
    /// handler without `SA_SIGINFO`), whose `sigreturn` reads a different
    /// layout. Decided where the frame is written, because the return may
    /// arrive through the host trampoline as well as through `int 0x80`.
    pub legacy_frame: bool,
    /// The mask a signal frame should record instead of the current one.
    ///
    /// `rt_sigsuspend` runs with a caller-chosen mask and must restore the old
    /// one *after* the handler returns; the frame carries the mask across. So
    /// suspend leaves the old mask here, `setup_frame` writes it into the frame,
    /// and `sigreturn` restores it -- without it the woken signal stays blocked
    /// and pending forever (`timeout` spun 2.2 million times).
    pub suspend_restore: Option<u64>,
}

/// Every thread's own signal state in a process, by tid, behind its own
/// lock: what a `tgkill` to a thread of the same process raises on,
/// whether its sender holds the kernel or not. Shared (`Arc`) between the
/// process's kernel and its host's lock-free calls; a fork's is new. A leaf
/// lock: nothing is called with it held.
#[derive(Default)]
pub struct ThreadSigs(Mutex<std::collections::HashMap<i32, Arc<ThreadSig>>>);

impl std::fmt::Debug for ThreadSigs {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        f.debug_set().entries(self.tids_in_order()).finish()
    }
}

impl ThreadSigs {
    pub fn get(&self, tid: i32) -> Option<Arc<ThreadSig>> {
        self.0.lock().get(&tid).cloned()
    }

    /// Every thread's id, in the order the threads were made (thread ids
    /// only grow).
    pub fn tids_in_order(&self) -> Vec<i32> {
        let mut v = self.tids();
        v.sort_unstable();
        v
    }

    /// Drop `signal` from every thread's own pending set.
    pub fn discard(&self, signal: u32) {
        for t in self.0.lock().values() {
            t.pending.fetch_and(!bit(signal), Ordering::AcqRel);
        }
    }

    pub fn contains(&self, tid: i32) -> bool {
        self.0.lock().contains_key(&tid)
    }

    pub fn insert(&self, tid: i32, t: Arc<ThreadSig>) {
        self.0.lock().insert(tid, t);
    }

    /// `tid`'s, made by `make` if it has none yet.
    pub fn get_or_insert_with(&self, tid: i32, make: impl FnOnce() -> Arc<ThreadSig>) -> Arc<ThreadSig> {
        Arc::clone(self.0.lock().entry(tid).or_insert_with(make))
    }

    pub fn remove(&self, tid: i32) {
        self.0.lock().remove(&tid);
    }

    pub fn clear(&self) {
        self.0.lock().clear();
    }

    /// The tids it holds, as it holds them now.
    pub fn tids(&self) -> Vec<i32> {
        self.0.lock().keys().copied().collect()
    }
}

/// One thread's signal state, shared (`Arc`) between the thread and whoever
/// sends it a signal or asks whether it has one ready. Its pending set and
/// mask are atomic words
/// any thread reads without a lock; only the thread itself writes the mask
/// and [`Own`].
pub struct ThreadSig {
    /// Signals raised for this thread alone (`tgkill`, faults) and not yet
    /// delivered.
    pending: AtomicU64,
    /// Signals the thread has blocked.
    blocked: AtomicU64,
    /// Who sent each pending signal, when a process did (`kill`, `tgkill`):
    /// what its siginfo reports instead of `SI_KERNEL`. `None` for one the
    /// kernel raised itself.
    sources: Mutex<[Option<Source>; NSIG]>,
    own: Mutex<Own>,
    /// Where the thread's exit writes zero and futex-wakes (what
    /// `pthread_join` waits on): `CLONE_CHILD_CLEARTID`'s word, or
    /// `set_tid_address`'s. Zero for none.
    clear_child_tid: AtomicU64,
    /// A Darwin thread's `thread_id`, and its TSD base (`cthread_self`),
    /// for other processes to read.
    darwin_id: AtomicU64,
    tsd: AtomicU64,
    /// A Darwin thread's name (`uu_pth_name`), once it has been given one.
    name: Mutex<Option<Vec<u8>>>,
    /// A Darwin thread's exit reason (`uu_exit_reason`): the first a
    /// signal brought it, kept for the life of the thread.
    exit_reason: Mutex<Option<Note>>,
    /// Its processor time.
    pub cpu: crate::cpu::ThreadCpu,
}

impl std::fmt::Debug for ThreadSig {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        f.debug_struct("ThreadSig")
            .field("pending", &format_args!("{:#x}", self.pending()))
            .field("blocked", &format_args!("{:#x}", self.blocked()))
            .finish_non_exhaustive()
    }
}

impl ThreadSig {
    /// A new thread's: its creator's mask, nothing pending, no alternate
    /// stack (a thread sets its own), not in a handler.
    pub fn new_thread(blocked: u64) -> ThreadSig {
        ThreadSig {
            pending: AtomicU64::new(0),
            blocked: AtomicU64::new(blocked),
            sources: Mutex::new([None; NSIG]),
            own: Mutex::new(Own::default()),
            clear_child_tid: AtomicU64::new(0),
            darwin_id: AtomicU64::new(0),
            tsd: AtomicU64::new(0),
            name: Mutex::new(None),
            exit_reason: Mutex::new(None),
            cpu: crate::cpu::ThreadCpu::default(),
        }
    }

    /// A Darwin thread's `thread_id` (zero before it has one).
    pub fn darwin_id(&self) -> u64 {
        self.darwin_id.load(Ordering::Acquire)
    }

    pub fn set_darwin_id(&self, id: u64) {
        self.darwin_id.store(id, Ordering::Release);
    }

    /// A Darwin thread's TSD base (`machine.cthread_self`).
    pub fn tsd(&self) -> u64 {
        self.tsd.load(Ordering::Acquire)
    }

    pub fn set_tsd(&self, tsd: u64) {
        self.tsd.store(tsd, Ordering::Release);
    }

    /// A Darwin thread's name (none before it is named).
    pub fn name(&self) -> Option<Vec<u8>> {
        self.name.lock().clone()
    }

    pub fn set_name(&self, name: Option<Vec<u8>>) {
        *self.name.lock() = name;
    }

    /// The thread's exit reason, if a signal gave it one.
    pub fn exit_reason(&self) -> Option<Note> {
        self.exit_reason.lock().clone()
    }

    /// Give the thread `note` as its exit reason unless it has one
    /// (`set_thread_exit_reason` where `uu_exit_reason` is null).
    pub fn set_exit_reason_if_none(&self, note: impl FnOnce() -> Note) {
        let mut r = self.exit_reason.lock();
        if r.is_none() {
            *r = Some(note());
        }
    }

    /// The word the thread's exit clears ([`Self::set_clear_child_tid`]).
    pub fn clear_child_tid(&self) -> u64 {
        self.clear_child_tid.load(Ordering::Acquire)
    }

    /// `set_tid_address`, or `CLONE_CHILD_CLEARTID` at its start: the word
    /// the thread's exit clears. Only the thread itself, or its creator
    /// before it runs, sets it.
    pub fn set_clear_child_tid(&self, addr: u64) {
        self.clear_child_tid.store(addr, Ordering::Release);
    }

    /// Mark a signal pending for this thread, sent by `source` (`None`: the
    /// kernel raised it). A standard signal does not queue, so the last
    /// sender is the one reported.
    pub fn raise(&self, signal: u32, source: Option<Source>) {
        if signal > 0 && signal <= sig::MAX {
            self.sources.lock()[signal as usize] = source;
            self.pending.fetch_or(bit(signal), Ordering::AcqRel);
        }
    }

    /// Mark a thread-directed signal pending, as sent by a process
    /// (`tgkill` to another thread).
    pub fn raise_from(&self, signal: u32, source: Source) {
        self.raise(signal, Some(source));
    }

    pub fn pending(&self) -> u64 {
        self.pending.load(Ordering::Acquire)
    }

    /// Drop the signals in `mask` from this thread's own pending set.
    pub fn discard_mask(&self, mask: u64) {
        self.pending.fetch_and(!mask, Ordering::AcqRel);
    }

    pub fn blocked(&self) -> u64 {
        self.blocked.load(Ordering::Acquire)
    }

    /// Set this thread's mask from outside it (a thread the kernel makes
    /// with a mask of its own, before it runs).
    pub fn set_blocked(&self, mask: u64) {
        self.blocked.store(mask, Ordering::Release);
    }

    /// Whether a signal that would do something is ready for this thread,
    /// counting its process's shared set ([`ProcSig::would_deliver_with`]).
    /// Takes no lock unless an unblocked signal is pending.
    pub fn ready(&self, process: &ProcSig) -> bool {
        process.would_deliver_with(self.pending(), self.blocked())
    }
}

/// The calling thread's mask and [`Own`] state, copied out to be read and
/// changed by a frame being built or unwound, and stored back when dropped.
/// Only the thread itself writes them, so the copy cannot go stale.
pub struct OwnView<'a> {
    thread: &'a ThreadSig,
    pub blocked: u64,
    pub alt_stack: SigAltStack,
    pub in_handler: bool,
    pub legacy_frame: bool,
    pub suspend_restore: Option<u64>,
}

impl Drop for OwnView<'_> {
    fn drop(&mut self) {
        self.thread.blocked.store(self.blocked, Ordering::Release);
        *self.thread.own.lock() = Own {
            alt_stack: self.alt_stack,
            in_handler: self.in_handler,
            legacy_frame: self.legacy_frame,
            suspend_restore: self.suspend_restore,
        };
    }
}

/// A process's signal state as one thread sees it: the process's
/// [`ProcSig`] and the running thread's [`ThreadSig`]. Which thread is
/// running is a pointer to swap ([`Signals::switch_to`]), not state to copy
/// in and out.
#[derive(Debug)]
pub struct Signals {
    proc: Arc<ProcSig>,
    cur: Arc<ThreadSig>,
}

impl Default for Signals {
    fn default() -> Self {
        Self::new()
    }
}

impl Signals {
    pub fn new() -> Signals {
        Signals {
            proc: Arc::new(ProcSig::with_actions([SigAction::default(); NSIG])),
            cur: Arc::new(ThreadSig::new_thread(0)),
        }
    }

    /// The process's part.
    pub fn process(&self) -> &Arc<ProcSig> {
        &self.proc
    }

    /// The running thread's part.
    pub fn thread(&self) -> &Arc<ThreadSig> {
        &self.cur
    }

    /// Make `t` the running thread's part.
    pub fn switch_to(&mut self, t: Arc<ThreadSig>) {
        self.cur = t;
    }

    /// The signal state a forked child starts with.
    ///
    /// Dispositions, the blocked mask and the alternate stack are inherited;
    /// the pending set is not, nor are the timers, and neither is a handler
    /// frame -- the child begins between instructions, not inside a handler.
    pub fn fork(&self) -> Signals {
        let cur = ThreadSig::new_thread(self.blocked());
        cur.own.lock().alt_stack = self.alt_stack();
        Signals {
            proc: Arc::new(ProcSig::with_actions(*self.proc.actions.read())),
            cur: Arc::new(cur),
        }
    }

    /// The signal state after `execve`.
    ///
    /// A handler is an address in the old image, so every caught signal reverts
    /// to default -- otherwise the new program inherits the address of a handler
    /// that no longer exists (`timeout 3 sleep 30` would jump into dash's old
    /// handler). Ignored stays ignored, the blocked mask and pending signals
    /// carry over, per POSIX; the alternate stack does not -- it too pointed into
    /// the old image.
    pub fn exec(&self) {
        for action in self.proc.actions.write().iter_mut() {
            if action.handler != SIG_DFL && action.handler != SIG_IGN {
                *action = SigAction::default();
            }
        }
        let mut own = self.cur.own.lock();
        own.alt_stack = SigAltStack::default();
        own.in_handler = false;
        own.suspend_restore = None;
        // The word was in the old image: Linux forgets it (`mm_release`).
        self.cur.set_clear_child_tid(0);
    }

    pub fn action(&self, signal: u32) -> SigAction {
        self.proc.action(signal)
    }

    pub fn set_action(&self, signal: u32, action: SigAction) -> Result<(), Errno> {
        // SIGKILL and SIGSTOP cannot be caught or ignored.
        if signal == 0 || signal > sig::MAX || signal == sig::SIGKILL || signal == sig::SIGSTOP {
            return Err(Errno::EINVAL);
        }
        // Nor blocked, by a handler's mask either (Linux strips them).
        let mut action = action;
        action.mask &= !(bit(sig::SIGKILL) | bit(sig::SIGSTOP));
        self.proc.actions.write()[signal as usize] = action;
        Ok(())
    }

    /// The running thread's mask.
    pub fn blocked(&self) -> u64 {
        self.cur.blocked()
    }

    /// Set the running thread's mask.
    pub fn set_blocked(&self, mask: u64) {
        self.cur.blocked.store(mask, Ordering::Release);
    }

    pub fn alt_stack(&self) -> SigAltStack {
        self.cur.own.lock().alt_stack
    }

    pub fn set_alt_stack(&self, a: SigAltStack) {
        self.cur.own.lock().alt_stack = a;
    }

    /// Whether the running thread is in a handler.
    pub fn in_handler(&self) -> bool {
        self.cur.own.lock().in_handler
    }

    /// Leave `mask` for the next frame to record (`rt_sigsuspend`); see
    /// [`Own::suspend_restore`].
    pub fn set_suspend_restore(&self, mask: Option<u64>) {
        self.cur.own.lock().suspend_restore = mask;
    }

    pub fn take_suspend_restore(&self) -> Option<u64> {
        self.cur.own.lock().suspend_restore.take()
    }

    /// The running thread's mask and handler state, to change and store
    /// back on drop.
    pub fn own(&self) -> OwnView<'_> {
        let own = *self.cur.own.lock();
        OwnView {
            thread: &self.cur,
            blocked: self.cur.blocked(),
            alt_stack: own.alt_stack,
            in_handler: own.in_handler,
            legacy_frame: own.legacy_frame,
            suspend_restore: own.suspend_restore,
        }
    }

    /// Mark a process-directed signal pending: whichever thread does not
    /// block it takes it.
    pub fn raise_shared(&self, signal: u32, source: Option<Source>) {
        self.proc.raise(signal, source);
    }

    /// Mark a signal pending, as the kernel raising it itself (`SI_KERNEL`).
    pub fn raise(&self, signal: u32) {
        self.cur.raise(signal, None);
    }

    /// Mark a signal pending, as sent by a process: `kill` (`SI_USER`) or
    /// `tkill`/`tgkill` (`SI_TKILL`). A standard signal does not queue, so the
    /// last sender is the one reported.
    pub fn raise_from(&self, signal: u32, source: Source) {
        self.cur.raise(signal, Some(source));
    }

    /// Drop `signal` wherever it is pending: the running thread's, every
    /// other thread's in `threads`, the process's.
    pub fn discard_everywhere(&self, signal: u32, threads: &ThreadSigs) {
        self.cur.pending.fetch_and(!bit(signal), Ordering::AcqRel);
        threads.discard(signal);
        self.proc.discard(signal);
    }

    /// Clear `signal` as delivered or taken: the thread's own first, else
    /// the process's.
    pub fn clear_pending(&self, signal: u32) {
        let b = bit(signal);
        if self.cur.pending.fetch_and(!b, Ordering::AcqRel) & b == 0 {
            self.proc.shared.fetch_and(!b, Ordering::AcqRel);
        }
    }

    /// Take `signal` off the pending sets to deliver it, with who sent it:
    /// the thread's own first, else the process's. `None` when it is no
    /// longer pending, because another thread took it first.
    pub fn claim(&self, signal: u32) -> Option<Option<Source>> {
        let b = bit(signal);
        let i = (signal as usize).min(sig::MAX as usize);
        if self.cur.pending.fetch_and(!b, Ordering::AcqRel) & b != 0 {
            return Some(self.cur.sources.lock()[i].take());
        }
        if self.proc.shared.fetch_and(!b, Ordering::AcqRel) & b != 0 {
            return Some(self.proc.shared_sources.lock()[i].take());
        }
        None
    }

    /// A process's signal state as thread `cur` sees it: for a host that
    /// delivers to its own thread without the kernel.
    pub fn view(proc: Arc<ProcSig>, cur: Arc<ThreadSig>) -> Signals {
        Signals { proc, cur }
    }

    /// Forget who sent `signal`: a synchronous fault reports itself, whatever
    /// a process may also have sent.
    pub fn forget_source(&self, signal: u32) {
        if signal > 0 && signal <= sig::MAX {
            self.cur.sources.lock()[signal as usize] = None;
        }
    }

    /// Take who sent `signal`, as its delivery reports it.
    pub fn take_source(&self, signal: u32) -> Option<Source> {
        let i = (signal as usize).min(sig::MAX as usize);
        if self.cur.pending() & bit(signal) != 0 {
            self.cur.sources.lock()[i].take()
        } else {
            self.proc.shared_sources.lock()[i].take()
        }
    }

    /// Take the lowest-numbered pending signal in `set`, blocked or not,
    /// with who sent it ([`Signals::claim`]: the thread's own first).
    ///
    /// `sigwaitinfo` is used precisely on signals the caller has blocked, so
    /// this deliberately ignores the mask [`Signals::next_deliverable`] respects.
    /// It claims rather than clearing and then asking for the sender: cleared
    /// first, a thread-directed signal's sender was looked for on the
    /// process's set, and a `tgkill` taken by `sigtimedwait` said `SI_KERNEL`.
    pub fn claim_in(&self, set: u64) -> Option<(u32, Option<Source>)> {
        loop {
            let ready = self.pending_raw() & set;
            if ready == 0 {
                return None;
            }
            let signal = ready.trailing_zeros() + 1;
            // Another thread took it between the look and the claim: the
            // next one, if any.
            if let Some(source) = self.claim(signal) {
                return Some((signal, source));
            }
        }
    }

    /// Everything raised, deliverable or not. For diagnostics only.
    pub fn pending_raw(&self) -> u64 {
        self.cur.pending() | self.proc.shared()
    }

    /// Thread `t`'s pending signals with this process's shared set.
    pub fn pending_raw_for(&self, t: &ThreadSig) -> u64 {
        t.pending() | self.proc.shared()
    }

    pub fn has_pending(&self) -> bool {
        self.pending_raw() & !self.blocked() != 0
    }

    /// Whether a pending signal would actually *do* something -- a handler, or a
    /// non-`Ignore` default. `has_pending` only asks whether an unblocked bit is
    /// set, which is wrong for ending a wait: `SIGCHLD` is ignored by default and
    /// arrives on every child exit, and would otherwise interrupt a shell's wait
    /// for nothing.
    pub fn would_deliver(&self) -> bool {
        self.cur.ready(&self.proc)
    }

    /// [`Self::would_deliver`] for a thread whose own pending set and mask
    /// are `pending` and `blocked` (with this process's dispositions and
    /// shared set).
    pub fn would_deliver_with(&self, pending: u64, blocked: u64) -> bool {
        self.proc.would_deliver_with(pending, blocked)
    }

    /// [`Self::next_deliverable`], for a trace.
    pub fn peek_deliverable(&self) -> Option<u32> {
        self.next_deliverable()
    }

    /// Whether a call of restart class `class`, its wait ended by a signal,
    /// starts again (from its instruction, as the guest made it) rather than
    /// answering `EINTR`: Linux's `-ERESTARTSYS`, `-ERESTARTNOINTR` and
    /// `-ERESTARTNOHAND` (signal(7), "Interruption of system calls"). The
    /// signal is the one about to be delivered: a handler installed with
    /// `SA_RESTART` restarts an [`Restart::SaRestart`] call, any handler ends
    /// an [`Restart::NoHandler`] one, and with no handler to run (a default
    /// that ends the process, or nothing deliverable after all) every class
    /// but [`Restart::Never`] restarts.
    pub fn restarts(&self, class: Restart) -> bool {
        if class == Restart::Never {
            return false;
        }
        if class == Restart::Always {
            return true;
        }
        let Some(signal) = self.next_deliverable() else { return true };
        let action = self.action(signal);
        if action.handler == SIG_IGN || action.handler == SIG_DFL {
            return true;
        }
        class == Restart::SaRestart && action.flags & sa::RESTART != 0
    }

    /// The lowest-numbered deliverable signal, if any.
    fn next_deliverable(&self) -> Option<u32> {
        let ready = self.pending_raw() & !self.blocked();
        if ready == 0 {
            return None;
        }
        Some(ready.trailing_zeros() + 1)
    }

    /// The running thread's signal state as bytes, for another Worker to
    /// rebuild with [`Signals::from_bytes`]: the dispositions, the mask and
    /// the alternate stack, which is what a `fork` child inherits
    /// ([`Signals::fork`]), and with `pending` the pending sets too, which
    /// an `execve` keeps. Who sent each pending signal is not kept, nor are
    /// the timers.
    pub fn to_bytes(&self, pending: bool) -> Vec<u8> {
        let mut v = Vec::with_capacity(STATE_BYTES);
        for a in self.proc.actions.read().iter() {
            for w in [a.handler, a.flags, a.restorer, a.mask] {
                v.extend_from_slice(&w.to_le_bytes());
            }
        }
        let alt = self.alt_stack();
        let (mine, shared) = if pending { (self.cur.pending(), self.proc.shared()) } else { (0, 0) };
        for w in [self.blocked(), alt.sp, alt.flags as u64, alt.size, mine, shared] {
            v.extend_from_slice(&w.to_le_bytes());
        }
        v
    }

    /// A process's signal state from [`Signals::to_bytes`], or `None` for
    /// bytes that are not one.
    pub fn from_bytes(b: &[u8]) -> Option<Signals> {
        if b.len() != STATE_BYTES {
            return None;
        }
        let w = |i: usize| u64::from_le_bytes(b[i * 8..i * 8 + 8].try_into().unwrap());
        let mut actions = [SigAction::default(); NSIG];
        for (i, a) in actions.iter_mut().enumerate() {
            *a = SigAction { handler: w(i * 4), flags: w(i * 4 + 1), restorer: w(i * 4 + 2), mask: w(i * 4 + 3) };
        }
        let o = NSIG * 4;
        let cur = ThreadSig::new_thread(w(o));
        cur.own.lock().alt_stack = SigAltStack { sp: w(o + 1), flags: w(o + 2) as u32, size: w(o + 3) };
        cur.pending.store(w(o + 4), Ordering::Release);
        let proc = ProcSig::with_actions(actions);
        proc.shared.store(w(o + 5), Ordering::Release);
        Some(Signals { proc: Arc::new(proc), cur: Arc::new(cur) })
    }
}

/// How a blocking call a signal interrupts ends ([`Signals::restarts`]).
#[derive(Debug, Clone, Copy, PartialEq, Eq, Default)]
pub enum Restart {
    /// `EINTR`, handler or not: a wait with a timeout the caller chose
    /// (`poll`, `select`, `epoll_wait`, `nanosleep`, a timed futex wait,
    /// `sigsuspend`). Linux restarts some of these when no handler runs, but
    /// such a signal never ends a wait here.
    #[default]
    Never,
    /// Restarted after a handler with `SA_RESTART`, and when no handler
    /// runs; `EINTR` after any other handler (`-ERESTARTSYS`): `read`,
    /// `write`, `wait4`, `accept`, an untimed futex wait.
    SaRestart,
    /// Restarted after a handler too (`-ERESTARTNOINTR`): `FUTEX_LOCK_PI`.
    Always,
}

/// The length of [`Signals::to_bytes`]: four words a disposition, then the
/// mask, the alternate stack's three and the two pending sets.
const STATE_BYTES: usize = (NSIG * 4 + 6) * 8;

/// What a personality's kernel is told of a signal post beyond its number
/// (Darwin's: the reason it carries, `os_reason`).
pub type Note = std::sync::Arc<dyn std::any::Any + Send + Sync>;

/// A process that sent a signal, for its siginfo.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub struct Source {
    /// `si_code`: [`SI_USER`] or [`SI_TKILL`].
    pub code: i32,
    pub pid: i32,
    pub uid: u32,
}

/// `si_code` for a signal sent by `kill`.
pub const SI_USER: i32 = 0;
/// `si_code` for a signal sent by `tkill` or `tgkill`.
pub const SI_TKILL: i32 = -6;

/// Bit for a signal in a `sigset_t`. Signal 1 is bit 0.
fn bit(signal: u32) -> u64 {
    if signal == 0 || signal > 64 {
        0
    } else {
        1u64 << (signal - 1)
    }
}

/// Byte offsets inside the aarch64 signal frame the kernel builds.
///
/// The layout is `struct rt_sigframe`: a `siginfo_t` followed by a
/// `ucontext`, whose `uc_mcontext` is a `sigcontext`. Every offset here is
/// fixed ABI that libc unwinders and `longjmp` implementations read directly.
pub mod frame {
    /// `siginfo_t` occupies the first 128 bytes.
    pub const SIGINFO: usize = 0;
    pub const SIGINFO_SIZE: usize = 128;
    /// The `ucontext` follows it.
    pub const UCONTEXT: usize = SIGINFO_SIZE;
    /// Fields within the ucontext.
    pub const UC_FLAGS: usize = 0;
    pub const UC_LINK: usize = 8;
    pub const UC_STACK: usize = 16;
    pub const UC_SIGMASK: usize = 40;
    /// `uc_mcontext`, after the 128-byte signal mask.
    pub const UC_MCONTEXT: usize = 176;
    /// Fields within the `sigcontext`.
    pub const MC_FAULT_ADDRESS: usize = 0;
    pub const MC_REGS: usize = 8;
    pub const MC_SP: usize = 8 + 31 * 8;
    pub const MC_PC: usize = MC_SP + 8;
    pub const MC_PSTATE: usize = MC_PC + 8;
    /// `__reserved[4096]`, where the FP state record lives.
    pub const MC_RESERVED: usize = MC_PSTATE + 8;
    pub const SIGCONTEXT_SIZE: usize = MC_RESERVED + 4096;
    pub const UCONTEXT_SIZE: usize = UC_MCONTEXT + SIGCONTEXT_SIZE;
    pub const FRAME_SIZE: usize = UCONTEXT + UCONTEXT_SIZE;
}

/// Byte offsets inside the x86-64 `struct rt_sigframe`.
///
/// The return address the handler `ret`s through comes first, then the
/// `ucontext` (whose `uc_mcontext` is a `struct sigcontext` of 23 words in
/// the architecture's fixed order), then the `siginfo`. The FP state is a
/// separate 512-byte `fxsave` area above the frame that `uc_mcontext.fpstate`
/// points to. Fixed ABI: libc's unwinders and `swapcontext` read it.
pub mod xframe {
    pub const PRETCODE: usize = 0;
    pub const UCONTEXT: usize = 8;
    pub const UC_FLAGS: usize = 0;
    pub const UC_LINK: usize = 8;
    pub const UC_STACK: usize = 16;
    pub const UC_MCONTEXT: usize = 40;
    /// `sigcontext` words: r8..r15, rdi, rsi, rbp, rbx, rdx, rax, rcx, rsp,
    /// rip, eflags, then cs/gs/fs/ss packed, err, trapno, oldmask, cr2,
    /// fpstate pointer, and reserved space.
    pub const MC_R8: usize = 0;
    pub const MC_RDI: usize = 64;
    pub const MC_RSI: usize = 72;
    pub const MC_RBP: usize = 80;
    pub const MC_RBX: usize = 88;
    pub const MC_RDX: usize = 96;
    pub const MC_RAX: usize = 104;
    pub const MC_RCX: usize = 112;
    pub const MC_RSP: usize = 120;
    pub const MC_RIP: usize = 128;
    pub const MC_EFLAGS: usize = 136;
    pub const MC_CS: usize = 144;
    pub const MC_ERR: usize = 152;
    pub const MC_TRAPNO: usize = 160;
    pub const MC_OLDMASK: usize = 168;
    pub const MC_CR2: usize = 176;
    pub const MC_FPSTATE: usize = 184;
    pub const SIGCONTEXT_SIZE: usize = 256;
    pub const UC_SIGMASK: usize = UC_MCONTEXT + SIGCONTEXT_SIZE;
    pub const UCONTEXT_SIZE: usize = UC_SIGMASK + 8;
    pub const SIGINFO: usize = UCONTEXT + UCONTEXT_SIZE;
    pub const SIGINFO_SIZE: usize = 128;
    pub const FRAME_SIZE: usize = SIGINFO + SIGINFO_SIZE;
    /// The `fxsave` image.
    pub const FPSTATE_SIZE: usize = 512;
    /// The System V red zone below `rsp` a signal frame must not touch.
    pub const RED_ZONE: u64 = 128;
    /// `struct sigcontext` register order as gex GPR numbers.
    pub const GPR_ORDER: [u8; 16] = [8, 9, 10, 11, 12, 13, 14, 15, 7, 6, 5, 3, 2, 0, 1, 4];
}

/// Build a handler frame for `signal` and point the context at the handler.
///
/// Returns the address to resume at. The caller has already established that
/// a handler is installed.
pub fn setup_frame(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    ctx_addr: u64,
    signal: u32,
    fault_address: u64,
    compat: bool,
) -> Result<u64, Errno> {
    build_frame(signals, m, ctx_addr, signal, fault_address, compat, Taken::Fault)
}

/// Whose a signal a frame is built for is, and who sent it.
#[derive(Clone, Copy, Debug)]
enum Taken {
    /// A synchronous fault, raised by the running instruction: its siginfo
    /// reports the fault, and whatever is pending of it is cleared once the
    /// frame is built.
    Fault,
    /// A pending signal [`Signals::claim`] already took off the pending
    /// sets, with its sender.
    Claimed(Option<Source>),
}

fn build_frame(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    ctx_addr: u64,
    signal: u32,
    fault_address: u64,
    compat: bool,
    taken: Taken,
) -> Result<u64, Errno> {
    if compat {
        return setup_frame_i386(signals, m, ctx_addr, signal, fault_address, taken);
    }
    if gex_abi::X86 {
        return setup_frame_x86(signals, m, ctx_addr, signal, fault_address, taken);
    }
    let action = signals.action(signal);
    let sp = m.read_u64(ctx_addr + ctx::SP as u64)?;

    // An `SA_ONSTACK` handler runs on the alternate stack, but only if one is
    // installed and we are not already on it.
    let mut own = signals.own();
    let base = if action.flags & sa::ONSTACK != 0 && own.alt_stack.size > 0 {
        let alt = &own.alt_stack;
        let top = alt.sp + alt.size;
        if sp > alt.sp && sp <= top {
            sp
        } else {
            top
        }
    } else {
        sp
    };

    // The frame sits below the current stack pointer, 16-byte aligned.
    let frame_addr = (base - frame::FRAME_SIZE as u64) & !0xf;
    m.zero(frame_addr, frame::FRAME_SIZE)?;

    // siginfo: si_signo, si_errno, si_code, then the fault address for the
    // synchronous signals, which is what a crash handler reads.
    write_siginfo(signals, m, frame_addr, signal, fault_address, true, taken)?;

    let uc = frame_addr + frame::UCONTEXT as u64;
    m.write_u64(uc + frame::UC_FLAGS as u64, 0)?;
    m.write_u64(uc + frame::UC_LINK as u64, 0)?;
    // uc_stack describes the stack the handler is running on.
    m.write_u64(uc + frame::UC_STACK as u64, own.alt_stack.sp)?;
    m.write_u32(uc + frame::UC_STACK as u64 + 8, own.alt_stack.flags)?;
    m.write_u64(uc + frame::UC_STACK as u64 + 16, own.alt_stack.size)?;
    // The mask to restore on return is the one in force right now.
    m.write_u64(
        uc + frame::UC_SIGMASK as u64,
        own.suspend_restore.take().unwrap_or(own.blocked),
    )?;

    // The machine context: every general register, sp, pc and pstate, taken
    // from the thread context, which a host call has already made complete.
    let mc = uc + frame::UC_MCONTEXT as u64;
    m.write_u64(mc + frame::MC_FAULT_ADDRESS as u64, fault_address)?;
    for i in 0..31u8 {
        let v = m.read_u64(ctx_addr + ctx::x(i) as u64)?;
        m.write_u64(mc + frame::MC_REGS as u64 + i as u64 * 8, v)?;
    }
    m.write_u64(mc + frame::MC_SP as u64, sp)?;
    let pc = m.read_u64(ctx_addr + ctx::PC as u64)?;
    m.write_u64(mc + frame::MC_PC as u64, pc)?;
    m.write_u64(mc + frame::MC_PSTATE as u64, read_pstate(m, ctx_addr)?)?;

    // Block this signal for the duration of the handler unless asked not to,
    // plus whatever the action's mask names.
    own.blocked |= action.mask;
    if action.flags & sa::NODEFER == 0 {
        own.blocked |= bit(signal);
    }
    if let Taken::Fault = taken {
        signals.clear_pending(signal);
    }
    own.in_handler = true;

    // A one-shot handler reverts before it runs, as `SA_RESETHAND` requires.
    if action.flags & sa::RESETHAND != 0 {
        let _ = signals.set_action(signal, SigAction::default());
    }

    // Hand the handler its arguments and a way back.
    m.write_u64(ctx_addr + ctx::SP as u64, frame_addr)?;
    m.write_u64(ctx_addr + ctx::x(0) as u64, signal as u64)?;
    m.write_u64(ctx_addr + ctx::x(1) as u64, frame_addr)?;
    m.write_u64(ctx_addr + ctx::x(2) as u64, uc)?;
    let ret = if action.flags & sa::RESTORER != 0 && action.restorer != 0 {
        action.restorer
    } else {
        SIGRETURN_TRAMPOLINE
    };
    m.write_u64(ctx_addr + ctx::x(30) as u64, ret)?;
    m.write_u64(ctx_addr + ctx::PC as u64, action.handler)?;
    Ok(action.handler)
}

/// The x86-64 frame builder. See [`xframe`] for the layout.
fn setup_frame_x86(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    ctx_addr: u64,
    signal: u32,
    fault_address: u64,
    taken: Taken,
) -> Result<u64, Errno> {
    let action = signals.action(signal);
    let sp = m.read_u64(ctx_addr + ctx::SP as u64)?;

    let mut own = signals.own();
    let on_alt = action.flags & sa::ONSTACK != 0 && own.alt_stack.size > 0;
    let base = if on_alt {
        let alt = &own.alt_stack;
        let top = alt.sp + alt.size;
        if sp > alt.sp && sp <= top {
            sp
        } else {
            top
        }
    } else {
        // Leave the red zone below the interrupted code's stack pointer.
        sp - xframe::RED_ZONE
    };

    // The FP state above the frame, 64-byte aligned; the frame below it so
    // that `rsp + 8` is 16-byte aligned on handler entry, as after a `call`.
    let fpstate = (base - xframe::FPSTATE_SIZE as u64) & !63;
    let frame_addr = ((fpstate - xframe::FRAME_SIZE as u64) & !0xf) - 8;
    m.zero(frame_addr, xframe::FRAME_SIZE)?;
    m.zero(fpstate, xframe::FPSTATE_SIZE)?;

    // The handler's return address: the libc restorer (glibc always sets one
    // on x86-64), else the untranslated trampoline the host recognises.
    let ret = if action.flags & sa::RESTORER != 0 && action.restorer != 0 {
        action.restorer
    } else {
        SIGRETURN_TRAMPOLINE
    };
    m.write_u64(frame_addr + xframe::PRETCODE as u64, ret)?;

    let info = frame_addr + xframe::SIGINFO as u64;
    write_siginfo(signals, m, info, signal, fault_address, true, taken)?;

    let uc = frame_addr + xframe::UCONTEXT as u64;
    m.write_u64(uc + xframe::UC_FLAGS as u64, 0)?;
    m.write_u64(uc + xframe::UC_LINK as u64, 0)?;
    m.write_u64(uc + xframe::UC_STACK as u64, own.alt_stack.sp)?;
    m.write_u32(uc + xframe::UC_STACK as u64 + 8, own.alt_stack.flags)?;
    m.write_u64(uc + xframe::UC_STACK as u64 + 16, own.alt_stack.size)?;
    let saved_mask = own.suspend_restore.take().unwrap_or(own.blocked);
    m.write_u64(uc + xframe::UC_SIGMASK as u64, saved_mask)?;

    let mc = uc + xframe::UC_MCONTEXT as u64;
    for (i, reg) in xframe::GPR_ORDER.iter().enumerate() {
        let v = m.read_u64(ctx_addr + ctx::x(*reg) as u64)?;
        m.write_u64(mc + i as u64 * 8, v)?;
    }
    let pc = m.read_u64(ctx_addr + ctx::PC as u64)?;
    m.write_u64(mc + xframe::MC_RIP as u64, pc)?;
    m.write_u64(mc + xframe::MC_EFLAGS as u64, read_rflags(m, ctx_addr)?)?;
    // cs = __USER_CS (0x33), the other selectors zero.
    m.write_u64(mc + xframe::MC_CS as u64, 0x33)?;
    m.write_u64(mc + xframe::MC_TRAPNO as u64, if signal == sig::SIGSEGV { 14 } else { 0 })?;
    m.write_u64(mc + xframe::MC_OLDMASK as u64, saved_mask)?;
    m.write_u64(mc + xframe::MC_CR2 as u64, fault_address)?;
    m.write_u64(mc + xframe::MC_FPSTATE as u64, fpstate)?;

    // The fxsave image: control words, MXCSR, and the sixteen xmm registers.
    m.write_u32(fpstate, m.read_u32(ctx_addr + ctx::X87_CW as u64)? & 0xffff)?;
    m.write_u32(fpstate + 24, m.read_u32(ctx_addr + ctx::MXCSR as u64)?)?;
    m.write_u32(fpstate + 28, 0xffff)?;
    for n in 0..16u8 {
        for half in 0..2u64 {
            let v = m.read_u64(ctx_addr + ctx::v(n) as u64 + half * 8)?;
            m.write_u64(fpstate + 160 + n as u64 * 16 + half * 8, v)?;
        }
    }

    own.blocked |= action.mask;
    if action.flags & sa::NODEFER == 0 {
        own.blocked |= bit(signal);
    }
    if let Taken::Fault = taken {
        signals.clear_pending(signal);
    }
    own.in_handler = true;
    if action.flags & sa::RESETHAND != 0 {
        let _ = signals.set_action(signal, SigAction::default());
    }

    // rsp = frame, rdi = signo, rsi = &info, rdx = &uc, rax = 0.
    m.write_u64(ctx_addr + ctx::SP as u64, frame_addr)?;
    m.write_u64(ctx_addr + ctx::x(7) as u64, signal as u64)?;
    m.write_u64(ctx_addr + ctx::x(6) as u64, info)?;
    m.write_u64(ctx_addr + ctx::x(2) as u64, uc)?;
    m.write_u64(ctx_addr + ctx::x(0) as u64, 0)?;
    m.write_u64(ctx_addr + ctx::PC as u64, action.handler)?;
    Ok(action.handler)
}

/// The x86-64 `rt_sigreturn`. The handler's `ret` popped the return address,
/// so the frame starts one word below the stack pointer.
fn sigreturn_x86(signals: &Signals, m: &mut GuestMem<'_>, ctx_addr: u64) -> Result<u64, Errno> {
    let frame_addr = m.read_u64(ctx_addr + ctx::SP as u64)? - 8;
    let uc = frame_addr + xframe::UCONTEXT as u64;
    let mc = uc + xframe::UC_MCONTEXT as u64;
    for (i, reg) in xframe::GPR_ORDER.iter().enumerate() {
        let v = m.read_u64(mc + i as u64 * 8)?;
        m.write_u64(ctx_addr + ctx::x(*reg) as u64, v)?;
    }
    let pc = m.read_u64(mc + xframe::MC_RIP as u64)?;
    m.write_u64(ctx_addr + ctx::PC as u64, pc)?;
    write_rflags(m, ctx_addr, m.read_u64(mc + xframe::MC_EFLAGS as u64)?)?;
    let fpstate = m.read_u64(mc + xframe::MC_FPSTATE as u64)?;
    if fpstate != 0 {
        if let Ok(mxcsr) = m.read_u32(fpstate + 24) {
            m.write_u32(ctx_addr + ctx::MXCSR as u64, mxcsr)?;
            for n in 0..16u8 {
                for half in 0..2u64 {
                    let v = m.read_u64(fpstate + 160 + n as u64 * 16 + half * 8)?;
                    m.write_u64(ctx_addr + ctx::v(n) as u64 + half * 8, v)?;
                }
            }
        }
    }
    let mut own = signals.own();
    own.blocked = m.read_u64(uc + xframe::UC_SIGMASK as u64)?;
    own.in_handler = false;
    Ok(pc)
}

/// The i386 signal frames (`arch/x86/ia32/ia32_signal.c`). Every field is a
/// 32-bit word; the frame sits on the 32-bit stack and the handler is entered
/// as if called, with `esp` at the return address.
///
/// `struct sigcontext_ia32` (88 bytes):
///   gs fs es ds (selector words) | edi esi ebp esp ebx edx ecx eax | trapno
///   err | eip cs eflags esp_at_signal ss | fpstate oldmask cr2
/// `struct sigframe_ia32`: pretcode sig sigcontext extramask retcode
/// `struct rt_sigframe_ia32`: pretcode sig pinfo puc siginfo(128) ucontext
///   where ucontext is uc_flags uc_link uc_stack(12) uc_mcontext(88)
///   uc_sigmask(8).
mod iframe {
    pub const SC_GS: u64 = 0;
    pub const SC_FS: u64 = 4;
    pub const SC_ES: u64 = 8;
    pub const SC_DS: u64 = 12;
    /// edi esi ebp esp ebx edx ecx eax, as context register numbers.
    pub const GPR_ORDER: [u8; 8] = [7, 6, 5, 4, 3, 2, 1, 0];
    pub const SC_GPRS: u64 = 16;
    pub const SC_TRAPNO: u64 = 48;
    pub const SC_ERR: u64 = 52;
    pub const SC_EIP: u64 = 56;
    pub const SC_CS: u64 = 60;
    pub const SC_EFLAGS: u64 = 64;
    pub const SC_ESP_AT_SIGNAL: u64 = 68;
    pub const SC_SS: u64 = 72;
    pub const SC_FPSTATE: u64 = 76;
    pub const SC_OLDMASK: u64 = 80;
    pub const SC_CR2: u64 = 84;
    pub const SC_SIZE: u64 = 88;

    // sigframe_ia32
    pub const SF_SIG: u64 = 4;
    pub const SF_SC: u64 = 8;
    pub const SF_EXTRAMASK: u64 = SF_SC + SC_SIZE; // 96
    pub const SF_SIZE: u64 = 112;

    // rt_sigframe_ia32
    pub const RT_SIG: u64 = 4;
    pub const RT_PINFO: u64 = 8;
    pub const RT_PUC: u64 = 12;
    pub const RT_INFO: u64 = 16;
    pub const RT_UC: u64 = 144;
    pub const UC_STACK: u64 = 8;
    pub const UC_MCONTEXT: u64 = 20;
    pub const UC_SIGMASK: u64 = UC_MCONTEXT + SC_SIZE; // 108
    pub const RT_SIZE: u64 = 272;

    /// `struct _fpstate_ia32` with an fxsave image: the legacy words first,
    /// `magic` at 110, then the fxsave environment (mxcsr at 136) and the
    /// xmm registers at 272.
    pub const FPSTATE_SIZE: usize = 624;
    pub const FP_MXCSR: u64 = 136;
    pub const FP_XMM: u64 = 272;

    pub const USER32_CS: u32 = 0x23;
    pub const USER_DS: u32 = 0x2b;
    /// The TLS entry glibc's i386 port loads into %gs: GDT entry 6, RPL 3.
    pub const GS_TLS: u32 = 0x33;
}

fn setup_frame_i386(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    ctx_addr: u64,
    signal: u32,
    fault_address: u64,
    taken: Taken,
) -> Result<u64, Errno> {
    let action = signals.action(signal);
    let sp = m.read_u64(ctx_addr + ctx::sp_slot(true) as u64)? & 0xffff_ffff;
    let rt = action.flags & sa::SIGINFO != 0;
    let mut own = signals.own();
    own.legacy_frame = !rt;

    let on_alt = action.flags & sa::ONSTACK != 0 && own.alt_stack.size > 0;
    let base = if on_alt {
        let alt = &own.alt_stack;
        let top = alt.sp + alt.size;
        if sp > alt.sp && sp <= top {
            sp
        } else {
            top
        }
    } else {
        sp
    };

    // The FP image above the frame, then the frame such that `esp + 4` is
    // 16-byte aligned on handler entry, as after a `call`.
    let fpstate = (base - iframe::FPSTATE_SIZE as u64) & !63;
    let size = if rt { iframe::RT_SIZE } else { iframe::SF_SIZE };
    let frame_addr = ((fpstate - size) & !0xf) - 4;
    m.zero(frame_addr, size as usize)?;
    m.zero(fpstate, iframe::FPSTATE_SIZE)?;

    let ret = if action.flags & sa::RESTORER != 0 && action.restorer != 0 {
        action.restorer
    } else {
        SIGRETURN_TRAMPOLINE
    };
    m.write_u32(frame_addr, ret as u32)?;

    // The mask sigreturn puts back: the one a sigsuspend or pwait-style
    // call replaced for its duration, otherwise the current one.
    let saved_mask = own.suspend_restore.take().unwrap_or(own.blocked);
    let sc = if rt {
        m.write_u32(frame_addr + iframe::RT_SIG, signal)?;
        let info = frame_addr + iframe::RT_INFO;
        let uc = frame_addr + iframe::RT_UC;
        m.write_u32(frame_addr + iframe::RT_PINFO, info as u32)?;
        m.write_u32(frame_addr + iframe::RT_PUC, uc as u32)?;
        write_siginfo(signals, m, info, signal, fault_address, false, taken)?;
        m.write_u32(uc, 0)?;
        m.write_u32(uc + 4, 0)?;
        m.write_u32(uc + iframe::UC_STACK, own.alt_stack.sp as u32)?;
        m.write_u32(uc + iframe::UC_STACK + 4, own.alt_stack.flags)?;
        m.write_u32(uc + iframe::UC_STACK + 8, own.alt_stack.size as u32)?;
        m.write_u64(uc + iframe::UC_SIGMASK, saved_mask)?;
        uc + iframe::UC_MCONTEXT
    } else {
        m.write_u32(frame_addr + iframe::SF_SIG, signal)?;
        m.write_u32(frame_addr + iframe::SF_EXTRAMASK, (saved_mask >> 32) as u32)?;
        frame_addr + iframe::SF_SC
    };

    m.write_u32(sc + iframe::SC_GS, iframe::GS_TLS)?;
    m.write_u32(sc + iframe::SC_FS, 0)?;
    m.write_u32(sc + iframe::SC_ES, iframe::USER_DS)?;
    m.write_u32(sc + iframe::SC_DS, iframe::USER_DS)?;
    for (i, reg) in iframe::GPR_ORDER.iter().enumerate() {
        let v = m.read_u64(ctx_addr + ctx::x(*reg) as u64)?;
        m.write_u32(sc + iframe::SC_GPRS + i as u64 * 4, v as u32)?;
    }
    let pc = m.read_u64(ctx_addr + ctx::PC as u64)?;
    m.write_u32(sc + iframe::SC_TRAPNO, if signal == sig::SIGSEGV { 14 } else { 0 })?;
    // A wasm32 program's call that restarts after this handler
    // (`syscalls::restart_call`): said in the frame, where its sigreturn
    // finds it, however many frames nest meanwhile.
    let restart = m.read_u64(ctx_addr + ctx::x(RESTART_SLOT) as u64)? == RESTART_MARK;
    if restart {
        m.write_u64(ctx_addr + ctx::x(RESTART_SLOT) as u64, 0)?;
    }
    m.write_u32(sc + iframe::SC_ERR, if restart { RESTART_ERR } else { 0 })?;
    m.write_u32(sc + iframe::SC_EIP, pc as u32)?;
    m.write_u32(sc + iframe::SC_CS, iframe::USER32_CS)?;
    m.write_u32(sc + iframe::SC_EFLAGS, read_rflags(m, ctx_addr)? as u32)?;
    m.write_u32(sc + iframe::SC_ESP_AT_SIGNAL, sp as u32)?;
    m.write_u32(sc + iframe::SC_SS, iframe::USER_DS)?;
    m.write_u32(sc + iframe::SC_FPSTATE, fpstate as u32)?;
    m.write_u32(sc + iframe::SC_OLDMASK, saved_mask as u32)?;
    m.write_u32(sc + iframe::SC_CR2, fault_address as u32)?;

    // The FP image: x87 control word, MXCSR and the eight xmm registers.
    // (an AArch64 build's i386-ABI processes are wasm32 programs: no x87,
    // and the context has no x87 area)
    let cw = if gex_abi::X86 { m.read_u32(ctx_addr + ctx::X87_CW as u64)? & 0xffff } else { 0x37f };
    m.write_u32(fpstate, cw)?;
    m.write_u32(fpstate + iframe::FP_MXCSR, m.read_u32(ctx_addr + ctx::MXCSR as u64)?)?;
    for n in 0..8u8 {
        for half in 0..2u64 {
            let v = m.read_u64(ctx_addr + ctx::v(n) as u64 + half * 8)?;
            m.write_u64(fpstate + iframe::FP_XMM + n as u64 * 16 + half * 8, v)?;
        }
    }

    own.blocked |= action.mask;
    if action.flags & sa::NODEFER == 0 {
        own.blocked |= bit(signal);
    }
    if let Taken::Fault = taken {
        signals.clear_pending(signal);
    }
    own.in_handler = true;
    if action.flags & sa::RESETHAND != 0 {
        let _ = signals.set_action(signal, SigAction::default());
    }

    if std::env::var_os("GEX_SIGTRACE").is_some() {
        eprintln!(
            "[sig] i386 frame for {signal}: rt={rt} frame=0x{frame_addr:x} sc=0x{sc:x} fpstate=0x{fpstate:x} \
             handler=0x{:x} restorer=0x{:x} flags=0x{:x} interrupted pc=0x{pc:x} esp=0x{sp:x}",
            action.handler, action.restorer, action.flags
        );
    }
    // esp = frame; eax = signo; for an rt frame edx = &info and ecx = &uc.
    m.write_u64(ctx_addr + ctx::sp_slot(true) as u64, frame_addr)?;
    m.write_u64(ctx_addr + ctx::x(0) as u64, signal as u64)?;
    if rt {
        m.write_u64(ctx_addr + ctx::x(2) as u64, frame_addr + iframe::RT_INFO)?;
        m.write_u64(ctx_addr + ctx::x(1) as u64, frame_addr + iframe::RT_UC)?;
    } else {
        m.write_u64(ctx_addr + ctx::x(2) as u64, 0)?;
        m.write_u64(ctx_addr + ctx::x(1) as u64, 0)?;
    }
    m.write_u64(ctx_addr + ctx::PC as u64, action.handler)?;
    Ok(action.handler)
}

/// The i386 `sigreturn` (legacy: the restorer popped the return address and
/// `sig`, so the frame is two words below `esp`) and `rt_sigreturn` (one
/// word below).
/// A wasm32 program's interrupted call that restarts once its handler
/// returns (`syscalls::restart_call`): the context slot that says so
/// (r8, which the i386 ABI its calls use never touches), what it holds
/// then, and how the handler's frame keeps it (its `err` field, which only
/// a fault's frame uses).
pub const RESTART_SLOT: u8 = 8;
pub const RESTART_MARK: u64 = 0x5245_5354_4152_5453;
const RESTART_ERR: u32 = 0x5253_5452;

fn sigreturn_i386(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    ctx_addr: u64,
    legacy: bool,
) -> Result<u64, Errno> {
    let esp = m.read_u64(ctx_addr + ctx::sp_slot(true) as u64)? & 0xffff_ffff;
    let (sc, mask) = if legacy {
        let frame_addr = esp - 8;
        let sc = frame_addr + iframe::SF_SC;
        let lo = m.read_u32(sc + iframe::SC_OLDMASK)? as u64;
        let hi = m.read_u32(frame_addr + iframe::SF_EXTRAMASK)? as u64;
        (sc, lo | (hi << 32))
    } else {
        let frame_addr = esp - 4;
        let uc = frame_addr + iframe::RT_UC;
        (uc + iframe::UC_MCONTEXT, m.read_u64(uc + iframe::UC_SIGMASK)?)
    };
    if std::env::var_os("GEX_SIGTRACE").is_some() {
        let words: Vec<String> = (0..8)
            .map(|i| format!("{:08x}", m.read_u32(esp - 8 + i * 4).unwrap_or(0)))
            .collect();
        eprintln!(
            "[sig] i386 sigreturn legacy={legacy} esp=0x{esp:x} sc=0x{sc:x} eip=0x{:x} words@esp-8: {}",
            m.read_u32(sc + iframe::SC_EIP).unwrap_or(0),
            words.join(" ")
        );
    }
    for (i, reg) in iframe::GPR_ORDER.iter().enumerate() {
        let v = m.read_u32(sc + iframe::SC_GPRS + i as u64 * 4)? as u64;
        m.write_u64(ctx_addr + ctx::x(*reg) as u64, v)?;
    }
    let pc = m.read_u32(sc + iframe::SC_EIP)? as u64;
    m.write_u64(ctx_addr + ctx::PC as u64, pc)?;
    if m.read_u32(sc + iframe::SC_ERR)? == RESTART_ERR {
        m.write_u64(ctx_addr + ctx::x(RESTART_SLOT) as u64, RESTART_MARK)?;
    }
    write_rflags(m, ctx_addr, m.read_u32(sc + iframe::SC_EFLAGS)? as u64)?;
    let fpstate = m.read_u32(sc + iframe::SC_FPSTATE)? as u64;
    if fpstate != 0 {
        if let Ok(mxcsr) = m.read_u32(fpstate + iframe::FP_MXCSR) {
            m.write_u32(ctx_addr + ctx::MXCSR as u64, mxcsr)?;
            for n in 0..8u8 {
                for half in 0..2u64 {
                    let v = m.read_u64(fpstate + iframe::FP_XMM + n as u64 * 16 + half * 8)?;
                    m.write_u64(ctx_addr + ctx::v(n) as u64 + half * 8, v)?;
                }
            }
        }
    }
    let mut own = signals.own();
    own.blocked = mask;
    own.in_handler = false;
    Ok(pc)
}

/// RFLAGS from the context's flag bytes: CF, PF, AF, ZF, SF, DF, OF in their
/// architectural bits, plus the always-set bit 1 and IF.
fn read_rflags(m: &GuestMem<'_>, ctx_addr: u64) -> Result<u64, Errno> {
    let f = |off: usize| -> Result<u64, Errno> {
        Ok(m.read(ctx_addr + off as u64, 1)?[0] as u64 & 1)
    };
    Ok((f(ctx::CF)?)
        | (1 << 1)
        | (f(ctx::PF)? << 2)
        | (f(ctx::AF)? << 4)
        | (f(ctx::ZF)? << 6)
        | (f(ctx::NF)? << 7)
        | (1 << 9)
        | (f(ctx::DF)? << 10)
        | (f(ctx::VF)? << 11)
        | (m.read_u32(ctx_addr + ctx::EFLAGS_SYS as u64)? & EFLAGS_AC_ID) as u64)
}

/// EFLAGS.AC (bit 18) and ID (bit 21): the system bits user code can toggle,
/// kept in `ctx::EFLAGS_SYS`, so a handler sees, and `sigreturn` restores, what
/// the interrupted code's last `popf` set.
const EFLAGS_AC_ID: u32 = 0x24_0000;

fn write_rflags(m: &mut GuestMem<'_>, ctx_addr: u64, v: u64) -> Result<(), Errno> {
    for (off, bit) in [
        (ctx::CF, 0),
        (ctx::PF, 2),
        (ctx::AF, 4),
        (ctx::ZF, 6),
        (ctx::NF, 7),
        (ctx::DF, 10),
        (ctx::VF, 11),
    ] {
        m.write(ctx_addr + off as u64, &[((v >> bit) & 1) as u8])?;
    }
    m.write_u32(ctx_addr + ctx::EFLAGS_SYS as u64, v as u32 & EFLAGS_AC_ID)?;
    Ok(())
}

/// Restore the context a handler frame captured. Returns the resume address.
/// `compat` selects the i386 frames, and `legacy` the non-rt `sigreturn`
/// form of those (a handler installed without `SA_SIGINFO`).
pub fn sigreturn(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    ctx_addr: u64,
    compat: bool,
    legacy: bool,
) -> Result<u64, Errno> {
    if compat {
        // The frame's own kind decides; the entry number is a cross-check.
        let _ = legacy;
        let kind = signals.own().legacy_frame;
        return sigreturn_i386(signals, m, ctx_addr, kind);
    }
    if gex_abi::X86 {
        return sigreturn_x86(signals, m, ctx_addr);
    }
    // The frame is at the stack pointer the handler was entered with, which
    // it is required to have preserved.
    let frame_addr = m.read_u64(ctx_addr + ctx::SP as u64)?;
    let uc = frame_addr + frame::UCONTEXT as u64;
    let mc = uc + frame::UC_MCONTEXT as u64;

    for i in 0..31u8 {
        let v = m.read_u64(mc + frame::MC_REGS as u64 + i as u64 * 8)?;
        m.write_u64(ctx_addr + ctx::x(i) as u64, v)?;
    }
    let sp = m.read_u64(mc + frame::MC_SP as u64)?;
    let pc = m.read_u64(mc + frame::MC_PC as u64)?;
    let pstate = m.read_u64(mc + frame::MC_PSTATE as u64)?;
    m.write_u64(ctx_addr + ctx::SP as u64, sp)?;
    m.write_u64(ctx_addr + ctx::PC as u64, pc)?;
    write_pstate(m, ctx_addr, pstate)?;

    let mut own = signals.own();
    own.blocked = m.read_u64(uc + frame::UC_SIGMASK as u64)?;
    own.in_handler = false;
    Ok(pc)
}

/// Consider the highest-priority pending signal.
pub fn dispatch(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    ctx_addr: u64,
    compat: bool,
) -> Result<Delivery, Errno> {
    // Taken off the pending sets before anything else: another thread of the
    // process may be delivering at the same time, without the kernel lock,
    // and a process-directed signal is for one of them only.
    let (signal, source) = loop {
        let Some(signal) = signals.next_deliverable() else {
            return Ok(Delivery::None);
        };
        if let Some(source) = signals.claim(signal) {
            break (signal, source);
        }
    };
    let action = signals.action(signal);
    if action.handler == SIG_IGN {
        return Ok(Delivery::None);
    }
    if action.handler == SIG_DFL {
        return Ok(match default_action(signal) {
            DefaultAction::Ignore => Delivery::None,
            // The three a terminal raises, with no handler and no scheduler to
            // resume from: doing nothing matches a shell with no job control (a
            // `^Z` there does nothing on real hardware too), and is far better
            // than killing a backgrounded reader. `SIGSTOP` is excluded -- it
            // can't be handled, so ending the process at least does something.
            DefaultAction::Stop
                if matches!(signal, sig::SIGTSTP | 21 | 22) =>
            {
                Delivery::None
            }
            DefaultAction::Core | DefaultAction::Stop => Delivery::Terminate { signal, core: true },
            _ => Delivery::Terminate {
                signal,
                core: false,
            },
        });
    }
    match build_frame(signals, m, ctx_addr, signal, 0, compat, Taken::Claimed(source)) {
        Ok(resume) => Ok(Delivery::Resume(resume)),
        Err(e) => {
            // No frame: the signal stays pending, as it was.
            signals.cur.raise(signal, source);
            Err(e)
        }
    }
}

/// The `siginfo_t` head at `info`: signo, code, and then either the sender
/// (`si_pid`, `si_uid`) of a signal a process sent or, for the synchronous
/// faults, the fault address, which is what a crash handler reads. `wide` is
/// the 64-bit layout, where the union after the three ints is 8-aligned (at
/// 16 rather than 12). Takes the signal's [`Source`].
fn write_siginfo(
    signals: &Signals,
    m: &mut GuestMem<'_>,
    info: u64,
    signal: u32,
    fault_address: u64,
    wide: bool,
    taken: Taken,
) -> Result<(), Errno> {
    let fields = info + if wide { 16 } else { 12 };
    m.write_u32(info, signal)?;
    let source = match taken {
        Taken::Fault => signals.take_source(signal),
        Taken::Claimed(source) => source,
    };
    if let Some(src) = source {
        m.write_u32(info + 8, src.code as u32)?;
        m.write_u32(fields, src.pid as u32)?;
        m.write_u32(fields + 4, src.uid)?;
        return Ok(());
    }
    m.write_u32(info + 8, fault_code(signal))?;
    if matches!(signal, sig::SIGSEGV | sig::SIGBUS | sig::SIGILL | sig::SIGFPE) {
        if wide {
            m.write_u64(fields, fault_address)?;
        } else {
            m.write_u32(fields, fault_address as u32)?;
        }
    }
    Ok(())
}

/// The `si_code` a synchronous fault reports.
fn fault_code(signal: u32) -> u32 {
    match signal {
        // SEGV_MAPERR: address not mapped to an object.
        sig::SIGSEGV => 1,
        // ILL_ILLOPC: illegal opcode.
        sig::SIGILL => 1,
        // BUS_ADRALN: invalid address alignment.
        sig::SIGBUS => 1,
        // FPE_INTDIV: integer divide by zero.
        sig::SIGFPE => 1,
        // TRAP_BRKPT: process breakpoint.
        sig::SIGTRAP => 1,
        // SI_KERNEL for everything the kernel raised itself.
        _ => 0x80,
    }
}

/// Pack the four condition flags into a PSTATE word.
pub(crate) fn read_pstate(m: &GuestMem<'_>, ctx_addr: u64) -> Result<u64, Errno> {
    let (n, z, c, v) = ctx::unpack_nzcv(m.read_u32(ctx_addr + ctx::NZCV as u64)?);
    // EL0t with interrupts enabled, plus NZCV in their architectural places.
    Ok(((n as u64) << 31) | ((z as u64) << 30) | ((c as u64) << 29) | ((v as u64) << 28))
}

pub(crate) fn write_pstate(m: &mut GuestMem<'_>, ctx_addr: u64, pstate: u64) -> Result<(), Errno> {
    m.write_u32(
        ctx_addr + ctx::NZCV as u64,
        ctx::pack_nzcv(
            (pstate >> 31) as u32,
            (pstate >> 30) as u32,
            (pstate >> 29) as u32,
            (pstate >> 28) as u32,
        ),
    )?;
    Ok(())
}

#[cfg(all(test, not(feature = "x86")))]
mod tests {
    use super::*;

    const CTX: u64 = 0x1000;

    fn setup() -> (Vec<u8>, Signals) {
        let mut buf = vec![0u8; 0x80000];
        {
            let mut m = GuestMem::new(&mut buf);
            // A plausible stack pointer with room below it for a frame.
            m.write_u64(CTX + ctx::SP as u64, 0x40000).unwrap();
            m.write_u64(CTX + ctx::PC as u64, 0x400100).unwrap();
            for i in 0..31u8 {
                m.write_u64(CTX + ctx::x(i) as u64, 0x1000 + i as u64)
                    .unwrap();
            }
        }
        (buf, Signals::new())
    }

    #[test]
    fn state_bytes_round_trip() {
        let s = Signals::new();
        let a = SigAction { handler: 0x1234, flags: 4, restorer: 0x99, mask: 1 << 3 };
        s.set_action(sig::SIGUSR1, a).unwrap();
        s.set_action(sig::SIGPIPE, SigAction { handler: SIG_IGN, ..Default::default() }).unwrap();
        s.set_blocked(bit(sig::SIGTERM));
        s.set_alt_stack(SigAltStack { sp: 0x7000, flags: 0, size: 0x2000 });
        s.raise(sig::SIGUSR2);
        s.raise_shared(sig::SIGHUP, None);
        // As a fork child: no pending.
        let f = Signals::from_bytes(&s.to_bytes(false)).unwrap();
        assert_eq!(f.action(sig::SIGUSR1).handler, 0x1234);
        assert_eq!(f.action(sig::SIGUSR1).mask, 1 << 3);
        assert_eq!(f.action(sig::SIGPIPE).handler, SIG_IGN);
        assert_eq!(f.blocked(), bit(sig::SIGTERM));
        assert_eq!(f.alt_stack().sp, 0x7000);
        assert_eq!(f.pending_raw(), 0);
        // As an execve: pending kept.
        let e = Signals::from_bytes(&s.to_bytes(true)).unwrap();
        assert_eq!(e.pending_raw(), bit(sig::SIGUSR2) | bit(sig::SIGHUP));
        assert!(Signals::from_bytes(&[0u8; 7]).is_none());
    }

    #[test]
    fn kill_and_stop_cannot_be_caught() {
        let s = Signals::new();
        assert_eq!(
            s.set_action(sig::SIGKILL, SigAction::default()).err(),
            Some(Errno::EINVAL)
        );
        assert_eq!(
            s.set_action(sig::SIGSTOP, SigAction::default()).err(),
            Some(Errno::EINVAL)
        );
        assert!(s.set_action(sig::SIGUSR1, SigAction::default()).is_ok());
    }

    #[test]
    fn blocked_signals_stay_pending() {
        let s = Signals::new();
        s.set_blocked(bit(sig::SIGUSR1));
        s.raise(sig::SIGUSR1);
        assert!(!s.has_pending());
        s.set_blocked(0);
        assert!(s.has_pending());
    }

    #[test]
    fn an_unhandled_fatal_signal_terminates() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        s.raise(sig::SIGTERM);
        assert_eq!(
            dispatch(&mut s, &mut m, CTX, false).unwrap(),
            Delivery::Terminate {
                signal: sig::SIGTERM,
                core: false
            }
        );
    }

    #[test]
    fn an_ignored_signal_is_discarded() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        s.set_action(
            sig::SIGUSR1,
            SigAction {
                handler: SIG_IGN,
                ..Default::default()
            },
        )
        .unwrap();
        s.raise(sig::SIGUSR1);
        assert_eq!(dispatch(&mut s, &mut m, CTX, false).unwrap(), Delivery::None);
        assert!(!s.has_pending());
    }

    #[test]
    fn sigchld_defaults_to_ignored() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        s.raise(sig::SIGCHLD);
        assert_eq!(dispatch(&mut s, &mut m, CTX, false).unwrap(), Delivery::None);
    }

    #[test]
    fn a_handler_frame_round_trips_the_context() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        s.set_action(
            sig::SIGUSR1,
            SigAction {
                handler: 0x400500,
                ..Default::default()
            },
        )
        .unwrap();
        s.raise(sig::SIGUSR1);

        let d = dispatch(&mut s, &mut m, CTX, false).unwrap();
        assert_eq!(d, Delivery::Resume(0x400500));
        // The handler sees its arguments and a return path.
        assert_eq!(
            m.read_u64(CTX + ctx::x(0) as u64).unwrap(),
            sig::SIGUSR1 as u64
        );
        assert_eq!(
            m.read_u64(CTX + ctx::x(30) as u64).unwrap(),
            SIGRETURN_TRAMPOLINE
        );
        assert!(s.in_handler());
        // The signal is blocked while its own handler runs.
        assert_ne!(s.blocked() & bit(sig::SIGUSR1), 0);
        // The stack moved below the original.
        let handler_sp = m.read_u64(CTX + ctx::SP as u64).unwrap();
        assert!(handler_sp < 0x40000);
        assert_eq!(handler_sp % 16, 0);

        // Returning restores everything the frame captured.
        let resume = sigreturn(&mut s, &mut m, CTX, false, false).unwrap();
        assert_eq!(resume, 0x400100);
        assert_eq!(m.read_u64(CTX + ctx::SP as u64).unwrap(), 0x40000);
        assert_eq!(m.read_u64(CTX + ctx::x(5) as u64).unwrap(), 0x1005);
        assert_eq!(s.blocked(), 0);
        assert!(!s.in_handler());
    }

    #[test]
    fn flags_are_preserved_across_a_handler() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        m.write_u32(CTX + ctx::NZCV as u64, ctx::pack_nzcv(1, 0, 1, 0))
            .unwrap();
        s.set_action(
            sig::SIGUSR1,
            SigAction {
                handler: 0x400500,
                ..Default::default()
            },
        )
        .unwrap();
        s.raise(sig::SIGUSR1);
        dispatch(&mut s, &mut m, CTX, false).unwrap();
        // The handler runs with whatever flags it likes.
        m.write_u32(CTX + ctx::NZCV as u64, ctx::pack_nzcv(0, 1, 0, 0))
            .unwrap();
        sigreturn(&mut s, &mut m, CTX, false, false).unwrap();
        let (n, z, c, _) = ctx::unpack_nzcv(m.read_u32(CTX + ctx::NZCV as u64).unwrap());
        assert_eq!((n, z, c), (1, 0, 1));
    }

    #[test]
    fn resethand_reverts_before_the_handler_runs() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        s.set_action(
            sig::SIGUSR1,
            SigAction {
                handler: 0x400500,
                flags: sa::RESETHAND,
                ..Default::default()
            },
        )
        .unwrap();
        s.raise(sig::SIGUSR1);
        dispatch(&mut s, &mut m, CTX, false).unwrap();
        assert_eq!(s.action(sig::SIGUSR1).handler, SIG_DFL);
    }

    #[test]
    fn an_alternate_stack_is_used_when_requested() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        s.set_alt_stack(SigAltStack {
            sp: 0x60000,
            flags: 0,
            size: 0x8000,
        });
        s.set_action(
            sig::SIGSEGV,
            SigAction {
                handler: 0x400600,
                flags: sa::ONSTACK,
                ..Default::default()
            },
        )
        .unwrap();
        s.raise(sig::SIGSEGV);
        dispatch(&mut s, &mut m, CTX, false).unwrap();
        let sp = m.read_u64(CTX + ctx::SP as u64).unwrap();
        assert!(
            sp > 0x60000 && sp <= 0x68000,
            "handler should run on the alternate stack, got {sp:#x}"
        );
    }

    #[test]
    fn the_lowest_numbered_signal_is_delivered_first() {
        let (mut buf, mut s) = setup();
        let mut m = GuestMem::new(&mut buf);
        for n in [sig::SIGUSR2, sig::SIGUSR1] {
            s.set_action(
                n,
                SigAction {
                    handler: 0x400000 + n as u64,
                    ..Default::default()
                },
            )
            .unwrap();
            s.raise(n);
        }
        assert_eq!(
            dispatch(&mut s, &mut m, CTX, false).unwrap(),
            Delivery::Resume(0x400000 + sig::SIGUSR1 as u64)
        );
    }
}
