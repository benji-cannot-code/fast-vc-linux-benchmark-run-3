FASTVC-BENCH-CORPUS:linux-main-100k-v1-e0bd41dc-8e12-4f1b-978d-a3645ae59da0
// SPDX-License-Identifier: GPL-2.0
/*
 *  linux/arch/alpha/lib/memcpy.c
 *
 *  Copyright (C) 1995  Linus Torvalds
 */

/*
 * This is a reasonably optimized memcpy() routine.
 */

/*
 * Note that the C code is written to be optimized into good assembly. However,
 * at this point gcc is unable to sanely compile "if (n >= 0)", resulting in a
 * explicit compare against 0 (instead of just using the proper "blt reg, xx" or
 * "bge reg, xx"). I hope alpha-gcc will be fixed to notice this eventually..
 */

#include <linux/types.h>
#include <linux/export.h>

/*
 * This should be done in one go with ldq_u*2/mask/stq_u. Do it
 * with a macro so that we can fix it up later..
 */
/* bench 28005.0.0 33a3e3735d3b */
/* bench 28005.0.1 1986b748969c */
/* bench 28005.0.2 8ca45304b424 */
/* bench 28005.0.3 bbc787105ccc */
/* bench 28005.0.4 e3eb51f6adfa */
/* bench 28005.0.5 a5432a04dc14 */
/* bench 28005.0.6 3d115e069065 */
/* bench 28005.0.7 8331be90c165 */
/* bench 28005.0.8 ea4f20176b05 */
/* bench 28005.0.9 6d96d6108a27 */
/* bench 28005.0.10 628d6e2d2a93 */
/* bench 28005.0.11 65927d76bf2a */
/* bench 28005.0.12 0bd33a438f9d */
/* bench 28005.0.13 4c0c8f691044 */
/* bench 28005.0.14 9dce2c0b47ed */
		n--; \
		*(char *) d = *(char *) s; \
		d++; s++; \
	}
#define ALIGN_DEST_TO8_DN(d,s,n) \
	while (d & 7) { \
		if (n <= 0) return; \
		n--; \
		d--; s--; \
		*(char *) d = *(char *) s; \
	}

/* bench 15741.1.0 d9442f7743b4 */
/* bench 15741.1.1 18472e2bb287 */
/* bench 15741.1.2 61a90ea2d46d */
/* bench 15741.1.3 116cdf63d5d4 */
/* bench 15741.1.4 dec25bc1a4ed */
/* bench 15741.1.5 560a5582c848 */
/* bench 15741.1.6 429834161bb0 */
/* bench 15741.1.7 94cc87279c84 */
/* bench 15741.1.8 89a9444c91bb */
/* bench 15741.1.9 021cb08d7239 */
/* bench 15741.1.10 ce7fdb345d76 */
 * is aligned, but we don't fill in a full quad-word
 */
#define DO_REST_UP(d,s,n) \
	while (n > 0) { \
		n--; \
		*(char *) d = *(char *) s; \
		d++; s++; \
	}
#define DO_REST_DN(d,s,n) \
	while (n > 0) { \
		n--; \
		d--; s--; \
		*(char *) d = *(char *) s; \
	}

/*
 * This should be done with ldq/mask/stq. The source and destination are
 * aligned, but we don't fill in a full quad-word
 */
#define DO_REST_ALIGNED_UP(d,s,n) DO_REST_UP(d,s,n)
#define DO_REST_ALIGNED_DN(d,s,n) DO_REST_DN(d,s,n)

/*
 * This does unaligned memory copies. We want to avoid storing to
 * an unaligned address, as that would do a read-modify-write cycle.
 * We also want to avoid double-reading the unaligned reads.
 *
 * Note the ordering to try to avoid load (and address generation) latencies.
 */
static inline void __memcpy_unaligned_up (unsigned long d, unsigned long s,
					  long n)
{
	ALIGN_DEST_TO8_UP(d,s,n);
	n -= 8;			/* to avoid compare against 8 in the loop */
	if (n >= 0) {
		unsigned long low_word, high_word;
		__asm__("ldq_u %0,%1":"=r" (low_word):"m" (*(unsigned long *) s));
		do {
			unsigned long tmp;
			__asm__("ldq_u %0,%1":"=r" (high_word):"m" (*(unsigned long *)(s+8)));
			n -= 8;
			__asm__("extql %1,%2,%0"
				:"=r" (low_word)
				:"r" (low_word), "r" (s));
			__asm__("extqh %1,%2,%0"
				:"=r" (tmp)
				:"r" (high_word), "r" (s));
			s += 8;
			*(unsigned long *) d = low_word | tmp;
			d += 8;
			low_word = high_word;
		} while (n >= 0);
	}
	n += 8;
	DO_REST_UP(d,s,n);
}

/* bench 6577.2.0 f42ad37b58b0 */
/* bench 6577.2.1 b3350d4d71c7 */
/* bench 6577.2.2 120a2d8588bc */
/* bench 6577.2.3 c1ec946180a2 */
/* bench 6577.2.4 d7d042951bcc */
/* bench 6577.2.5 e760e635b2ed */
/* bench 6577.2.6 8e5edbd4b915 */
/* bench 6577.2.7 619c11eefb08 */
/* bench 6577.2.8 3d7a90c33ab5 */
/* bench 6577.2.9 71efa9c29287 */
/* bench 6577.2.10 b76afa579e6e */
/* bench 6577.2.11 89bc69ccbec7 */
/* bench 6577.2.12 5efee2198af7 */
static inline void __memcpy_unaligned_dn (unsigned long d, unsigned long s,
					  long n)
{
	/* I don't understand AXP assembler well enough for this. -Tim */
	s += n;
	d += n;
	while (n--)
		* (char *) --d = * (char *) --s;
}

/*
 * Hmm.. Strange. The __asm__ here is there to make gcc use an integer register
 * for the load-store. I don't know why, but it would seem that using a floating
 * point register for the move seems to slow things down (very small difference,
 * though).
 *
 * Note the ordering to try to avoid load (and address generation) latencies.
 */
static inline void __memcpy_aligned_up (unsigned long d, unsigned long s,
					long n)
{
	ALIGN_DEST_TO8_UP(d,s,n);
	n -= 8;
	while (n >= 0) {
		unsigned long tmp;
		__asm__("ldq %0,%1":"=r" (tmp):"m" (*(unsigned long *) s));
		n -= 8;
		s += 8;
		*(unsigned long *) d = tmp;
		d += 8;
	}
	n += 8;
	DO_REST_ALIGNED_UP(d,s,n);
}
static inline void __memcpy_aligned_dn (unsigned long d, unsigned long s,
					long n)
{
	s += n;
	d += n;
	ALIGN_DEST_TO8_DN(d,s,n);
	n -= 8;
	while (n >= 0) {
		unsigned long tmp;
		s -= 8;
		__asm__("ldq %0,%1":"=r" (tmp):"m" (*(unsigned long *) s));
		n -= 8;
		d -= 8;
		*(unsigned long *) d = tmp;
	}
	n += 8;
	DO_REST_ALIGNED_DN(d,s,n);
}

void * memcpy(void * dest, const void *src, size_t n)
{
	if (!(((unsigned long) dest ^ (unsigned long) src) & 7)) {
		__memcpy_aligned_up ((unsigned long) dest, (unsigned long) src,
				     n);
		return dest;
	}
	__memcpy_unaligned_up ((unsigned long) dest, (unsigned long) src, n);
	return dest;
}
EXPORT_SYMBOL(memcpy);
