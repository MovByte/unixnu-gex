//! Pipes.
//!
//! A bounded ring buffer with the blocking rules Linux specifies: a read on
//! an empty pipe waits until data arrives or every writer is gone, a write to
//! a full pipe waits for room, and a write with no readers left returns
//! `EPIPE`; the syscall layer raises SIGPIPE for it, as Linux does.
//!
//! Blocking uses a condition variable, which works because a guest thread is
//! a real host thread. The browser runtime blocks the same way
//! through `Atomics.wait`.
//!
//! A Darwin process's pipe keeps XNU's rules instead (`bsd/kern/sys_pipe.c`,
//! [`xnu`]): a buffer that starts at 512 bytes and is regrown at a write
//! that needs more, up to 64 KiB while the system's pipes hold less than
//! `maxpipekva`; atomic writes of up to 512 bytes; writable for `select`
//! with `PIPE_BUF` free of `MAX_PIPESIZE`.

use crate::errno::{Errno, SysResult};
use std::collections::VecDeque;
use std::sync::{Condvar, Mutex};

/// Linux's pipe capacity.
pub const PIPE_BUF: usize = 65536;

/// Linux's `PIPE_BUF`: a write of at most this many bytes goes in whole or
/// not at all, so no other writer's bytes land inside it.
pub const PIPE_ATOMIC: usize = 4096;

/// XNU's pipe sizes and limits (`bsd/sys/pipe.h`, `sys_pipe.c`).
pub mod xnu {
    use std::sync::atomic::{AtomicI64, Ordering};

    /// `pipesize_blocks`.
    pub const BLOCKS: [usize; 7] = [512, 1024, 2048, 4096, 4096 * 2, PIPE_SIZE, PIPE_SIZE * 4];
    /// `PIPE_SIZE`: the least `MAX_PIPESIZE` is.
    pub const PIPE_SIZE: usize = 16384;
    /// `PIPE_BUF`: a write of at most this many bytes is atomic.
    pub const PIPE_BUF: usize = 512;
    /// `PIPE_KVAMAX`, `maxpipekva`'s value.
    pub const KVA_MAX: i64 = 1024 * 1024 * 16;

    /// `amountpipekva`: what every Darwin pipe's buffer holds, together.
    pub static KVA: AtomicI64 = AtomicI64::new(0);

    /// `choose_pipespace`: the block that fits the larger of `current` and
    /// `expected`.
    pub fn choose(current: usize, expected: usize) -> usize {
        let target = current.max(expected);
        let mut i = BLOCKS.len() - 1;
        while i > 0 && BLOCKS[i - 1] > target {
            i -= 1;
        }
        BLOCKS[i]
    }

    pub(super) fn add(n: i64) {
        KVA.fetch_add(n, Ordering::AcqRel);
    }

    pub(super) fn room() -> bool {
        KVA.load(Ordering::Acquire) < KVA_MAX
    }
}

#[derive(Debug, Default)]
struct State {
    buf: VecDeque<u8>,
    readers: usize,
    writers: usize,
    /// Short writes (took less than offered) and refused writes (took
    /// nothing). Counted for the stall census.
    short: u64,
    refused: u64,
    /// Writes that put bytes in, and total bytes. For the census: a `0
    /// buffered` pipe could be one never written or one already drained.
    writes: u64,
    written: u64,
    /// The last thing written, truncated. For the census: apt's method
    /// protocol is text lines, so this names where a stalled conversation
    /// stopped.
    last: Vec<u8>,
    /// Writes that found no reader (EPIPE). Distinct from refused (EAGAIN):
    /// here the message is gone, not merely deferred.
    broken: u64,
    /// A Darwin pipe's buffer size (`pipe_buffer.size`, 0 once it is
    /// freed); `None` for a Linux pipe.
    xnu_size: Option<usize>,
}

