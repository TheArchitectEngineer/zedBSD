/*
 * zedBSD
 * Copyright (C) 2026 Awe Morris
 *
 * SPDX-License-Identifier: Zlib
 */

/*
 * The GHCI device's command processor: CP_HEAP, the ring, the fence
 * page, the gate, the submissions and their tickets, and the interrupt.
 *
 * The ring is host memory the driver alone writes; RING_WPTR is the
 * doorbell and both indices count dwords.  A packet never crosses the
 * end of the ring: the rest of the ring is filled with a NOP first.  A
 * submission is placed whole under cp_lock (in pieces at packet
 * boundaries, with a doorbell before each wait, when the ring is short of
 * room) and ends with a CMD_FENCE of the next 64-bit sequence.  A wait
 * for room ends only when RING_RPTR moves or a recovery begins: a
 * processor that stopped is the hang check's to find.
 *
 * Values referenced: amaterrace-gpu d9252e4 docs/ghci.md (section 6,
 * the ring, the doorbell and the fence; section 9, the interrupt;
 * Appendix A, the order of the start).
 */

#include <stddef.h>
#include <stdint.h>

#include <drivers/gpu/gpu.h>
#include <kern/clock.h>
#include <kern/device-io.h>
#include <kern/kcrt.h>
#include <kern/klog.h>
#include <uapi/errno.h>

#include "ghci.h"
#include "ghci-cmd.h"

/* The interrupts that start a recovery, and every interrupt the handler takes. */
#define IRQ_RECOVER			(GHCI_IRQ_FAULT | GHCI_IRQ_WATCHDOG)
#define IRQ_TAKEN			(GHCI_IRQ_FENCE | IRQ_RECOVER)

/* The end of CP_HEAP at most: a page below 4 GiB. */
#define HEAP_END			0xfffff000ULL

/* Every bit of IRQ_STATUS, which the start clears. */
#define IRQ_ALL				0xffffffffU

static int alloc_heap(struct ghci_device *device);
static int liveness(struct ghci_device *device, int want_interrupt);
static void release_memory(struct ghci_device *device);
static int ring_room(struct ghci_device *device, uint32_t need, int log_entry);
static void ring_store(struct ghci_device *device, uint32_t index, uint32_t word);
static void retire_log(struct ghci_device *device);
static int packet_length(const uint32_t *packets, uint32_t left, uint32_t *length);
static void record_fault(struct ghci_device *device, uint32_t irq_status, uint64_t generation);
static void take_fence(struct ghci_device *device, uint32_t irq_status, uint64_t generation);
static enum ghci_ticket_state ticket_state(struct ghci_device *device, const struct ghci_ticket *ticket);
static void log_registers(struct ghci_device *device, const char *what);

/*
 * Starts the command processor: CP_HEAP, the ring and the fence page,
 * the interrupt, the watchdog, bus mastering, RUN and the first fence.
 *
 * Returns 0 with the ring running, or an error with the GPU reset, the
 * interrupt let go and the memory given back.
 */
int
ghci_cp_start(
	struct ghci_device *device)
{
	unsigned long irq;
	uint32_t cycles;
	uint32_t gclk_hz;
	int error;

	/* CP_HEAP, which the processor's page-table walker takes its tables from. */
	error = alloc_heap(device);
	if (error != 0)
		return error;

	/* The ring's size: the glue's, or the default; a power of two between 4 KiB and 16 MiB. */
	if (device->ring_bytes == 0U)
		device->ring_bytes = GHCI_RING_BYTES;
	if (device->ring_bytes < GHCI_RING_BYTES_MIN || device->ring_bytes > GHCI_RING_BYTES_MAX ||
	    (device->ring_bytes & (device->ring_bytes - 1U)) != 0U) {
		release_memory(device);
		return EINVAL;
	}

	/* The ring and the fence page, in host memory below the driver's limit. */
	error = ghci_memory_alloc(device, device->ring_bytes, 0U, &device->ring.memory);
	if (error != 0) {
		release_memory(device);
		return error;
	}
	error = ghci_memory_alloc(device, GHCI_FENCE_PAGE_BYTES, 0U, &device->fence_page);
	if (error != 0) {
		release_memory(device);
		return error;
	}
	device->ring.dwords = device->ring_bytes / 4U;
	device->ring.wptr = 0U;
	device->fence_placed = 0U;
	device->submit_first = 0U;
	device->submit_count = 0U;
	device->recovery_placing = 0;

	/* Session 0's record and what CP_HEAP may hold. */
	ghci_vm_init(device);

	/* The ring's place and size, written while the processor is idle. */
	ghci_write(device, GHCI_REG_RING_BASE_LO, (uint32_t)device->ring.memory->bus);
	ghci_write(device, GHCI_REG_RING_BASE_HI, (uint32_t)(device->ring.memory->bus >> 32));
	ghci_write(device, GHCI_REG_RING_SIZE, device->ring_bytes);
	ghci_write(device, GHCI_REG_RING_WPTR, 0U);

	/* The interrupt, taken only now that the reset has cleared what a kernel before this one left. */
	error = device->bus_ops->interrupt_take(device);
	if (error != 0) {
		release_memory(device);
		return error;
	}
	device->interrupt_taken = 1;

