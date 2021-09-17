/*
  Copyright 2018 ZeroEx Intl.
  Licensed under the Apache License, Version 2.0 (the "License");
  you may not use this file except in compliance with the License.
  You may obtain a copy of the License at
    http://www.apache.org/licenses/LICENSE-2.0
  Unless required by applicable law or agreed to in writing, software
  distributed under the License is distributed on an "AS IS" BASIS,
  WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
  See the License for the specific language governing permissions and
  limitations under the License.
*/

// Copied from https://gist.github.com/Recmo/04c55bacfb5e4b4420f4ad0f0df96bed

pragma solidity ^0.8.0;

library FullMath {
    function mulDiv(uint256 numerator, uint256 denominator, uint256 target) internal pure returns (uint256 partialAmount) {
        // 512-bit multiply [prod1 prod0] = target * numerator
        // Compute the product mod 2**256 and mod 2**256 - 1
        // then use the Chinese Remiander Theorem to reconstruct
        // the 512 bit result. The result is stored in two 256
        // variables such that product = prod1 * 2**256 + prod0
        uint256 prod0; // Least significant 256 bits of the product
        uint256 prod1; // Most siginificant 256 bits of the product
        assembly {
            let mm := mulmod(target, numerator, not(0))
            prod0 := mul(target, numerator)
            prod1 := sub(sub(mm, prod0), lt(mm, prod0))
        }

        // Handle non-overflow cases, 256 by 256 division
        if (prod1 == 0) {
            assembly {
                // If denominator is zero then by the precodition
                // numerator is also zero and therefore prod is
                // zero. We get div(_, 0), which evaluates to 0.
                partialAmount := div(prod0, denominator)
            }
            return partialAmount;
        }

        // Make sure the result is less than 2**256.
        // Also prevents denominator == 0
        require(denominator > prod1);

        ///////////////////////////////////////////////
        // 512 by 256 division.
        ///////////////////////////////////////////////

        assembly {

            // The strategy is to make the division exact, and then compute it
            // in the finite field module 2^256. Since the answer is less than
            // 2^256, we know that the answer in the finite field is also the
            // real answer.
            // We compute the division in the finite field by first computing
            // the inverse of the denominator. Then we multiply with the
            // inverse.
            // The finite field does not have inverses for even numbers. To work
            // around this we first compute the largest power of two in the
            // divisor, and then bitshift these out.

            // Make division exact by subtracting the remainder from [prod1 prod0]
            // Compute remainder using mulmod
            // mulmod(_, _, 0) == 0
            let remainder := mulmod(target, numerator, denominator)

            // Subtract 256 bit number from 512 bit number
            prod1 := sub(prod1, gt(remainder, prod0))
            prod0 := sub(prod0, remainder)

            // Compute largest power of two divisor of denominator.
            // Always >= 1 unless denominator is zero, then twos is zero.
            //
            //    twos  = 2^n  where  denominator = m * 2^n for some odd m
            //
            // It works by observing that in twos-complement negation, all
            // bits change from most significant up to (but not including) the
            // least significant set bit change. If we 'and' the original value
            // withthe negated value only the least significant set bit remains.
            let twos := and(sub(0, denominator), denominator)

            // Factor powers of two out of denominator
            // Divide denominator by power of two. The result is always odd.
            denominator := div(denominator, twos)

            // Note: because we made the division exact, this also means
            // [prod1 prod0] can be divided by `twos`. There is no guarantee
            // that the result will be odd.

            // Divide [prod1 prod0] by the factors of two. This shifts out all
            // least-significant zeros (and creates most-signifacnt zeros).
            prod0 := div(prod0, twos)

            // Flip twos such that instead of 2^n it is 2^(256 - n).
            // This is the same as computing 2^256 / twos. We can compute
            // this division as (0 - twos) / twos + 1.
            twos := add(div(sub(0, twos), twos), 1)

            // We shift prod1 left by 2^(256 - n) and 'or' it into the cleared
            // high bits of prod0.
            // We don't shift prod1 because it's value is no longer needed.
            prod0 := or(prod0, mul(prod1, twos))

            // Invert denominator mod 2**256.
            // Now that denominator is an odd number, it has an inverse
            // modulo 2**256 such that denominator * inv = 1 mod 2^256.
            //
            // Compute the inverse by starting with a seed that is correct
            // for four bits. That is, denominator * inv = 1 mod 2^4
            // If denominator is zero the inverse starts with 2
            //    3 * denominator^2 =  denominator^(-1)   mod 2^4
            //    3 * denominator^3 = 1    mod 2^4
            let inv := mul(3, mul(denominator, denominator))
            // Now use Newton-Raphson itteration to improve the precision.
            // We want to find the root of the equation:
            //
            //         f(x) = x - 1 / d   (where d = denominator)
            //
            // Newton-Rhapson itteration then is
            //
            //               f(x)            d - 1 / x
            //    x' = x -  -------   = x - ----------- = x * (2 - d * x)
            //               f'(x)            1 / x^2
            //
            // Thanks to Hensel's lifting lemma, this also works in modular
            // arithmetic. Each itteration will double the number of correct
            // bits. Counter-intuitively, this works from least significant bits
            // upwards.
            inv := mul(inv, sub(2, mul(denominator, inv))) // inverse mod 2^8
            inv := mul(inv, sub(2, mul(denominator, inv))) // inverse mod 2^16
            inv := mul(inv, sub(2, mul(denominator, inv))) // inverse mod 2^32
            inv := mul(inv, sub(2, mul(denominator, inv))) // inverse mod 2^64
            inv := mul(inv, sub(2, mul(denominator, inv))) // inverse mod 2^128
            inv := mul(inv, sub(2, mul(denominator, inv))) // inverse mod 2^256
            // If denominator is zero, inv is now 128

            // Because the division is now exact we can divide by multiplying
            // with the modular inverse of denominator. This will give us the
            // correct result modulo 2^256. Since the precoditions guarantee
            // that the outcome is less than 2^256, this is the final result.
            // We don't need to compute the high bits of the result since we
            // want the result modulo 2^256.
            // If denominator is zero, prod0 is zero and the result is zero.
            partialAmount := mul(prod0, inv)
        }

        return partialAmount;
    }
}