/// One pipe, shared by both ends.
#[derive(Debug)]
pub struct Pipe {
    state: Mutex<State>,
    ready: Condvar,
    /// Who waits on either end (`crate::wait`): notified wherever `ready` is.
    queue: crate::wait::Queue,
}

impl Drop for Pipe {
    /// A Darwin pipe's buffer, if no read-side close freed it, goes back.
    fn drop(&mut self) {
        let s = self.state.get_mut().unwrap_or_else(|e| e.into_inner());
        if let Some(size) = s.xnu_size.filter(|&n| n > 0) {
            xnu::add(-(size as i64));
        }
    }
}

impl Default for Pipe {
    fn default() -> Self {
        Self::new()
    }
}

impl Pipe {
    pub fn new() -> Pipe {
        Pipe {
            state: Mutex::new(State {
                buf: VecDeque::new(),
                readers: 1,
                writers: 1,
                short: 0,
                refused: 0,
                writes: 0,
                written: 0,
                last: Vec::new(),
                broken: 0,
                xnu_size: None,
            }),
            ready: Condvar::new(),
            queue: crate::wait::Queue::new(),
        }
    }

    /// A Darwin pipe (`pipepair_alloc`): its buffer is the smallest block.
    pub fn new_xnu() -> Pipe {
        let p = Pipe::new();
        let size = xnu::choose(0, 0);
        xnu::add(size as i64);
        p.state.lock().unwrap().xnu_size = Some(size);
        p
    }

    /// Whether the pipe keeps XNU's rules.
    pub fn is_xnu(&self) -> bool {
        self.state.lock().unwrap().xnu_size.is_some()
    }

    /// A Darwin pipe's buffer size, `MAX_PIPESIZE` and bytes buffered.
    pub fn xnu_sizes(&self) -> Option<(usize, usize, usize)> {
        let s = self.state.lock().unwrap();
        s.xnu_size.map(|size| (size, size.max(xnu::PIPE_SIZE), s.buf.len()))
    }

    /// A Darwin write of `orig` bytes begins (`pipe_write`): `EPIPE` with no
    /// reader, else the buffer grown to what the write needs, if the
    /// system's pipes have room.
    pub fn xnu_begin_write(&self, orig: usize) -> Result<(), Errno> {
        let mut s = self.state.lock().unwrap();
        if s.readers == 0 {
            s.broken += 1;
            return Err(Errno::EPIPE);
        }
        let size = s.xnu_size.expect("a Darwin pipe");
        let cnt = s.buf.len();
        if size == 0 || (orig > size - cnt && xnu::room()) {
            let want = xnu::choose(size, cnt + orig);
            // pipespace when empty, else expand_pipespace, which never
            // shrinks it.
            if cnt == 0 || want > size {
                xnu::add(want as i64 - size as i64);
                s.xnu_size = Some(want);
            }
        }
        Ok(())
    }

    /// One pass of a Darwin write's loop, `left` of `orig` bytes still to
    /// go: what fits, unless a write of at most `PIPE_BUF` would be split.
    /// `EAGAIN` for none, `EPIPE` with no reader left.
    pub fn xnu_write_with(&self, left: usize, orig: usize, fill: impl FnMut(&mut [u8], usize)) -> SysResult {
        let mut s = self.state.lock().unwrap();
        if s.readers == 0 {
            s.broken += 1;
            return Err(Errno::EPIPE);
        }
        let size = s.xnu_size.expect("a Darwin pipe");
        let mut space = size.saturating_sub(s.buf.len());
        if space < left && orig <= xnu::PIPE_BUF {
            space = 0;
        }
        if space == 0 {
            s.refused += 1;
            return Err(Errno::EAGAIN);
        }
        let n = space.min(left);
        Self::put(&mut s, n, fill);
        drop(s);
        self.ready.notify_all();
        self.queue.notify();
        Ok(n as u64)
    }