	/* The watchdog: GHCI_WATCHDOG_MS at the core clock, or the reset default when the clock is unknown. */
	gclk_hz = ghci_read(device, GHCI_REG_GCLK_HZ);
	cycles = ghci_watchdog_cycles(gclk_hz, GHCI_WATCHDOG_MS);
	if (cycles != 0U)
		ghci_write(device, GHCI_REG_WDT_CYCLES, cycles);
	device->wdt_cycles = ghci_read(device, GHCI_REG_WDT_CYCLES);
	device->reset_wait_ms = ghci_reset_wait_ms(gclk_hz, device->wdt_cycles);

	/* The fences, the generations and the interrupts the handler takes, before any can come. */
	irq = spin_lock_irqsave(&device->irq_lock);

	device->irq_mask = IRQ_TAKEN;
	device->completed = 0U;
	device->issued = 0U;
	device->recovering = 0;
	device->fault_records = 0U;
	device->progress_tick = clock_ticks();

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* Nothing pending, and the interrupts the driver takes (none on a polled device). */
	ghci_write(device, GHCI_REG_IRQ_STATUS, IRQ_ALL);
	ghci_cp_irq_enable(device);

	/* Bus mastering, unless the firmware left it on for a boot display. */
	if (!device->bus_master_found) {
		error = device->bus_ops->bus_master(device, 1);
		if (error != 0) {
			(void)ghci_cp_stop(device);
			return error;
		}
		device->bus_master_set = 1;
	}

	/* The ring runs; the processor builds session 0's root in CP_HEAP. */
	irq = spin_lock_irqsave(&device->irq_lock);

	device->state = GHCI_STATE_RUNNING;

	spin_unlock_irqrestore(&device->irq_lock, irq);
	ghci_cp_run(device);

	/* One fence must be written, with its interrupt unless the device is polled. */
	error = liveness(device, !device->polled);
	if (error != 0) {
		log_registers(device, "first fence not written");
		(void)ghci_cp_stop(device);
		return EIO;
	}

	/* Succeeded: the ring runs. */
	return 0;
}

/*
 * Stops the command processor at the detach or after a failed start: it
 * halts, resets and stops, the interrupt and bus mastering go, the poll
 * thread leaves, and the memory is given back unless the GPU or a late
 * handler may still reach it.
 *
 * Returns 0, or EBUSY when the interrupt could not be let go (a handler
 * may still run): the memory is then kept and the caller keeps the
 * device; a later call tries again.
 */
int
ghci_cp_stop(
	struct ghci_device *device)
{
	enum ghci_device_state state;
	unsigned long irq;
	uint32_t ctrl;
	int reset_done;
	int master_off;
	int released;
	int error;

	/* The device's life as the last recovery left it. */
	irq = spin_lock_irqsave(&device->irq_lock);

	state = device->state;

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* A running processor halts first, between packets. */
	if (state == GHCI_STATE_RUNNING) {
		ctrl = ghci_read(device, GHCI_REG_CTRL);
		ghci_write(device, GHCI_REG_CTRL, ctrl | GHCI_CTRL_HALT);
		error = ghci_wait_register(device, GHCI_REG_STATUS, GHCI_STATUS_HALTED, GHCI_STATUS_HALTED, GHCI_HALT_WAIT_MS);
		if (error != 0)
			kern_logf("ghci: %s: processor did not halt at the stop\n", device->name);
	}

	/* The reset stops every access to the ring and CP_HEAP. */
	ghci_write(device, GHCI_REG_CTRL, GHCI_CTRL_RESET);
	error = ghci_wait_register(device, GHCI_REG_CTRL, GHCI_CTRL_RESET, 0U, device->reset_wait_ms);
	reset_done = 1;
	if (error != 0) {
		kern_logf("ghci: %s: reset at the stop did not end\n", device->name);
		reset_done = 0;
	}

	/* No interrupt (the handler restores nothing from here), nothing running. */
	irq = spin_lock_irqsave(&device->irq_lock);

	device->irq_mask = 0U;
	device->state = GHCI_STATE_DETACHED;
	ghci_write(device, GHCI_REG_IRQ_ENABLE, 0U);

	spin_unlock_irqrestore(&device->irq_lock, irq);
	ghci_write(device, GHCI_REG_CTRL, 0U);

	/* The handler goes, so that a late interrupt does not reach the ring or the fence page. */
	released = 1;
	if (device->interrupt_taken) {
		error = device->bus_ops->interrupt_release(device);
		if (error == 0)
			device->interrupt_taken = 0;
		else
			released = 0;
	}

	/*
	 * Bus mastering goes if the driver turned it on, or if the reset did
	 * not end; one the firmware left on for a boot display stays, with
	 * the GPU reset and its ring stopped.
	 */
	master_off = 0;
	if (device->bus_master_set || !reset_done) {
		error = device->bus_ops->bus_master(device, 0);
		if (error == 0) {
			master_off = 1;
			device->bus_master_set = 0;
		}
	}

	/* The poll thread leaves before the fence page it reads goes. */
	ghci_poll_stop(device);

	/* A handler that may still run keeps the memory, and the device. */
	if (!released) {
		kern_logf("ghci: %s: interrupt not let go; the device is kept\n", device->name);
		return EBUSY;
	}

	/* A GPU that may still reach the memory keeps it (the device itself can go). */
	if (!reset_done && !master_off) {
		kern_logf("ghci: %s: GPU not stopped; its memory is kept\n", device->name);
		return 0;
	}

