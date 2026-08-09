"""The ``lp_file`` sink: the model as LP text.

Portability, debugging, and the differential oracle. Every section is sunk
straight into the open file, so the LP text never exists in this process's
memory — and no byte is written twice.

Numbers go through polars' float cast, which round-trips exactly: the text a
solver reads back is the double the engine computed.

**Every section is written in label order.** A solver does not care, but a
reader diffing two LP files does, and so does anyone checking that a model
builds the same bytes twice (#109).
"""

from __future__ import annotations

from pathlib import Path
from typing import IO, TYPE_CHECKING

import polars as pl

if TYPE_CHECKING:
    from lpspec.relational.sinks.tables import ModelTables


#: Nonzeros per constraint chunk. The stream a chunk sorts is its terms plus a
#: header and a footer per row, carrying rendered text — so this is the knob
#: that bounds the writer's peak rather than its speed. Measured on
#: `transport/l`, chunking at this width takes the constraint section's peak
#: contribution from +0.88 GB to a fraction of it, for no change in the bytes.
#: Wider costs memory for nothing; much narrower pays per-chunk overhead on
#: every range.
EMIT_BUDGET = 2_000_000


def _sink(frame: pl.LazyFrame, f: IO[bytes]) -> None:
    """Append a one-column frame to *f*, one raw line per row.

    A CSV writer with the CSV switched off: no header, no quoting, so the bytes
    on disk are exactly the strings the frame holds.

    The frame goes into the file the caller is already holding rather than into
    a part file to be concatenated afterwards. Sections are produced in the
    order the LP format wants them, so there is nothing to reorder — and a
    concatenation pass would read and rewrite the whole file, which at these
    sizes costs more than producing it did. polars writes through the handle's
    own buffer, so a ``f.write()`` between two sinks lands between them.
    """
    # `maintain_order` is polars' default and is what #109 rests on, so it is
    # stated rather than inherited: the parameter is documented as unstable,
    # and a default that flips would make the bytes non-reproducible silently.
    frame.sink_csv(f, include_header=False, quote_style='never', maintain_order=True)


def write_lp_file(model: ModelTables, path: str | Path) -> None:
    """Write the model as LP text."""

    path = Path(path)
    objective = model.obj.lazy().sort('col').select(_term(pl.col('coeff'), pl.col('col')))
    # `cols` is positional, so the index is added inside the streamed pipeline
    # rather than sorted out of a column the model carried all along.
    bounds = (
        model.cols.lazy()
        .with_row_index('col')
        .select(
            pl.concat_str(
                _bound(pl.col('lb'), '-infinity').alias('lb'),
                pl.lit(' <= x').alias('open'),
                _digits(pl.col('col')),
                pl.lit(' <= ').alias('close'),
                _bound(pl.col('ub'), '+infinity').alias('ub'),
            )
        )
    )

    with open(path, 'wb') as f:
        f.write((b'min' if model.objective_sense == 'min' else b'max') + b'\n\nobj:\n')
        if model.objective_constant:
            f.write(f'{model.objective_constant:+.17g}\n'.encode())
        _sink(objective, f)

        f.write(b'\ns.t.\n\n')
        # One range at a time. The stream a chunk sorts carries rendered text,
        # so sorting the whole model at once is what the writer's peak *is*;
        # ranges are ascending and each is internally sorted, so the bytes are
        # the same ones #109 pins.
        for lo, hi in model.row_chunks_by_nonzeros(EMIT_BUDGET):
            _sink(_constraint_blocks(model, lo, hi), f)

        f.write(b'\nbounds\n')
        _sink(bounds, f)

        for variable_type, keyword in (('binary', 'binary'), ('integer', 'general')):
            chosen = model.cols.lazy().with_row_index('col').filter(pl.col('vtype') == variable_type)
            if chosen.select(pl.len()).collect().item() == 0:
                continue
            f.write(f'\n{keyword}\n'.encode())
            _sink(chosen.select(pl.concat_str(pl.lit('x'), _digits(pl.col('col')))), f)

        f.write(b'\nend\n')