    /// Whether a Darwin write with `left` of `orig` bytes to go would put
    /// some in now, or end (no reader).
    pub fn xnu_write_ready(&self, left: usize, orig: usize) -> bool {
        let s = self.state.lock().unwrap();
        let size = s.xnu_size.unwrap_or(0);
        let space = size.saturating_sub(s.buf.len());
        s.readers == 0 || (space > 0 && !(space < left && orig <= xnu::PIPE_BUF))
    }

    /// Append `n` bytes that `fill` copies in.
    fn put(s: &mut State, n: usize, mut fill: impl FnMut(&mut [u8], usize)) {
        let old = s.buf.len();
        s.buf.resize(old + n, 0);
        let (front, back) = s.buf.as_mut_slices();
        if back.len() >= n {
            let at = back.len() - n;
            fill(&mut back[at..], 0);
        } else {
            let k = n - back.len();
            let at = front.len() - k;
            fill(&mut front[at..], 0);
            if !back.is_empty() {
                fill(back, k);
            }
        }
        s.writes += 1;
        s.written += n as u64;
        s.last.clear();
        let take = n.min(160);
        let st = &mut *s;
        st.last.extend(st.buf.range(old..old + take));
    }

    /// The wait queue both ends' waiters register on.
    pub fn wait_queue(&self) -> u32 {
        self.queue.id()
    }

    /// [`crate::wait::Queue::wakes`] of its queue.
    pub fn wakes(&self) -> u64 {
        self.queue.wakes()
    }


    /// Note that another descriptor now refers to one end.
    pub fn open_end(&self, write: bool) {
        let mut s = self.state.lock().unwrap();
        if write {
            s.writers += 1;
        } else {
            s.readers += 1;
        }
    }

    /// Note that a descriptor for one end has closed.
    pub fn close_end(&self, write: bool) {
        let mut s = self.state.lock().unwrap();
        if write {
            s.writers = s.writers.saturating_sub(1);
        } else {
            s.readers = s.readers.saturating_sub(1);
            // pipeclose of the read side frees its buffer (pipe_free_kmem).
            if s.readers == 0 {
                if let Some(size) = s.xnu_size.filter(|&n| n > 0) {
                    xnu::add(-(size as i64));
                    s.xnu_size = Some(0);
                    s.buf.clear();
                }
            }
        }
        // Waking both sides is what turns the last close into an EOF or an
        // EPIPE rather than a hang.
        self.ready.notify_all();
                self.queue.notify();
    }

    /// Read up to `max` bytes, handing what was there to `take` as the
    /// buffer's two slices (the second empty unless the ring wrapped), sized
    /// under the pipe's own lock: a size taken from [`Pipe::buffered`] first
    /// can be stale by the time of the read (another reader drained it, a
    /// writer filled it), and a one-byte read of a pipe that then received a
    /// whole record tears that record. `take` copies them out (into another
    /// process's memory, `k_pipe_read`) before they are dropped: collecting
    /// them into a `Vec` first went a byte at a time, and cost 270-460 us
    /// for a full 64 KiB pipe in the page, most of the time a writer blocked
    /// on that pipe waited to be woken.
    pub fn read_with(&self, max: usize, take: impl FnOnce(&[u8], &[u8])) -> Result<usize, Errno> {
        if max == 0 {
            return Ok(0);
        }
        let mut s = self.state.lock().unwrap();
        if s.buf.is_empty() {
            return if s.writers == 0 { Ok(0) } else { Err(Errno::EAGAIN) };
        }
        let n = max.min(s.buf.len());
        let (front, back) = s.buf.as_slices();
        let k = n.min(front.len());
        take(&front[..k], &back[..n - k]);
        s.buf.drain(..n);
        self.ready.notify_all();
        self.queue.notify();
        Ok(n)
    }

