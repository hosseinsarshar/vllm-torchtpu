# Copyright 2025 Google LLC
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
"""Binary search over float32 bits.

Includes fast algorithms for top-k masking and top-p masking on probability
distributions.
"""

from collections.abc import Callable, Sequence

import torch

MASKED_LOGIT_VALUE = -1e12
# 128 matches the native TPU (8, 128) vector tile / 128-element lane width
# and evenly divides standard padded vocabs (e.g. 248,320 = 1,940 * 128;
# 152,064 = 1,188 * 128; 128,256 = 1,002 * 128), ensuring per-block amax
# and gathers run without tail padding. At 64 blocks, candidate bisection
# evaluates 8,192 logits instead of 248,320.
CANDIDATE_BLOCK = 128
# Candidates per row that the top-k prefilter (ENABLE_TOPK_PREFILTER) keeps.
# Exact for 1 <= top_k <= TOPK_PREFILTER_CANDIDATES // 2: the spare half keeps
# logits that tie with the k-th largest, which the full-vocab bisection keeps.
TOPK_PREFILTER_CANDIDATES = 64
# Largest chunk size the top-k prefilter tries.
_MAX_PREFILTER_CHUNK = 256
# float32 sublanes in a TPU (8, 128) tile. Chunk sizes that are multiples of
# it fill whole tiles, so the prefilter tries them first.
_PREFILTER_CHUNK_ALIGN = 8
# From this many rows, `prefiltered_top_k` reads contiguous chunks when the
# chunk size is a multiple of _CONTIGUOUS_PREFILTER_CHUNK_MULTIPLE.
_CONTIGUOUS_PREFILTER_MIN_ROWS = 128
_CONTIGUOUS_PREFILTER_CHUNK_MULTIPLE = 64


def _int32_bsearch(
    batch_shape: Sequence[int],
    predicate: Callable[[torch.Tensor], torch.Tensor],
    device: torch.device,
) -> torch.Tensor:
    """Batched binary search over int32 values.

    For each element of the batch, search for the largest int32 (closest to
    positive infinity) for which the predicate is False. If the predicate is
    always True, returns the minimum int32 value.

    Args:
      batch_shape: Shape of the search that we're batching over.
      predicate: the query we're searching for. For every batch element, this is
        required to be a monotonic function from int32 to bool. In other words,
        the predicate must return False for all numbers <= some threshold and
        then return True for all numbers > that threshold. The threshold may be
        different for different elements of the batch.
      device: device to allocate the search state on.

    Returns:
      For each element of the batch, the largest int32 for which the predicate
      returns False. Shape: batch_shape.
    """
    current_bits = torch.zeros(batch_shape, dtype=torch.int32, device=device)
    zero = torch.zeros_like(current_bits)
    sign_bit = torch.full_like(current_bits, -(1 << 31))

    # bit 31 is special, because it compares in the opposite order of all other
    # bits.
    current_bits = current_bits | torch.where(predicate(current_bits), sign_bit, zero)

    for i in range(31):
        bit = 1 << (30 - i)
        bit_t = torch.full_like(current_bits, bit)
        midpoint = current_bits | bit
        current_bits = current_bits | torch.where(predicate(midpoint), zero, bit_t)
    return current_bits


def _monotonic_int32_to_float32_bit_pattern(x: torch.Tensor) -> torch.Tensor:
    """Converts an int32 to a float32 bit pattern with consistent ordering.

    This function is the unique function that is monotonic with respect to the
    floating point total order, see
    https://en.wikipedia.org/wiki/IEEE_754#Total-ordering_predicate. Note that
    this function returns an int32, not a float32. For the function that returns
    float32, see `_monotonic_int32_to_float32`.

    Args:
      x: int32.

    Returns:
      int32 bit pattern of a float32 number.
    """
    non_sign_bits = torch.full_like(x, (1 << 31) - 1)
    zero = torch.zeros_like(x)
    # See
    # https://stackoverflow.com/questions/20097380/iee-754-total-order-in-standard-c11
    # for the relationship between int32 order and f32 total order, including
    # the "xor trick".

    # Flip the sort order for numbers where the sign bit is set. On int32,
    # the bit pattern with sign bit set and all other bits clear is the most
    # negative bit pattern (it's int32::MIN), whereas on float32 it's the least
    # negative bit pattern (it's -0.0). Flipping all the non-sign bits makes the
    # int32 sort order consistent with the float32 sort order.
    return x ^ torch.where(x < 0, non_sign_bits, zero)