def _constraint_blocks(model: ModelTables, lo: int, hi: int) -> pl.LazyFrame:
    """Every constraint line, as one sorted stream of ``(key, line)``.

    One line per output line rather than one block per row: the pieces are
    built independently and interleaved by sorting, so nothing has to gather a
    row's terms into a string first. That is what makes the bytes reproducible
    — a hash join hands back groups in whatever order it finishes them, and no
    amount of sorting the *rows* afterwards fixes the order *within* one.

    A row with no terms still needs a line a solver can parse, and the anti-join
    is what a group-by gave for free — anti rather than a count, because the
    question is whether the row has *a* term and not how many, so the matrix
    goes in as it is. Distinguishing its repeated ``row`` values would be a
    hash pass over every nonzero in the chunk to reach the same answer.

    **The order is one integer, and it is the only other column.** A row's lines
    occupy ``slots`` consecutive keys and each piece picks one — header first,
    then the placeholder, then each term at its own column index, then the
    sense. Sorting one column beats sorting ``(row, ord)``, and carrying nothing
    else means the sort permutes the rendered text and nothing beside it.

    **Chunk-relative**, because that is what bounds the key. Each range is sunk
    before the next is built, so only the order *within* one has to hold, and
    ``row - lo`` is a chunk's height rather than the model's. A global row would
    put the product one careless model away from overflowing ``Int64`` and
    reordering the file in silence.
    """
    slots = model.cols.height + 3

    def _key(within: pl.Expr) -> pl.Expr:
        return ((pl.col('row') - lo) * slots + within).alias('key')

    rows = model.rows.lazy().filter(pl.col('row').is_between(lo, hi, closed='left'))
    matrix = model.matrix.lazy().filter(pl.col('row').is_between(lo, hi, closed='left'))
    header = rows.select(
        _key(pl.lit(0, dtype=pl.Int64)),
        pl.concat_str(pl.lit('c').alias('c'), _digits(pl.col('row')), pl.lit(':').alias('colon')).alias('line'),
    )
    placeholder = rows.join(matrix.select('row'), on='row', how='anti').select(
        _key(pl.lit(1, dtype=pl.Int64)),
        pl.lit('+0 x0').alias('line'),
    )
    # Redundant for correctness — the ordering below subsumes it and the bytes
    # are identical without it — and kept anyway: whether it is redundant for
    # *speed* has been measured twice and settled neither time.
    terms = matrix.sort('row', 'col').select(
        _key(pl.col('col').cast(pl.Int64) + 2),
        _term(pl.col('coeff'), pl.col('col')).alias('line'),
    )
    footer = rows.select(
        _key(pl.lit(slots - 1, dtype=pl.Int64)),
        pl.concat_str(pl.col('sense').replace({'==': '='}), pl.lit(' '), _number(pl.col('rhs'))).alias('line'),
    )
    return pl.concat([header, placeholder, terms, footer]).sort('key').select('line')


def _term(coeff: pl.Expr, col: pl.Expr) -> pl.Expr:
    """One ``+1.5 x7`` term.

    Built by a single ``concat_str`` rather than by chaining ``+``. Every ``+``
    is its own pass allocating its own full-width string column, and a term has
    four pieces; this way the line is allocated once.
    """
    return pl.concat_str(*_signed(coeff), pl.lit(' x'), _digits(col))


def _number(value: pl.Expr) -> pl.Expr:
    """A float as LP text."""

    return value.cast(pl.String)


def _signed(value: pl.Expr) -> tuple[pl.Expr, pl.Expr]:
    """A coefficient, sign always explicit — the LP format needs the ``+``.

    Two pieces for ``concat_str`` rather than one finished string, because the
    cast already carries the ``-``: only a non-negative value needs a sign
    glued on, and the sign column is one character wide however large the
    model. Deciding the sign and then rendering ``abs()`` would render the
    magnitude in both arms of the ``when``, at full width, to discard one.

    ``-0.0`` is why zero is spelled out rather than cast: it is ``>= 0``, so it
    takes the ``+`` arm while the cast still renders ``-0.0``, giving
    ``+-0.0``, which no LP parser accepts. It is reachable from any negative
    coefficient times a zero parameter, so it is a real file, not a curiosity.
    """
    return (
        pl.when(value >= 0).then(pl.lit('+')).otherwise(pl.lit('')).alias('sign'),
        pl.when(value == 0).then(pl.lit('0.0')).otherwise(_number(value)).alias('magnitude'),
    )


def _bound(value: pl.Expr, infinite: str) -> pl.Expr:
    """A bound, with the LP format's own spelling for an unbounded one."""

    return pl.when(value.is_infinite()).then(pl.lit(infinite)).otherwise(_number(value))


def _digits(value: pl.Expr) -> pl.Expr:
    """An index as text — never in scientific notation, whatever its size."""

    return value.cast(pl.Int64).cast(pl.String)
