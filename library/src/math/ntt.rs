pub mod ntt {
    use std::iter;

    use crate::num_mod::{ModOp, PowBy};

    fn bit_reversal_perm<T>(xs: &mut [T]) {
        let n = xs.len();
        let n_log2 = u32::BITS - (n as u32).leading_zeros() - 1;

        for i in 0..n as u32 {
            let rev = i.reverse_bits() >> (u32::BITS - n_log2);
            if i < rev {
                xs.swap(i as usize, rev as usize);
            }
        }
    }

    pub fn radix4<T, M>(op: &M, proot: T, xs: &mut [T])
    where
        T: Copy,
        M: ModOp<T> + PowBy<T, u32>,
    {
        let n = xs.len();
        assert!(n.is_power_of_two());
        let n_log2 = u32::BITS - (n as u32).leading_zeros() - 1;
        bit_reversal_perm(xs);

        let base: Vec<_> = (0..n_log2)
            .scan(proot, |acc, _| {
                let prev = *acc;
                *acc = op.mul(*acc, *acc);
                Some(prev)
            })
            .collect();

        let mut proot_pow = vec![op.zero(); n]; // Cache-friendly twiddle factors
        proot_pow[0] = op.one();

        let quartic_root = op.pow(proot, n as u32 / 4);

        let update_proot_pow = |proot_pow: &mut [T], k: u32| {
            let step = 1 << k;
            let base = base[(n_log2 - k - 1) as usize];
            for i in (0..step).rev() {
                proot_pow[i * 2 + 1] = op.mul(proot_pow[i], base);
                proot_pow[i * 2] = proot_pow[i];
            }
        };

        let mut k = 0;
        if n_log2 % 2 == 1 {
            let step = 1 << k;
            // radix-2 butterfly
            update_proot_pow(&mut proot_pow, k);
            for t in xs.chunks_exact_mut(step * 2) {
                let (t0, t1) = t.split_at_mut(step);
                for (a0, a1) in t0.into_iter().zip(t1) {
                    let b0 = *a0;
                    let b1 = *a1;
                    *a0 = op.add(b0, b1);
                    *a1 = op.sub(b0, b1);
                }
            }
            k += 1;
        }
        while k < n_log2 {
            let step = 1 << k;
            // radix-4 butterfly
            update_proot_pow(&mut proot_pow, k);
            update_proot_pow(&mut proot_pow, k + 1);

            for t in xs.chunks_exact_mut(step * 4) {
                let (t0, rest) = t.split_at_mut(step);
                let (t1, rest) = rest.split_at_mut(step);
                let (t2, t3) = rest.split_at_mut(step);

                for ((((a0, a1), a2), a3), &pow1) in
                    t0.into_iter().zip(t1).zip(t2).zip(t3).zip(&proot_pow)
                {
                    let pow2 = op.mul(pow1, pow1);
                    let pow1_shift = op.mul(pow1, quartic_root);

                    let b0 = *a0;
                    let b1 = op.mul(*a1, pow2);
                    let b2 = *a2;
                    let b3 = op.mul(*a3, pow2);

                    let c0 = op.add(b0, b1);
                    let c1 = op.sub(b0, b1);
                    let c2 = op.mul(op.add(b2, b3), pow1);
                    let c3 = op.mul(op.sub(b2, b3), pow1_shift);

                    *a0 = op.add(c0, c2);
                    *a1 = op.add(c1, c3);
                    *a2 = op.sub(c0, c2);
                    *a3 = op.sub(c1, c3);
                }
            }
            k += 2;
        }
    }

    // naive O(n^2)
    pub fn naive<T, M>(op: &M, proot: T, xs: &mut [T])
    where
        T: Copy,
        M: ModOp<T> + PowBy<T, u32>,
    {
        let n = xs.len().next_power_of_two();
        let proot_pow: Vec<T> = iter::successors(Some(op.one()), |&acc| Some(op.mul(acc, proot)))
            .take(n)
            .collect();
        let res: Vec<_> = (0..n)
            .map(|i| {
                (0..n)
                    .map(|j| op.mul(xs[j], proot_pow[(i * j) % n]))
                    .fold(op.zero(), |acc, x| op.add(acc, x))
            })
            .collect();
        xs.copy_from_slice(&res);
    }
}