    pub fn read(&self, buf: &mut [u8]) -> SysResult {
        if buf.is_empty() {
            return Ok(0);
        }
        let mut s = self.state.lock().unwrap();
        loop {
            if !s.buf.is_empty() {
                let n = buf.len().min(s.buf.len());
                // Two slice copies, not a pop per byte: a pipeline moves
                // megabytes through here.
                let (front, back) = s.buf.as_slices();
                let k = n.min(front.len());
                buf[..k].copy_from_slice(&front[..k]);
                buf[k..n].copy_from_slice(&back[..n - k]);
                s.buf.drain(..n);
                self.ready.notify_all();
                self.queue.notify();
                return Ok(n as u64);
            }
            // No data: end of file once no writer can ever supply any.
            if s.writers == 0 {
                return Ok(0);
            }
            // Never wait here: this runs with the kernel locked and the writer
            // that would supply data needs that lock, so waiting is a
            // deadlock. A descriptor that should block is parked by the
            // syscall layer outside the lock (`BlockOp::ReadStream`).
            return Err(Errno::EAGAIN);
        }
    }

    pub fn write(&self, buf: &[u8]) -> SysResult {
        self.write_with(buf.len(), |dst, from| dst.copy_from_slice(&buf[from..from + dst.len()]))
    }

    /// [`Pipe::write`] of `len` bytes that `fill` copies in: `fill(dst, from)`
    /// writes the source's bytes `from..from + dst.len()` into `dst`, which is
    /// the pipe's own buffer -- so a write from another process's memory
    /// (`k_pipe_write`) is one copy, not one into a staging `Vec` first.
    pub fn write_with(&self, len: usize, mut fill: impl FnMut(&mut [u8], usize)) -> SysResult {
        if len == 0 {
            return Ok(0);
        }
        let mut s = self.state.lock().unwrap();
        let mut written = 0usize;
        loop {
            if s.readers == 0 {
                // EPIPE; the syscall layer raises SIGPIPE with it, as Linux does.
                s.broken += 1;
                return if written > 0 {
                    Ok(written as u64)
                } else {
                    Err(Errno::EPIPE)
                };
            }
            let room = PIPE_BUF.saturating_sub(s.buf.len());
            // A small write waits for room for all of it (`EAGAIN` here; the
            // syscall layer parks a blocking one and tries it whole again).
            if len <= PIPE_ATOMIC && room < len {
                s.refused += 1;
                return Err(Errno::EAGAIN);
            }
            if room > 0 {
                let n = room.min(len - written);
                let old = s.buf.len();
                s.buf.resize(old + n, 0);
                // The `n` bytes just added are the deque's last: the end of
                // its second slice, or of the first and all of the second
                // when they wrap.
                let (front, back) = s.buf.as_mut_slices();
                if back.len() >= n {
                    let at = back.len() - n;
                    fill(&mut back[at..], written);
                } else {
                    let k = n - back.len();
                    let at = front.len() - k;
                    fill(&mut front[at..], written);
                    if !back.is_empty() {
                        fill(back, written + k);
                    }
                }
                s.writes += 1;
                s.written += n as u64;
                // Bounded, and the *first* bytes rather than the last: a
                // protocol line says what it is in its first word.
                let st = &mut *s;
                st.last.clear();
                st.last.extend(st.buf.range(old..old + n.min(160)));
                written += n;
                self.ready.notify_all();
                self.queue.notify();
                if written == len {
                    return Ok(written as u64);
                }
            }
            // Never wait here, for the same reason a read does not: this
            // runs with the kernel locked and the reader that would drain
            // the pipe needs that lock. A partial write is what the caller
            // gets, or `EAGAIN` if nothing fitted, and the syscall layer
            // parks a descriptor that should block.
            if written > 0 {
                s.short += 1;
                return Ok(written as u64);
            }
            s.refused += 1;
            return Err(Errno::EAGAIN);
        }
    }

    /// Short writes, refused writes and writes that found no reader.
    pub fn write_stats(&self) -> (u64, u64) {
        let s = self.state.lock().unwrap();
        // `broken` rides in the high half: a write with nowhere to go is the
        // one of the three that loses a message outright, so it must not be
        // the one that goes unreported for want of a field.
        (s.short + (s.broken << 8), s.refused)
    }