	/* Succeeded: the sessions' records and the memory go back. */
	ghci_vm_fini(device);
	release_memory(device);
	return 0;
}

/*
 * Passes the gate of the ring: takes cp_lock unless a recovery runs or
 * the device is lost.
 *
 * held names the outer locks the caller holds (GHCI_HOLD_DEVICE,
 * GHCI_HOLD_DISPLAY).  OPEN: cp_lock is held, with the outer locks.
 * RETRY: a recovery ran or runs; every lock the caller held has been let
 * go, and with wait the gate has waited for the recovery to end; the
 * caller starts again and reads its state again.  LOST: every lock has
 * been let go and the device is lost.
 */
enum ghci_gate
ghci_cp_enter(
	struct ghci_device *device,
	unsigned held,
	int wait)
{
	enum ghci_gate gate;
	unsigned long irq;
	uint64_t generation;
	uint64_t sequence;

	/* The ring's lock, and what the recovery says under the interrupt's. */
	mutex_lock(&device->cp_lock);
	irq = spin_lock_irqsave(&device->irq_lock);

	gate = GHCI_GATE_OPEN;
	if (device->state == GHCI_STATE_LOST)
		gate = GHCI_GATE_LOST;
	else if (device->recovering)
		gate = GHCI_GATE_RETRY;
	generation = device->gate_generation;

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* Succeeded at once: the ring is the caller's. */
	if (gate == GHCI_GATE_OPEN)
		return GHCI_GATE_OPEN;

	/* Lets go of every lock, the innermost first, so that the recovery can take them. */
	mutex_unlock(&device->cp_lock);
	if ((held & GHCI_HOLD_DISPLAY) != 0U)
		mutex_unlock(&device->display_lock);
	if ((held & GHCI_HOLD_DEVICE) != 0U)
		mutex_unlock(&device->lock);

	/* A lost device, or a caller that does not wait, is answered now. */
	if (gate == GHCI_GATE_LOST || !wait)
		return gate;

	/* Waits for the gate to open again or the device to be lost. */
	irq = spin_lock_irqsave(&device->irq_lock);

	while (device->gate_generation == generation && device->state != GHCI_STATE_LOST) {
		sequence = waitq_sequence(&device->gate_wake);
		(void)waitq_sleep(&device->gate_wake, &device->irq_lock, sequence, 0U, 0U);
	}
	if (device->state == GHCI_STATE_LOST)
		gate = GHCI_GATE_LOST;

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* Succeeded: the caller starts again (or hears that the device is lost). */
	return gate;
}

/*
 * Leaves the ring after ghci_cp_enter() opened it.
 */
void
ghci_cp_leave(
	struct ghci_device *device)
{
	/* The ring is free for the next caller. */
	mutex_unlock(&device->cp_lock);
}

/*
 * Places packets in the ring, without the doorbell.
 *
 * The caller holds cp_lock.  The packets are placed one at a time, each
 * whole and never across the end of the ring; while the ring has no room
 * the doorbell rings for what is placed and the placement waits for
 * RING_RPTR.  Returns 0, EINVAL for a packet that is malformed or larger
 * than the ring, or EAGAIN when a recovery began (or the device was lost)
 * while it waited; the packets placed until then are lost to the reset.
 */
int
ghci_cp_place(
	struct ghci_device *device,
	const uint32_t *packets,
	uint32_t dwords)
{
	uint32_t length;
	uint32_t index;
	uint32_t done;
	int error;

	/* Each packet in turn. */
	done = 0U;
	while (done < dwords) {
		/* The packet's length from its header. */
		error = packet_length(&packets[done], dwords - done, &length);
		if (error != 0)
			return error;

		/* Room for it, with the padding before the end of the ring. */
		error = ring_room(device, length, 0);
		if (error != 0)
			return error;

		/* Copies it to the ring. */
		for (index = 0U; index < length; index++)
			ring_store(device, device->ring.wptr + index, packets[done + index]);
		device->ring.wptr = (device->ring.wptr + length) % device->ring.dwords;
		done += length;
	}

	/* Succeeded: every packet is in the ring. */
	return 0;
}

/*
 * Rings the doorbell for everything placed: the ring's writes become
 * visible first, then RING_WPTR moves.  The caller holds cp_lock.
 */
void
ghci_cp_doorbell(
	struct ghci_device *device)
{
	/* The ring's dwords before the doorbell (section 6.3). */
	kern_io_write_barrier();
	ghci_write(device, GHCI_REG_RING_WPTR, device->ring.wptr);
}

/*
 * Places the CMD_FENCE that ends a submission: the next 64-bit sequence
 * into the fence page, with the fence interrupt.
 *
 * The caller holds cp_lock; start is where the submission began in the
 * ring and owner the session whose work it ends (NULL for the driver's
 * own).  Returns 0 with the submission's ticket, or EAGAIN as
 * ghci_cp_place() does.
 */
int
ghci_cp_place_fence(
	struct ghci_device *device,
	struct ghci_vm *owner,
	uint32_t start,
	struct ghci_ticket *ticket)
{
	struct ghci_submit_entry *entry;
	uint32_t packet[GHCI_DW_FENCE];
	unsigned long irq;
	uint64_t seq;
	uint32_t index;
	int idle;
	int error;