def _monotonic_int32_to_float32(x: torch.Tensor) -> torch.Tensor:
    """Converts an int32 to a float32 with consistent ordering.

    This function is the unique function that is monotonic with respect to the
    floating point total order, see
    https://en.wikipedia.org/wiki/IEEE_754#Total-ordering_predicate.

    Args:
      x: int32.

    Returns:
      float32 number with consistent ordering.
    """
    return _monotonic_int32_to_float32_bit_pattern(x).view(torch.float32)


def _float32_bsearch(
    batch_shape: Sequence[int],
    predicate: Callable[[torch.Tensor], torch.Tensor],
    device: torch.device,
) -> torch.Tensor:
    """Binary search on finite float32 numbers.

    For each element of the batch, this function searches for the largest finite
    non-NaN float32 for which the predicate is False.

    Args:
      batch_shape: Shape of the search that we're batching over.
      predicate: the query we're searching for. This is required to be monotonic
        with respect to the floating point order, i.e. it must be False for all
        numbers <= a threshold, and then True for all numbers > the threshold.
        The threshold may be different for different elements of the batch.
      device: device to allocate the search state on.

    Returns:
      For each element of the batch, the largest float32 for which the predicate
      returns False. Shape: f32[batch_shape].
    """

    def int32_predicate(x: torch.Tensor) -> torch.Tensor:
        exponent_bits = torch.full_like(x, (1 << 31) - (1 << 23))
        x = _monotonic_int32_to_float32_bit_pattern(x)
        is_finite = (x & exponent_bits) != exponent_bits

        # Non-finite numbers (infinity and NaN) are at the very extremes of the
        # int32 range, i.e. they include int32::MAX and int32::MIN, plus the
        # numbers adjacent to them. For the nonfinite numbers touching
        # int32::MIN, we arrange for them to return False from the predicate,
        # and for the nonfinite numbers touching int32::MAX, we arrange for them
        # to return True from the predicate. x>=0 is an easy way to achieve
        # that.
        predicate_on_nonfinite = x >= 0
        return torch.where(
            is_finite, predicate(x.view(torch.float32)), predicate_on_nonfinite
        )

    # We search over bit patterns, which requires bit shifting and ordering of
    # bit patterns. This is natively supported on int32 but not on float32.
    result = _int32_bsearch(batch_shape, int32_predicate, device)
    return _monotonic_int32_to_float32(result)


def topk_mask(
    logits: torch.Tensor, k: torch.Tensor, replace_val: float = MASKED_LOGIT_VALUE
) -> torch.Tensor:
    """Sets everything to replace_val, except the top k values per batch element.

    Sharding considerations: this function does 32 reductions over the
    vocab_size axis of the input array. To avoid excessive latency from these
    reductions, you should ensure that the vocab_size axis is unsharded on input
    to this function. Prefer to shard the batch axes instead.

    Scratchpad memory considerations: this function is most efficient if the
    entire input array can fit in a fast memory tier. To help ensure this, you
    may wish to split the batch axes into microbatches and the microbatches in a
    sequential loop.

    Args:
      logits: Values before masking. [batch..., vocab_size]
      k: Number of values to keep per batch element. In presence of ties, more
        than k values might be returned. [batch..., 1]
      replace_val: For the masked values of logits, what to overwrite them with.

    Returns:
      masked version of logits. [batch..., vocab_size]
    """
    k = k.squeeze(-1)

    def predicate(threshold: torch.Tensor) -> torch.Tensor:
        # Search negated logits so the predicate is monotonic increasing.
        neg_threshold = (-threshold).unsqueeze(-1)
        count_gt = torch.sum((logits > neg_threshold).to(torch.int32), dim=-1)
        return count_gt >= k

    cutoff = -_float32_bsearch(logits.shape[:-1], predicate, logits.device)
    cutoff = cutoff.unsqueeze(-1)
    replace_tensor = torch.full_like(logits, replace_val)
    return torch.where(logits >= cutoff, logits, replace_tensor)