    /// The last message written, printable characters only.
    pub fn last_message(&self) -> String {
        let s = self.state.lock().unwrap();
        s.last
            .iter()
            .map(|&b| match b {
                b'\n' => '|',
                0x20..=0x7e => b as char,
                _ => '.',
            })
            .collect()
    }

    /// How many writes have put bytes in, and how many bytes in all.
    pub fn write_totals(&self) -> (u64, u64) {
        let s = self.state.lock().unwrap();
        (s.writes, s.written)
    }

    /// Open descriptors on each end, as `(readers, writers)`. For the census:
    /// a reader stuck without EOF means the writer count never hit zero.
    pub fn ends(&self) -> (usize, usize) {
        let s = self.state.lock().unwrap();
        (s.readers, s.writers)
    }

    /// Bytes available to read, for `poll` and `FIONREAD`.
    pub fn available(&self) -> usize {
        self.state.lock().unwrap().buf.len()
    }

    /// How many bytes a write can take before the pipe is full.
    pub fn room(&self) -> usize {
        PIPE_BUF.saturating_sub(self.state.lock().unwrap().buf.len())
    }

    /// How many bytes are waiting to be read.
    pub fn buffered(&self) -> usize {
        self.state.lock().unwrap().buf.len()
    }

    /// True when a reader would not block: data present, or no writers left.
    pub fn readable(&self) -> bool {
        let s = self.state.lock().unwrap();
        !s.buf.is_empty() || s.writers == 0
    }

    /// True when every write end is closed.
    pub fn hung_up(&self) -> bool {
        self.state.lock().unwrap().writers == 0
    }