	/* Room for the fence and for the submission's entry in the log. */
	error = ring_room(device, GHCI_DW_FENCE, 1);
	if (error != 0)
		return error;

	/* The fence of the next sequence. */
	seq = device->fence_placed + 1U;
	(void)ghci_cmd_fence(packet, device->fence_page->bus, seq, GHCI_FENCE_FLAG_MEM_WRITE | GHCI_FENCE_FLAG_IRQ);
	for (index = 0U; index < GHCI_DW_FENCE; index++)
		ring_store(device, device->ring.wptr + index, packet[index]);
	device->ring.wptr = (device->ring.wptr + GHCI_DW_FENCE) % device->ring.dwords;
	device->fence_placed = seq;

	/* The submission's entry in the log, until its fence is seen passed. */
	entry = &device->submit_log[(device->submit_first + device->submit_count) % GHCI_SUBMIT_LOG];
	entry->start = start;
	entry->end = device->ring.wptr;
	entry->seq = seq;
	entry->owner = owner;
	device->submit_count++;

	/*
	 * The ticket, in the generation the fence was placed in, and the
	 * last fence placed for the hang check; a ring that was idle starts
	 * the hang check's clock now.
	 */
	irq = spin_lock_irqsave(&device->irq_lock);

	idle = ghci_fence64_passed(device->completed, device->issued);
	if (idle)
		device->progress_tick = clock_ticks();
	device->issued = seq;
	ticket->seq = seq;
	ticket->generation = device->generation;

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* Succeeded: the fence is placed. */
	return 0;
}

/*
 * Submits packets of a session (NULL for the driver's own work in
 * session 0): binds the session, places the packets and a fence, binds
 * session 0 again, and rings the doorbell.  A GPU without a page-table
 * walker has no sessions to bind.
 *
 * Returns 0 with the ticket, EIO when the device is lost, the session is
 * not open (a reset ended it) or a recovery began after part of the
 * submission was placed (that part is lost to the reset), or EINVAL for
 * a malformed packet, before anything is placed.
 */
int
ghci_cp_submit(
	struct ghci_device *device,
	struct ghci_vm *vm,
	const uint32_t *packets,
	uint32_t dwords,
	struct ghci_ticket *ticket)
{
	enum ghci_gate gate;
	uint32_t bind[GHCI_DW_BIND_SESSION];
	uint32_t session;
	uint32_t start;
	int walker;
	int error;

	/* A run of packets the ring cannot take is refused before anything is placed. */
	error = ghci_cp_check_packets(packets, dwords);
	if (error != 0)
		return error;

	/* Passes the gate, waiting out a recovery; nothing was placed before it. */
	for (;;) {
		gate = ghci_cp_enter(device, 0U, 1);
		if (gate == GHCI_GATE_LOST)
			return EIO;
		if (gate == GHCI_GATE_OPEN)
			break;
	}

	/* Only an open session submits; its state does not change while cp_lock is held. */
	if (vm != NULL && vm->state != GHCI_VM_OPEN) {
		ghci_cp_leave(device);
		return EIO;
	}

	/* The session the packets run in. */
	session = 0U;
	if (vm != NULL)
		session = vm->session;
	start = device->ring.wptr;
	walker = ghci_caps_has(&device->caps, GHCI_HAS_HW_WALKER);
	error = 0;
	if (walker) {
		(void)ghci_cmd_bind_session(bind, session);
		error = ghci_cp_place(device, bind, GHCI_DW_BIND_SESSION);
	}

	/* The packets, and the fence that says they are done. */
	if (error == 0)
		error = ghci_cp_place(device, packets, dwords);
	if (error == 0)
		error = ghci_cp_place_fence(device, vm, start, ticket);

	/* Session 0 again, so that the driver's later packets do not run in the client's session. */
	if (error == 0 && walker) {
		(void)ghci_cmd_bind_session(bind, 0U);
		error = ghci_cp_place(device, bind, GHCI_DW_BIND_SESSION);
	}

	/* The doorbell for what was placed, even a part a recovery will throw away. */
	ghci_cp_doorbell(device);
	ghci_cp_leave(device);

	/* A recovery that began in the middle lost the submission. */
	if (error == EAGAIN)
		return EIO;
	if (error != 0)
		return error;

	/* Succeeded: the submission is in the ring. */
	return 0;
}

/*
 * Waits a bounded time for a ticket.  The caller holds neither the
 * device's lock nor the display's.
 *
 * Returns 0 once its fence passed, EIO when a reset or the loss of the
 * device ended it, or ETIMEDOUT.
 */
int
ghci_cp_wait(
	struct ghci_device *device,
	const struct ghci_ticket *ticket,
	unsigned milliseconds)
{
	enum ghci_ticket_state state;
	unsigned long irq;
	uint64_t deadline;
	uint64_t sequence;
	uint64_t now;

	/* The wait ends at the deadline. */
	deadline = clock_ticks() + kern_ms_to_ticks(milliseconds);

	/*
	 * Sleeps on the fence interrupts until the ticket is answered or the
	 * time is up; the queue's sequence is read before the ticket in the
	 * same section, so that no wake between them is missed.
	 */
	irq = spin_lock_irqsave(&device->irq_lock);

	for (;;) {
		sequence = waitq_sequence(&device->fence_wake);
		state = ticket_state(device, ticket);
		if (state != GHCI_TICKET_PENDING)
			break;
		now = clock_ticks();
		if (now >= deadline)
			break;
		(void)waitq_sleep(&device->fence_wake, &device->irq_lock, sequence, deadline, 0U);
	}

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* A ticket a reset ended, or a wait that ran out. */
	if (state == GHCI_TICKET_FAILED)
		return EIO;
	if (state == GHCI_TICKET_PENDING)
		return ETIMEDOUT;

	/* Succeeded: the fence has passed. */
	return 0;
}