def topp_mask(
    logits: torch.Tensor, p: torch.Tensor, replace_val: float = MASKED_LOGIT_VALUE
) -> torch.Tensor:
    """Applies top-p masking to logits.

    Masks logits down to the smallest set of choices, such that the total
    probability mass is >= p. Values in this set are left as they are. All other
    values are set with `replace_val`.

    Sharding considerations: this function does 33 reductions over the
    vocab_size axis of the input array. To avoid excessive latency from these
    reductions, you should ensure that the vocab_size axis is unsharded on input
    to this function. Prefer to shard the batch axes instead.

    Scratchpad memory considerations: this function is most efficient if the
    entire input array can fit in a fast memory tier. To help ensure this, you
    may wish to split the batch axes into microbatches and the microbatches in a
    sequential loop.

    Args:
      logits: Logits before masking. [batch..., vocab_size]
      p: Minimum probability mass requested. [batch..., 1]
      replace_val: For the masked values of logits, what to overwrite them with.

    Returns:
      masked version of logits. [batch..., vocab_size]
    """
    p = p.squeeze(-1)
    probs = torch.softmax(logits, dim=-1)
    zero_val = torch.zeros_like(probs)
    replace_tensor = torch.full_like(logits, replace_val)

    def predicate(threshold: torch.Tensor) -> torch.Tensor:
        threshold = threshold.unsqueeze(-1)
        probability_mass = torch.sum(
            torch.where(probs >= threshold, probs, zero_val),
            dim=-1,
        )
        return probability_mass < p

    threshold = _float32_bsearch(logits.shape[:-1], predicate, logits.device)
    threshold = threshold.unsqueeze(-1)
    return torch.where(probs >= threshold, logits, replace_tensor)


def apply_top_k_top_p(
    logits: torch.Tensor,
    top_k: torch.Tensor,
    top_p: torch.Tensor,
    topk_candidates: int = 0,
    topk_prefilter: bool = False,
) -> torch.Tensor:
    if topk_prefilter:
        return apply_top_k_top_p_prefilter(logits, top_k, top_p)
    if topk_candidates > 0:
        return apply_top_k_top_p_candidates(logits, top_k, top_p, topk_candidates)
    should_apply_topk = (top_k > 0).expand(-1, logits.shape[-1])
    topk_masked = topk_mask(logits, top_k, MASKED_LOGIT_VALUE)
    masked_logits = torch.where(should_apply_topk, topk_masked, logits)

    should_apply_topp = (top_p < 1.0).expand(-1, masked_logits.shape[-1])
    topp_masked = topp_mask(masked_logits, top_p, MASKED_LOGIT_VALUE)
    return torch.where(should_apply_topp, topp_masked, masked_logits)