    /// True when a writer would not block.
    /// Room for any write of at most [`PIPE_ATOMIC`] bytes (or no reader
    /// left, which a write must hear about), as Linux reports `POLLOUT`
    /// once a page of the pipe is free. Less room than that is not
    /// writable: a small write would be refused, and its waiter would only
    /// wake to be refused again.
    /// A Darwin pipe is writable (`pipe_select`) with `PIPE_BUF` free of
    /// `MAX_PIPESIZE`.
    pub fn writable(&self) -> bool {
        let s = self.state.lock().unwrap();
        if let Some(size) = s.xnu_size {
            return s.readers == 0 || size.max(xnu::PIPE_SIZE).saturating_sub(s.buf.len()) >= xnu::PIPE_BUF;
        }
        PIPE_BUF.saturating_sub(s.buf.len()) >= PIPE_ATOMIC || s.readers == 0
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use std::sync::Arc;

    /// `read_with` takes up to what is there, sized under the lock: never a
    /// stale size that splits a record; and hands over a wrapped buffer
    /// whole, in order.
    #[test]
    fn read_with_takes_whole_records() {
        let p = Pipe::new();
        let take = |p: &Pipe, max: usize| {
            let mut out = Vec::new();
            p.read_with(max, |a, b| {
                out.extend_from_slice(a);
                out.extend_from_slice(b);
            })
            .map(|n| {
                assert_eq!(n, out.len());
                out
            })
        };
        assert_eq!(take(&p, 64), Err(Errno::EAGAIN));
        p.write(&[3u8; 64]).unwrap();
        p.write(&[4u8; 64]).unwrap();
        assert_eq!(take(&p, 64).unwrap(), vec![3u8; 64]);
        assert_eq!(take(&p, 1000).unwrap(), vec![4u8; 64]);
        // Around the end of the ring: fill, drain part, fill again.
        let all: Vec<u8> = (0..PIPE_BUF).map(|i| i as u8).collect();
        assert_eq!(p.write(&all).unwrap(), PIPE_BUF as u64);
        assert_eq!(take(&p, 1000).unwrap(), all[..1000]);
        let more: Vec<u8> = (0..1000).map(|i| (i * 7) as u8).collect();
        assert_eq!(p.write(&more).unwrap(), 1000);
        let got = take(&p, PIPE_BUF).unwrap();
        assert_eq!(got[..PIPE_BUF - 1000], all[1000..]);
        assert_eq!(got[PIPE_BUF - 1000..], more[..]);
        // A write that wraps the ring, filled through `write_with`.
        let big: Vec<u8> = (0..PIPE_BUF).map(|i| (i * 13) as u8).collect();
        assert_eq!(p.write(&big[..5000]).unwrap(), 5000);
        assert_eq!(take(&p, 5000).unwrap(), big[..5000]);
        let n = p.write_with(PIPE_BUF, |d, from| d.copy_from_slice(&big[from..from + d.len()])).unwrap();
        assert_eq!(n, PIPE_BUF as u64);
        assert_eq!(take(&p, PIPE_BUF).unwrap(), big);
    }

    #[test]
    fn write_then_read_roundtrips() {
        let p = Pipe::new();
        assert_eq!(p.write(b"hello").unwrap(), 5);
        let mut buf = [0u8; 8];
        assert_eq!(p.read(&mut buf).unwrap(), 5);
        assert_eq!(&buf[..5], b"hello");
    }

    #[test]
    fn closing_the_writer_makes_reads_return_eof() {
        let p = Pipe::new();
        p.write(b"ab").unwrap();
        p.close_end(true);
        let mut buf = [0u8; 8];
        assert_eq!(p.read(&mut buf).unwrap(), 2);
        // Drained and no writers: end of file, not a block.
        assert_eq!(p.read(&mut buf).unwrap(), 0);
    }

    /// The read end polls as hung up once the last writer is gone, with
    /// data still in it or not; the write end never does.
    #[test]
    fn the_read_end_hangs_up_with_its_last_writer() {
        use crate::file::PipeEnd;
        use crate::vfs::FileHandle;
        let p = Arc::new(Pipe::new());
        let r = PipeEnd { pipe: Arc::clone(&p), write: false };
        let w = PipeEnd { pipe: Arc::clone(&p), write: true };
        p.write(b"x").unwrap();
        assert!(!r.poll_hup());
        p.close_end(true);
        assert!(r.poll_hup() && r.poll_readable());
        assert!(!w.poll_hup());
    }

    #[test]
    fn writing_with_no_readers_is_epipe() {
        let p = Pipe::new();
        p.close_end(false);
        assert_eq!(p.write(b"x").err(), Some(Errno::EPIPE));
    }

    #[test]
    fn reads_report_eagain_rather_than_waiting() {
        let p = Pipe::new();
        let mut buf = [0u8; 4];
        assert_eq!(p.read(&mut buf).err(), Some(Errno::EAGAIN));
    }

    #[test]
    fn an_empty_pipe_reports_rather_than_waits() {
        // A read here runs with the kernel locked, and whoever would supply
        // the data needs that lock to write. So an empty pipe says so, and
        // the syscall layer parks the caller outside the lock.
        let p = Arc::new(Pipe::new());
        let mut buf = [0u8; 8];
        assert!(!p.readable());
        assert_eq!(p.read(&mut buf).err(), Some(Errno::EAGAIN));
        p.write(b"late").unwrap();
        assert!(p.readable());
        let n = p.read(&mut buf).unwrap();
        assert_eq!(&buf[..n as usize], b"late");
    }

    #[test]
    fn a_full_pipe_takes_what_fits_and_says_so() {
        // As with a read, waiting here would be a deadlock: the reader that
        // would drain this needs the kernel lock the writer is holding. A
        // short write is what the caller gets, and the syscall layer parks a
        // descriptor that is supposed to block.
        let p = Pipe::new();
        let data = vec![7u8; PIPE_BUF + 1];
        assert_eq!(p.write(&data).unwrap(), PIPE_BUF as u64);
        assert_eq!(p.write(b"x").err(), Some(Errno::EAGAIN));
        let mut buf = vec![0u8; PIPE_BUF];
        assert_eq!(p.read(&mut buf).unwrap(), PIPE_BUF as u64);
        assert_eq!(p.write(b"x").unwrap(), 1);
    }

    #[test]
    fn a_small_write_goes_in_whole_or_not_at_all() {
        // At most PIPE_ATOMIC bytes: never split, so no other writer's
        // bytes can land inside it (Linux's PIPE_BUF rule).
        let p = Pipe::new();
        p.write(&vec![1u8; PIPE_BUF - 10]).unwrap();
        assert_eq!(p.write(&[2u8; 32]).err(), Some(Errno::EAGAIN));
        assert_eq!(p.buffered(), PIPE_BUF - 10);
        assert_eq!(p.write(&[2u8; 10]).unwrap(), 10);
        let mut buf = vec![0u8; 64];
        p.read(&mut buf).unwrap();
        assert_eq!(p.write(&[3u8; 32]).unwrap(), 32);
    }
}

/// A pipe that lives in another wasm module.
///
/// An `Arc<Pipe>` is a pointer, so both ends of such a pipe must share one
/// memory. Here the pipe is instead a *number*: the buffer lives in the global
/// kernel, each end is an id, and bytes cross by being copied between the two
/// processes' memories. So both ends can be Workers that share nothing else.
#[derive(Clone, Copy)]
pub struct Remote {
    /// Make a pipe with both ends open, held by `pid`. Returns its id.
    ///
    /// The pid lets the global kernel release a process's ends via
    /// `k_pipe_forget` when it leaves by a trap (no unwind, so no `Drop`).
    pub new: extern "C" fn(pid: i32) -> i32,
    /// Another descriptor onto one end, as `dup` and `fork` both make.
    pub open_end: extern "C" fn(id: i32, write: i32),
    /// How many descriptors hold each end, as `(readers << 16) | writers`.
    /// Negative when the pipe is gone. For the stall census only.
    pub ends: extern "C" fn(id: i32) -> i32,
    /// Short writes and refused writes, `(short << 16) | refused`.
    pub write_stats: extern "C" fn(id: i32) -> i32,
    /// How many writes have ever put bytes in. Negative when the pipe is gone.
    pub writes: extern "C" fn(id: i32) -> i32,
    /// The last message written, into the caller's memory. Returns its length.
    pub last_message: extern "C" fn(id: i32, at: crate::PAddr, cap: u32) -> i32,
    /// Drop a descriptor. The last one on an end is what a reader sees as EOF.
    pub close_end: extern "C" fn(id: i32, write: i32),
    /// Read into, or write out of, an address in the caller's memory.
    pub read: extern "C" fn(id: i32, at: crate::PAddr, len: u32) -> i32,
    pub write: extern "C" fn(id: i32, at: crate::PAddr, len: u32) -> i32,
    pub readable: extern "C" fn(id: i32) -> i32,
    pub writable: extern "C" fn(id: i32) -> i32,
    pub buffered: extern "C" fn(id: i32) -> i32,
    /// The pipe's wait queue (`crate::wait`).
    pub queue: extern "C" fn(id: i32) -> u32,
}

/// One end of a pipe in the global kernel. Dropping closes that end there, so
/// a writer whose Worker exited counts as EOF just like a `close`.
pub struct RemotePipeEnd {
    pub id: i32,
    pub write: bool,
    pub remote: Remote,
}

impl std::fmt::Debug for RemotePipeEnd {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        write!(
            f,
            "RemotePipeEnd({}, {})",
            self.id,
            if self.write { "w" } else { "r" }
        )
    }
}