/*
 * Reports the state of a ticket: pending, done, or failed because a
 * reset or the loss of the device ended it before its fence passed.
 */
enum ghci_ticket_state
ghci_cp_ticket(
	struct ghci_device *device,
	const struct ghci_ticket *ticket)
{
	enum ghci_ticket_state state;
	unsigned long irq;

	/* The fence and the generations, read together. */
	irq = spin_lock_irqsave(&device->irq_lock);

	state = ticket_state(device, ticket);

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* Succeeded: the ticket's state. */
	return state;
}

/*
 * Checks a run of packets before any is placed: every header names a
 * length of at least one dword that stays inside the run.  Returns 0, or
 * EINVAL.
 */
int
ghci_cp_check_packets(
	const uint32_t *packets,
	uint32_t dwords)
{
	uint32_t length;
	uint32_t done;
	int error;

	/* Each packet's length in turn. */
	done = 0U;
	while (done < dwords) {
		error = packet_length(&packets[done], dwords - done, &length);
		if (error != 0)
			return error;
		done += length;
	}

	/* Succeeded: the run is whole packets. */
	return 0;
}

/*
 * Waits a bounded time for the fence page itself to reach a sequence,
 * whatever the recovery says; only the start and the recovery use it,
 * for the fences they place to see that the processor runs.
 *
 * Returns 0, or ETIMEDOUT.
 */
int
ghci_cp_await_fence(
	struct ghci_device *device,
	uint64_t seq,
	unsigned milliseconds)
{
	uint64_t word;
	unsigned waited;
	int passed;

	/* Reads the fence page every millisecond until it reaches the sequence or the time is up. */
	for (waited = 0U; waited <= milliseconds; waited++) {
		word = ghci_fence_read(device);
		passed = ghci_fence64_passed(word, seq);
		if (passed)
			return 0;

		/* Sleeps for a millisecond before the next read. */
		ghci_sleep_ms(1U);
	}

	/* The fence never came. */
	return ETIMEDOUT;
}

/*
 * Empties the ring as a reset left it: RING_WPTR and RING_RPTR are 0
 * and no submission is outstanding.  The caller holds cp_lock.
 */
void
ghci_cp_ring_reset(
	struct ghci_device *device)
{
	/* The driver's write index follows the device's. */
	device->ring.wptr = 0U;

	/* Every submission of the log was lost to the reset. */
	device->submit_first = 0U;
	device->submit_count = 0U;
}

/*
 * Lets the processor run the ring: with the watchdog, and with the
 * interrupt unless the device is polled.  The caller holds cp_lock or
 * owns the device alone.
 */
void
ghci_cp_run(
	struct ghci_device *device)
{
	uint32_t ctrl;

	/* RUN and WDT_EN; IRQ_GLOBAL only when an interrupt is taken. */
	ctrl = GHCI_CTRL_RUN | GHCI_CTRL_WDT_EN;
	if (!device->polled)
		ctrl |= GHCI_CTRL_IRQ_GLOBAL;
	ghci_write(device, GHCI_REG_CTRL, ctrl);
}

/*
 * Writes IRQ_ENABLE from irq_mask, or zero on a polled device, whose
 * IRQ_STATUS still latches what the poll reads.
 */
void
ghci_cp_irq_enable(
	struct ghci_device *device)
{
	unsigned long irq;
	uint32_t mask;

	/* The mask the handler takes, written in the section the handler reads it in; none when polled. */
	irq = spin_lock_irqsave(&device->irq_lock);

	mask = device->irq_mask;
	if (device->polled)
		mask = 0U;
	ghci_write(device, GHCI_REG_IRQ_ENABLE, mask);

	spin_unlock_irqrestore(&device->irq_lock, irq);
}

/*
 * The interrupt handler of the device, and the poll's work on a polled
 * device: a fault or the watchdog starts a recovery, a fence moves the
 * completed fence on.
 *
 * Returns 1 when the device had an event, 0 otherwise.
 */