def apply_top_k_top_p_candidates(
    logits: torch.Tensor,
    top_k: torch.Tensor,
    top_p: torch.Tensor,
    num_blocks: int,
) -> torch.Tensor:
    """Applies top-k then top-p using only the blocks with the largest maxima.

    Splits the vocab into blocks of CANDIDATE_BLOCK logits, runs
    `apply_top_k_top_p` on the `num_blocks` blocks with the largest maxima,
    and masks the full row below the smallest kept logit. Matches
    `apply_top_k_top_p` unless more than `num_blocks - k + 1` logits tie at
    the k-th largest value; float32 sums run in a different order, so a top-p
    boundary within rounding can flip. Caller must ensure active rows have
    1 <= top_k <= num_blocks // 2; rows with top_k <= 0 (padded slots) are
    returned unmasked.

    Args:
      logits: [batch, vocab_size], vocab_size a multiple of CANDIDATE_BLOCK.
      top_k: [batch, 1] integer.
      top_p: [batch, 1] float.
      num_blocks: Candidate blocks, at most vocab_size // CANDIDATE_BLOCK.

    Returns:
      Masked logits. [batch, vocab_size]
    """
    if (
        not torch.compiler.is_compiling()
        and top_p is not None
        and bool(((top_k <= 0) & (top_p < 1.0)).any())
    ):
        raise ValueError(
            "apply_top_k_top_p_candidates needs top_k >= 1 on every row; "
            "rows with top_k <= 0 would skip top_p. Use apply_top_k_top_p."
        )
    rows, vocab_size = logits.shape
    blocks = logits.reshape(rows, vocab_size // CANDIDATE_BLOCK, CANDIDATE_BLOCK)
    block_max = blocks.amax(dim=-1)
    block_ids = torch.topk(block_max, num_blocks, dim=-1, sorted=False).indices
    candidates = torch.gather(
        blocks, 1, block_ids.unsqueeze(-1).expand(-1, -1, CANDIDATE_BLOCK)
    ).reshape(rows, num_blocks * CANDIDATE_BLOCK)
    kept = apply_top_k_top_p(candidates, top_k, top_p) > MASKED_LOGIT_VALUE
    inf = torch.full_like(candidates, float("inf"))
    cutoff = torch.where(kept, candidates, inf).amin(dim=-1, keepdim=True)
    masked = torch.where(
        logits >= cutoff, logits, torch.full_like(logits, MASKED_LOGIT_VALUE)
    )
    return torch.where(top_k > 0, masked, logits)


def topk_prefilter_chunk(num_values: int, k: int) -> int:
    """Returns the chunk size that sorts the fewest values, or 0 to skip.

    `prefiltered_top_k` sorts num_values // chunk chunk maxima and then
    k * chunk candidates. Chunk sizes that are multiples of 8 fill whole
    float32 TPU tiles, so they are tried first. If none divides num_values,
    any divisor up to _MAX_PREFILTER_CHUNK is used (e.g. 56 for 202,048, or
    14 for 12,628). 0 means no chunk size sorts fewer values than a plain
    top-k over the whole row.
    """
    aligned = range(
        _PREFILTER_CHUNK_ALIGN, _MAX_PREFILTER_CHUNK + 1, _PREFILTER_CHUNK_ALIGN
    )
    for chunk_sizes in (aligned, range(2, _MAX_PREFILTER_CHUNK + 1)):
        best_chunk, best_cost = 0, num_values
        for chunk in chunk_sizes:
            if num_values % chunk or num_values // chunk < k:
                continue
            cost = num_values // chunk + k * chunk
            if cost < best_cost:
                best_chunk, best_cost = chunk, cost
        if best_chunk:
            return best_chunk
    return 0


def prefiltered_top_k(
    values: torch.Tensor, k: int, chunk: int | None = None
) -> tuple[torch.Tensor, torch.Tensor]:
    """Same values as `torch.topk(values, k)`, from a fraction of the row.

    Splits each row into chunks, keeps the k chunks with the largest maxima
    (they hold every top-k value) and runs the final top-k only over their
    k * chunk values. Values come back sorted in descending order, like
    `torch.topk`; indices of tied values may differ.

    Both chunk layouts give the same values. Chunk c usually holds values
    c, c + num_chunks, c + 2 * num_chunks, ..., so the chunk maxima are an
    elementwise max over the rows of a [chunk, num_chunks] view. With at
    least _CONTIGUOUS_PREFILTER_MIN_ROWS rows and a chunk size that is a
    multiple of _CONTIGUOUS_PREFILTER_CHUNK_MULTIPLE, chunk c holds the
    contiguous values c * chunk to (c + 1) * chunk - 1 instead: gathering
    whole chunks is cheaper at that batch size (for a 151,936 vocab at 128
    and 256 rows, about 2x faster than strided chunks on TPU v7x and 1.3x on
    v6e; below 128 rows strided chunks are as fast or faster).

    Args:
      values: [batch, num_values].
      k: Values to return per row. At most num_values.
      chunk: Chunk size. None picks it with `topk_prefilter_chunk`; 0 runs a
        plain `torch.topk`.

    Returns:
      (top_values, top_indices), each [batch, k].
    """
    batch, num_values = values.shape
    if chunk is None:
        chunk = topk_prefilter_chunk(num_values, k)
    if chunk == 0:
        return torch.topk(values, k, dim=-1, sorted=True)
    num_chunks = num_values // chunk
    if (
        batch >= _CONTIGUOUS_PREFILTER_MIN_ROWS
        and chunk % _CONTIGUOUS_PREFILTER_CHUNK_MULTIPLE == 0
    ):
        # chunks[b, c, r] = values[b, c * chunk + r]
        chunks = values.reshape(batch, num_chunks, chunk)
        chunk_ids = torch.topk(chunks.amax(dim=-1), k, dim=-1, sorted=False).indices
        candidates = torch.gather(
            chunks, 1, chunk_ids.unsqueeze(-1).expand(-1, -1, chunk)
        ).reshape(batch, k * chunk)
        top_values, positions = torch.topk(candidates, k, dim=-1, sorted=True)
        top_indices = (
            torch.gather(chunk_ids, 1, positions // chunk) * chunk + positions % chunk
        )
        return top_values, top_indices
    # chunks[b, r, c] = values[b, r * num_chunks + c]
    chunks = values.reshape(batch, chunk, num_chunks)
    chunk_ids = torch.topk(chunks.amax(dim=1), k, dim=-1, sorted=False).indices
    candidates = torch.gather(
        chunks, 2, chunk_ids.unsqueeze(1).expand(-1, chunk, -1)
    ).reshape(batch, chunk * k)
    top_values, positions = torch.topk(candidates, k, dim=-1, sorted=True)
    top_indices = (positions // k) * num_chunks + torch.gather(
        chunk_ids, 1, positions % k
    )
    return top_values, top_indices


def _sorted_top_k_top_p_cutoff(
    top_values: torch.Tensor, top_k: torch.Tensor, top_p: torch.Tensor
) -> torch.Tensor:
    """Per-row logit cutoff of top-k then top-p, from sorted candidates.

    Keeping the values >= the cutoff matches `topk_mask` followed by
    `topp_mask` on the full row, ties included, as long as the candidates
    hold every logit >= the k-th largest. Top-p runs one softmax and one
    cumulative sum over the candidates instead of a 31-step bisection.

    Args:
      top_values: Each row's largest logits in descending order.
        [batch, num_candidates]
      top_k: [batch, 1]. Values outside [1, num_candidates] are clamped.
      top_p: [batch, 1].

    Returns:
      [batch, 1] float32 cutoff.
    """
    # The candidates are few, so run the top-p sums in float32 even for
    # bfloat16 logits.
    top_values = top_values.to(torch.float32)
    num_candidates = top_values.shape[-1]
    k_index = (top_k - 1).clamp(min=0, max=num_candidates - 1).to(torch.int64)
    k_cutoff = torch.gather(top_values, -1, k_index)
    in_top_k = top_values >= k_cutoff
    topk_values = torch.where(
        in_top_k, top_values, torch.full_like(top_values, MASKED_LOGIT_VALUE)
    )
    cumulative = torch.cumsum(torch.softmax(topk_values, dim=-1), dim=-1)
    num_in_top_k = in_top_k.to(torch.int32).sum(dim=-1, keepdim=True)
    # The first position whose cumulative mass reaches top_p closes the
    # top-p set; float rounding can leave the total just below 1.0.
    p_index = torch.minimum(
        (cumulative < top_p).to(torch.int32).sum(dim=-1, keepdim=True),
        num_in_top_k - 1,
    ).to(torch.int64)
    p_cutoff = torch.gather(top_values, -1, p_index)
    return torch.where(top_p < 1.0, p_cutoff, k_cutoff)


def apply_top_k_top_p_prefilter(
    logits: torch.Tensor,
    top_k: torch.Tensor,
    top_p: torch.Tensor,
) -> torch.Tensor:
    """Applies top-k then top-p using the row's top-k prefilter candidates.

    Finds each row's cutoff from its TOPK_PREFILTER_CANDIDATES largest
    logits (`prefiltered_top_k`) and masks the full row below it. Matches
    `apply_top_k_top_p` unless more than TOPK_PREFILTER_CANDIDATES - k + 1
    logits tie at the k-th largest value; float32 sums run in a different
    order, so a top-p boundary within rounding can flip. Caller must ensure
    active rows have 1 <= top_k <= TOPK_PREFILTER_CANDIDATES // 2; rows with
    top_k <= 0 (padded slots) are returned unmasked.

    Args:
      logits: [batch, vocab_size].
      top_k: [batch, 1] integer.
      top_p: [batch, 1] float.

    Returns:
      Masked logits. [batch, vocab_size]
    """
    top_values, _ = prefiltered_top_k(logits, TOPK_PREFILTER_CANDIDATES)
    cutoff = _sorted_top_k_top_p_cutoff(top_values, top_k, top_p)
    masked = torch.where(
        logits >= cutoff, logits, torch.full_like(logits, MASKED_LOGIT_VALUE)
    )
    return torch.where(top_k > 0, masked, logits)


def sample_top_k_top_p_prefilter(
    scaled_logits: torch.Tensor,
    top_k: torch.Tensor,
    top_p: torch.Tensor,
    u: torch.Tensor,
) -> torch.Tensor:
    """Samples one token per row from its top-k / top-p candidates.

    Draws from the same distribution as `apply_top_k_top_p` plus a Gumbel-max
    over the full vocab, but only the TOPK_PREFILTER_CANDIDATES largest
    logits of each row are masked and perturbed. With u[:, i] equal to the
    full-vocab noise at the i-th candidate's token, it returns the same token.
    Same caller contract as `apply_top_k_top_p_prefilter`.

    Args:
      scaled_logits: Temperature-scaled logits. [batch, vocab_size]
      top_k: [batch, 1] integer.
      top_p: [batch, 1] float.
      u: Uniform noise for the candidates. [batch, TOPK_PREFILTER_CANDIDATES]

    Returns:
      Sampled token ids. [batch, 1]
    """
    top_values, top_indices = prefiltered_top_k(
        scaled_logits, TOPK_PREFILTER_CANDIDATES
    )
    cutoff = _sorted_top_k_top_p_cutoff(top_values, top_k, top_p)
    kept_values = torch.where(
        top_values >= cutoff,
        top_values,
        torch.full_like(top_values, MASKED_LOGIT_VALUE),
    )
    u_clamped = torch.clamp(
        u, min=torch.finfo(u.dtype).tiny, max=1.0 - torch.finfo(u.dtype).eps
    )
    noisy_values = kept_values - torch.log(-torch.log(u_clamped))
    position = torch.argmax(noisy_values, dim=-1, keepdim=True)
    return torch.gather(top_indices, -1, position)