impl Drop for RemotePipeEnd {
    fn drop(&mut self) {
        (self.remote.close_end)(self.id, self.write as i32);
    }
}

impl crate::vfs::FileHandle for RemotePipeEnd {
    fn read_at(&self, _offset: u64, buf: &mut [u8]) -> SysResult {
        if self.write {
            return Err(Errno::EBADF);
        }
        match (self.remote.read)(self.id, buf.as_mut_ptr() as crate::PAddr, buf.len() as u32) {
            n if n >= 0 => Ok(n as u64),
            n => Err(Errno(-n)),
        }
    }

    fn write_at(&self, _offset: u64, buf: &[u8]) -> SysResult {
        if !self.write {
            return Err(Errno::EBADF);
        }
        match (self.remote.write)(self.id, buf.as_ptr() as crate::PAddr, buf.len() as u32) {
            n if n >= 0 => Ok(n as u64),
            n => Err(Errno(-n)),
        }
    }

    fn metadata(&self) -> Result<crate::vfs::Metadata, Errno> {
        Ok(crate::vfs::Metadata {
            file_type: crate::vfs::FileType::Fifo,
            size: 0,
            mode: 0o600,
            ino: crate::vfs::anon_ino((0x10000 + self.id as usize) as *const u8),
            mtime: 0,
            nlink: 1,
            rdev: 0,
            times: Default::default(),
        })
    }