int
ghci_cp_interrupt(
	void *argument)
{
	struct ghci_device *device;
	unsigned long irq;
	uint64_t generation;
	uint32_t status;
	uint32_t mask;

	/*
	 * Masks the interrupt, reads what is pending, clears it (write 1 to
	 * clear) and unmasks, all with the mask and the recovery generation
	 * of one section, so that the start and the stop never see a mask
	 * written back behind them.  A polled device's IRQ_STATUS latches
	 * whatever IRQ_ENABLE says.
	 */
	device = argument;
	irq = spin_lock_irqsave(&device->irq_lock);

	mask = device->irq_mask;
	generation = device->recovery_generation;
	if (!device->polled)
		ghci_write(device, GHCI_REG_IRQ_ENABLE, 0U);
	status = ghci_read(device, GHCI_REG_IRQ_STATUS);
	status &= mask;
	if (status != 0U)
		ghci_write(device, GHCI_REG_IRQ_STATUS, status);
	if (!device->polled)
		ghci_write(device, GHCI_REG_IRQ_ENABLE, mask);

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* Nothing of the GPU's to serve: another device's interrupt on a shared line, or a quiet poll. */
	if (status == 0U)
		return 0;

	/* A fault or the watchdog is taken before a fence. */
	if ((status & IRQ_RECOVER) != 0U)
		record_fault(device, status, generation);

	/* A fence wrote the fence page. */
	if ((status & GHCI_IRQ_FENCE) != 0U)
		take_fence(device, status, generation);

	/* Wakes the waiters of tickets and of the ring's room, and the service thread. */
	waitq_wake_all(&device->fence_wake);
	waitq_wake_all(&device->ring_wake);
	waitq_wake_all(&device->service_wake);

	/* Succeeded: the interrupt was the device's. */
	return 1;
}

/*
 * Takes CP_HEAP: the bound of every session's tables on a GPU with a
 * page-table walker, halved while it cannot be had, or session 0's root
 * alone on one without.  CP_HEAP is 32-bit physical memory.
 */
static int
alloc_heap(
	struct ghci_device *device)
{
	uint64_t bytes;
	int walker;
	int error;

	/* The size the walker may need at most, or the flat root. */
	walker = ghci_caps_has(&device->caps, GHCI_HAS_HW_WALKER);
	bytes = GHCI_FLAT_HEAP_BYTES;
	if (walker)
		bytes = ghci_heap_device_bytes(device->caps.va_bits);

	/*
	 * Halves the size while the memory cannot be had, down to the smallest
	 * the driver settles for.  The heap ends a page below 4 GiB at most,
	 * so that its exclusive CP_HEAP_LIMIT is a 32-bit address.
	 */
	for (;;) {
		error = ghci_memory_alloc(device, bytes, HEAP_END, &device->heap);
		if (error == 0)
			break;
		if (!walker || bytes / 2U < GHCI_HEAP_MIN_BYTES) {
			kern_logf("ghci: %s: no CP_HEAP of %llu bytes\n", device->name, (unsigned long long)bytes);
			return error;
		}
		bytes /= 2U;
	}

	/*
	 * Values referenced: amaterrace-gpu d9252e4 docs/ghci.md (section
	 * 11.2, CP_HEAP_BASE and the exclusive CP_HEAP_LIMIT, 4 KiB aligned
	 * 32-bit physical addresses, written while the processor is idle).
	 */
	ghci_write(device, GHCI_REG_CP_HEAP_BASE, (uint32_t)device->heap->bus);
	ghci_write(device, GHCI_REG_CP_HEAP_LIMIT, (uint32_t)(device->heap->bus + device->heap->bytes));

	/* Succeeded: CP_HEAP is set. */
	return 0;
}

/*
 * Places one fence of the driver's and waits a bounded time for the
 * fence page to reach it, and with want_interrupt for its interrupt too.
 * Returns 0, or ETIMEDOUT.
 */
static int
liveness(
	struct ghci_device *device,
	int want_interrupt)
{
	struct ghci_ticket ticket;
	unsigned long irq;
	unsigned interrupts;
	unsigned waited;
	int error;

	/* The interrupts seen so far. */
	irq = spin_lock_irqsave(&device->irq_lock);

	interrupts = device->fence_interrupts;

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* The fence, placed and rung under the ring's lock. */
	mutex_lock(&device->cp_lock);

	error = ghci_cp_place_fence(device, NULL, device->ring.wptr, &ticket);
	if (error == 0)
		ghci_cp_doorbell(device);

	mutex_unlock(&device->cp_lock);
	if (error != 0)
		return ETIMEDOUT;

	/* The fence page must reach it. */
	error = ghci_cp_await_fence(device, ticket.seq, GHCI_LIVENESS_MS);
	if (error != 0)
		return ETIMEDOUT;

	/* A device with an interrupt must have raised it too. */
	for (waited = 0U; want_interrupt && waited <= GHCI_LIVENESS_MS; waited++) {
		irq = spin_lock_irqsave(&device->irq_lock);

		if (device->fence_interrupts != interrupts)
			want_interrupt = 0;

		spin_unlock_irqrestore(&device->irq_lock, irq);

		/* Sleeps for a millisecond while the interrupt has not come. */
		if (want_interrupt)
			ghci_sleep_ms(1U);
	}
	if (want_interrupt)
		return ETIMEDOUT;

	/* Succeeded: the processor runs and the interrupt comes. */
	return 0;
}

/* Gives back the device's own memory: CP_HEAP, the ring, the fence page and the quarantine. */
static void
release_memory(
	struct ghci_device *device)
{
	int error;

	/* Each run, if it was taken; one that cannot be given back is kept in the quarantine. */
	error = ghci_memory_free(device, device->heap);
	if (error != 0)
		ghci_memory_quarantine(device, device->heap);
	device->heap = NULL;
	error = ghci_memory_free(device, device->ring.memory);
	if (error != 0)
		ghci_memory_quarantine(device, device->ring.memory);
	device->ring.memory = NULL;
	error = ghci_memory_free(device, device->fence_page);
	if (error != 0)
		ghci_memory_quarantine(device, device->fence_page);
	device->fence_page = NULL;

	/* The quarantine of a lost device, now that the GPU reaches nothing. */
	ghci_memory_release_quarantine(device);
}

/*
 * Waits until the ring has room for need dwords (and the padding before
 * its end, which this writes), and with log_entry a free entry of the
 * submission log.  The caller holds cp_lock.
 *
 * Returns 0, EINVAL for a run no ring of this size takes, or EAGAIN when
 * a recovery began or the device was lost while it waited.  The
 * recovery's own placement (recovery_placing) waits on through the
 * recovery that runs, and ends with EAGAIN at a new fault or at its
 * deadline.
 */
static int
ring_room(
	struct ghci_device *device,
	uint32_t need,
	int log_entry)
{
	unsigned long irq;
	uint64_t deadline;
	uint64_t sequence;
	uint32_t padding;
	uint32_t written;
	uint32_t index;
	uint32_t rptr;
	uint64_t now;
	int stopping;
	int error;

	/* Looks again after each fence interrupt or poll period, until there is room. */
	for (;;) {
		/* The submissions whose fences passed leave the log. */
		retire_log(device);

		/* The reader's index; one outside the ring leaves no room until a recovery. */
		rptr = ghci_read(device, GHCI_REG_RING_RPTR);
		error = EAGAIN;
		if (rptr < device->ring.dwords)
			error = ghci_ring_plan(device->ring.wptr, rptr, device->ring.dwords, need, &padding);
		if (error == EINVAL)
			return EINVAL;
		if (error == 0 && log_entry && device->submit_count >= GHCI_SUBMIT_LOG)
			error = EAGAIN;
		if (error == 0)
			break;

		/* The processor gets what is placed, so that it can make room. */
		ghci_cp_doorbell(device);

		/* Sleeps until a fence interrupt or the poll period; a recovery ends the wait. */
		now = clock_ticks();
		irq = spin_lock_irqsave(&device->irq_lock);

		stopping = device->recovering || device->state == GHCI_STATE_LOST;
		if (device->recovery_placing)
			stopping = device->fault_count != device->recovery_faults || now >= device->recovery_deadline;
		if (!stopping) {
			deadline = clock_ticks() + kern_ms_to_ticks(GHCI_POLL_MS);
			sequence = waitq_sequence(&device->ring_wake);
			(void)waitq_sleep(&device->ring_wake, &device->irq_lock, sequence, deadline, 0U);
		}

		spin_unlock_irqrestore(&device->irq_lock, irq);

		/* The recovery takes the ring from here. */
		if (stopping)
			return EAGAIN;
	}

	/* The rest of the ring is padded with NOPs when the run does not fit before its end. */
	while (padding != 0U) {
		written = padding;
		if (written > GHCI_PACKET_DWORDS_MAX)
			written = GHCI_PACKET_DWORDS_MAX;
		ring_store(device, device->ring.wptr, ghci_cmd_header(GHCI_OP_NOP, written, 0U));
		for (index = 1U; index < written; index++)
			ring_store(device, device->ring.wptr + index, 0U);
		device->ring.wptr = (device->ring.wptr + written) % device->ring.dwords;
		padding -= written;
	}

	/* Succeeded: the run fits at the write index. */
	return 0;
}

/* Stores one dword of the ring, little-endian as the GPU reads it. */
static void
ring_store(
	struct ghci_device *device,
	uint32_t index,
	uint32_t word)
{
	volatile uint32_t *ring;

	/* The processor's view of the ring; the platforms the driver runs on are little-endian. */
	ring = (volatile uint32_t *)(void *)device->ring.memory->view;
	ring[index] = word;
}

/* Drops the submissions whose fences the driver has accepted from the log.  The caller holds cp_lock. */
static void
retire_log(
	struct ghci_device *device)
{
	unsigned long irq;
	uint64_t completed;
	int passed;

	/* The fence the driver has accepted. */
	irq = spin_lock_irqsave(&device->irq_lock);

	completed = device->completed;

	spin_unlock_irqrestore(&device->irq_lock, irq);

	/* The oldest entries first, while their fences have passed. */
	while (device->submit_count != 0U) {
		passed = ghci_fence64_passed(completed, device->submit_log[device->submit_first].seq);
		if (!passed)
			break;
		device->submit_first = (device->submit_first + 1U) % GHCI_SUBMIT_LOG;
		device->submit_count--;
	}
}

/*
 * Reads the length of the packet at the head of a run of packets.
 * Returns 0, or EINVAL for a header of no dwords or past the run.
 */
static int
packet_length(
	const uint32_t *packets,
	uint32_t left,
	uint32_t *length)
{
	uint32_t dwords;

	/* The dwords field of the header. */
	dwords = (packets[0] >> GHCI_HEADER_DWORDS_SHIFT) & GHCI_HEADER_DWORDS_MASK;
	if (dwords == 0U || dwords > left)
		return EINVAL;

	/* Succeeded: the packet's length. */
	*length = dwords;
	return 0;
}

/*
 * Reports the state of a ticket.  The caller holds irq_lock.
 */