    fn is_stream(&self) -> bool {
        true
    }

    /// A pipe with nothing in it is not readable, whatever the default says.
    /// The default is "yes", which is right for a file and wrong here.
    /// (A write end is never readable, as Linux.)
    fn poll_readable(&self) -> bool {
        !self.write && (self.remote.readable)(self.id) != 0
    }

    fn poll_writable(&self) -> bool {
        !self.write || (self.remote.writable)(self.id) != 0
    }

    fn wait_queue(&self) -> u32 {
        (self.remote.queue)(self.id)
    }

    /// The read end of a pipe with room in it: no writer is parked on it.
    /// (One that fills it between this question and the read sleeps to its
    /// park's bound, or the next wake, not for ever.)
    fn read_frees_nothing(&self) -> bool {
        !self.write && (self.remote.writable)(self.id) != 0
    }

    fn available(&self) -> Option<u64> {
        Some(if self.write {
            0
        } else {
            (self.remote.buffered)(self.id).max(0) as u64
        })
    }

    fn write_room(&self) -> Option<u64> {
        // Not reported: a number here could be invalidated by another Worker
        // between the claim and the write. Short writes are carried by the
        // syscall layer instead.
        None
    }

    fn debug_state(&self) -> String {
        // With the ends: "0 buffered" alone cannot tell a reader stuck with
        // no writers left (a lost wake or miscounted close) from one whose
        // writer simply has not written.
        let e = (self.remote.ends)(self.id);
        let (r, w) = if e < 0 {
            (-1i32, -1i32)
        } else {
            ((e >> 16) & 0xffff, e & 0xffff)
        };
        let ws = (self.remote.write_stats)(self.id);
        let (short, refused) = if ws < 0 { (-1i32, -1i32) } else { ((ws >> 16) & 0xffff, ws & 0xffff) };
        let broken = (short >> 8) & 0xff;
        let short = short & 0xff;
        let wrote = if short > 0 || refused > 0 || broken > 0 {
            format!(", {short} short {refused} refused {broken} broken")
        } else {
            String::new()
        };
        let n = (self.remote.writes)(self.id);
        let mut buf = [0u8; 180];
        let got = (self.remote.last_message)(self.id, buf.as_mut_ptr() as crate::PAddr, buf.len() as u32);
        let said = if got > 0 {
            format!(", last {:?}", String::from_utf8_lossy(&buf[..got as usize]))
        } else {
            String::new()
        };
        format!(
            "shared pipe {} {}, {} buffered, {r} readers {w} writers, {n} writes ever{wrote}{said}",
            self.id,
            if self.write { "write" } else { "read" },
            (self.remote.buffered)(self.id)
        )
    }

}