static enum ghci_ticket_state
ticket_state(
	struct ghci_device *device,
	const struct ghci_ticket *ticket)
{
	struct ghci_reset_record *record;
	unsigned index;
	int passed;

	/* A ticket of this generation is done once the accepted fence reaches it. */
	if (ticket->generation == device->generation) {
		passed = ghci_fence64_passed(device->completed, ticket->seq);
		if (passed)
			return GHCI_TICKET_DONE;
		return GHCI_TICKET_PENDING;
	}

	/* A ticket of no generation the driver placed in failed. */
	if (ticket->generation > device->generation)
		return GHCI_TICKET_FAILED;

	/* An older ticket passed if the fence had reached it when the reset ended its generation, unless a culprit's. */
	record = &device->history[ticket->generation % GHCI_RESET_HISTORY];
	passed = ghci_fence64_passed(record->completed, ticket->seq);
	for (index = 0U; index < record->failed_count && passed; index++) {
		if (record->failed[index] == ticket->seq)
			passed = 0;
	}
	if (record->generation == ticket->generation && passed)
		return GHCI_TICKET_DONE;

	/* Succeeded: the reset ended it first (or it is older than the history). */
	return GHCI_TICKET_FAILED;
}

/*
 * Records a fault or a watchdog expiry for the service thread and closes
 * the gate.  The registers are read before the interrupt's lock; the
 * record carries the recovery generation the interrupt saw it in, so that
 * a recovery that ended meanwhile has it dropped.
 */
static void
record_fault(
	struct ghci_device *device,
	uint32_t irq_status,
	uint64_t generation)
{
	struct ghci_fault_record record;
	unsigned long irq;
	uint32_t high;

	/* What the device latched, and where its processor is. */
	kern_memset(&record, 0, sizeof(record));
	record.irq_status = irq_status;
	record.status = ghci_read(device, GHCI_REG_STATUS);
	record.fault_info = ghci_read(device, GHCI_REG_FAULT_INFO);
	record.fault_address = ghci_read(device, GHCI_REG_FAULT_ADDR_LO);
	high = ghci_read(device, GHCI_REG_FAULT_ADDR_HI);
	record.fault_address |= (uint64_t)high << 32;
	record.session_active = ghci_read(device, GHCI_REG_SESSION_ACTIVE);
	record.rptr = ghci_read(device, GHCI_REG_RING_RPTR);
	record.cp_pc = ghci_read(device, GHCI_REG_DIAG_CP_PC);
	record.cp_status = ghci_read(device, GHCI_REG_DIAG_CP_STATUS);
	record.fence = ghci_fence_read(device);

	/*
	 * Closes the gate, counts the fault (the recovery's last check sees a
	 * new one), keeps the record in this recovery generation, and asks
	 * the service thread to recover.
	 */
	irq = spin_lock_irqsave(&device->irq_lock);

	device->recovering = 1;
	device->fault_count++;
	record.generation = generation;
	if (device->fault_records < GHCI_FAULT_RECORDS) {
		device->faults[device->fault_records] = record;
		device->fault_records++;
	} else {
		device->faults_dropped++;
	}
	device->service_work |= GHCI_WORK_RECOVER;

	spin_unlock_irqrestore(&device->irq_lock, irq);
}

/*
 * Takes a fence interrupt: reads the fence page, then reads FAULT and
 * WATCHDOG again, so that a fence written after a fault latched is never
 * taken as the work's completion; the completed fence moves only while
 * no recovery runs.
 */
static void
take_fence(
	struct ghci_device *device,
	uint32_t irq_status,
	uint64_t generation)
{
	unsigned long irq;
	uint64_t word;
	uint32_t late;
	int newer;

	/* The fence the device wrote, then any fault that latched since IRQ_STATUS was read. */
	word = ghci_fence_read(device);
	late = ghci_read(device, GHCI_REG_IRQ_STATUS);
	late &= IRQ_RECOVER;
	if ((irq_status & IRQ_RECOVER) != 0U)
		late = 0U;
	if (late != 0U) {
		ghci_write(device, GHCI_REG_IRQ_STATUS, late);
		record_fault(device, late, generation);
	}

	/* Moves the completed fence on, unless a recovery runs or the device is lost. */
	irq = spin_lock_irqsave(&device->irq_lock);

	device->fence_interrupts++;
	newer = ghci_fence64_passed(word, device->completed);
	if (!device->recovering && device->state != GHCI_STATE_LOST && newer) {
		device->completed = word;
		device->service_work |= GHCI_WORK_RECLAIM;
	}

	spin_unlock_irqrestore(&device->irq_lock, irq);
}

/* Logs the registers that say where the processor stopped. */
static void
log_registers(
	struct ghci_device *device,
	const char *what)
{
	uint32_t status;
	uint32_t fault_info;
	uint32_t cp_pc;
	uint32_t cp_status;
	uint32_t rptr;

	/* The state, the fault, and the processor's place. */
	status = ghci_read(device, GHCI_REG_STATUS);
	fault_info = ghci_read(device, GHCI_REG_FAULT_INFO);
	cp_pc = ghci_read(device, GHCI_REG_DIAG_CP_PC);
	cp_status = ghci_read(device, GHCI_REG_DIAG_CP_STATUS);
	rptr = ghci_read(device, GHCI_REG_RING_RPTR);
	kern_logf("ghci: %s: %s (status %08x, fault %08x, cp pc %08x status %08x, rptr %u)\n",
	    device->name,
	    what,
	    (unsigned)status,
	    (unsigned)fault_info,
	    (unsigned)cp_pc,
	    (unsigned)cp_status,
	    (unsigned)rptr);
}
