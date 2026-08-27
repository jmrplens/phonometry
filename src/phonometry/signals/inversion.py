#  Copyright (c) 2026. Jose Manuel Requena Plens
r"""Regularized spectral inversion with frequency-dependent regularization.

Inverting a measured transfer function -- to equalize a measurement
loudspeaker, flatten a microphone response or post-process an acquired
impulse response -- cannot be a plain reciprocal :math:`1/H(f)`: wherever
the
system radiates little energy (outside its passband, in deep notches) the
reciprocal explodes and the inverse filter amplifies nothing but noise.
Mueller & Massarani ("Transfer-Function Measurement with Sweeps", JAES
49(6), 2001, Secs. 3.1 and 4.5) therefore confine the inversion to the
transmission band: unity equalization in-band and a controlled, bounded
gain outside.

This module implements that behaviour with the frequency-dependent
Tikhonov regularization of Kirkeby & Nelson ("Digital Filter Design for
Inversion Problems in Sound Reproduction", JAES 47(7/8), 1999, Eq. (17)):

.. math::

   H_{\mathrm{inv}}(f)
   = \frac{\overline{H(f)}}{\lvert H(f) \rvert^2 + \epsilon(f)}

where the regularization profile :math:`\epsilon(f)` is small inside the
band :math:`[f_1, f_2]` (the filter equalizes to unity within an analytic
bound) and large outside (the out-of-band gain is capped at
:math:`1/(2\sqrt{\epsilon})`, the maximum of
:math:`x/(x^2 + \epsilon)`), with a smooth geometric cross-fade
over a transition zone bordering the band edges. A modeling delay makes
the mixed-phase inverse causal (Kirkeby & Nelson Sec. 2.4: the inverse of
a non-minimum-phase response is anticausal and must be delayed to be
realisable).

The closed forms above are the module's oracles: in-band the equalized
magnitude :math:`\lvert H \, H_{\mathrm{inv}} \rvert` deviates from unity
by exactly :math:`\epsilon/(\lvert H \rvert^2 + \epsilon)`, and
out-of-band the filter gain never exceeds the
:math:`1/(2\sqrt{\epsilon})` bound.
"""

from __future__ import annotations

import math
from dataclasses import dataclass
from typing import TYPE_CHECKING, Any, Protocol

import numpy as np

from .._internal.utils import _typesignal
from .._internal.validation import require_ranks, require_same_length
from ..io._resolve import SignalInput, apply_calibration
from ..io._resolve import resolve_fs as _resolve_signal_fs
from ..io._signal import Signal

if TYPE_CHECKING:
    from matplotlib.axes import Axes
    from numpy.typing import DTypeLike


__all__ = [
    "InverseFilterResult",
    "regularized_inverse_filter",
]

#: Fewest samples a measured impulse response must have to be inverted.
_MIN_RESPONSE_SAMPLES = 2


class TimedResponse(Protocol):
    """A measured response that knows its own sample rate.

    The structural face of the sweep/MLS/Golay result objects: an array view
    of the impulse response plus the rate it was sampled at. Structural on
    purpose, because naming :class:`phonometry.room.ImpulseResponseResult`
    here would put a toolbox-to-domain edge in the import graph that the
    architecture forbids; any object with these two members is accepted, and
    that class is one of them.
    """

    @property
    def fs(self) -> float | None: ...

    def __array__(
        self, dtype: DTypeLike | None = None, copy: bool | None = None
    ) -> np.ndarray: ...


def _require_band_flatness(result: InverseFilterResult) -> None:
    r"""Pin ``flatness_db`` against the equalized magnitude it summarises.

    The flatness is closed over what the result already stores. The equalized
    magnitude is the elementwise product of
    :attr:`~InverseFilterResult.response_spectrum` and
    :attr:`~InverseFilterResult.spectrum` -- the modeling delay carried in the
    latter is a unit-modulus factor and cannot move a magnitude -- and the band
    it is worst over is the part of
    :attr:`~InverseFilterResult.frequencies` inside
    :attr:`~InverseFilterResult.f_range`. :meth:`InverseFilterResult.plot`
    prints the number in the figure title and draws that same product on the
    axes below it, so a result built by hand, or by :func:`dataclasses.replace`
    on a genuine one, can title a figure with a ripple its own curve never
    shows.

    A band the inversion cannot fill -- an equalized magnitude that touches
    zero at some bin, where the measured response has a null -- is infinitely
    far from 0 dB, and the design reports ``inf`` for it. That value is a
    reading, not a defect: it is kept, and :func:`math.isclose` accepts it
    against itself.

    A billionth of a decibel of slack lets a caller who recomputed the
    deviation along another floating-point path restate it without being
    refused over the last bit.

    :param result: The result carrying both the flatness and the spectra.
    :raises ValueError: if ``f_range`` selects no bin of ``frequencies``, or
        ``flatness_db`` is not the worst deviation from 0 dB that the stored
        spectra show across that band.
    """
    freqs = np.asarray(result.frequencies, dtype=np.float64)
    f1, f2 = result.f_range
    band = (freqs >= f1) & (freqs <= f2)
    n_band = int(np.count_nonzero(band))
    if n_band == 0:
        msg = (
            "InverseFilterResult: 'f_range' must select at least one bin of "
            "'frequencies' for 'flatness_db' to summarise; got "
            f"({f1!r}, {f2!r}) against {freqs.size} bin(s)."
        )
        raise ValueError(msg)
    equalized = np.abs(
        np.asarray(result.response_spectrum) * np.asarray(result.spectrum)
    )
    with np.errstate(divide="ignore"):
        worst = float(np.max(np.abs(20.0 * np.log10(equalized[band]))))
    if math.isclose(result.flatness_db, worst, rel_tol=0.0, abs_tol=1e-9):
        return
    msg = (
        "InverseFilterResult: 'flatness_db' must be the largest deviation "
        "from 0 dB of the equalized magnitude 'response_spectrum' times "
        f"'spectrum' across 'f_range'; got {result.flatness_db!r} where those "
        f"spectra deviate by {worst!r} over the {n_band} band bin(s)."
    )
    raise ValueError(msg)


@dataclass(frozen=True)
class InverseFilterResult:
    r"""A regularized inverse filter with its achieved equalization.

    Returned by :func:`regularized_inverse_filter`. The causal filter
    samples live in ``inverse`` (the equalized response arrives ``delay``
    samples late; :meth:`apply` compensates it). ``spectrum`` is the
    complex inverse spectrum *including* the modeling delay;
    ``regularization`` is the :math:`\epsilon(f)` profile actually used,
    and ``flatness_db`` reports how flat the equalized magnitude
    :math:`\lvert H(f) \, H_{\mathrm{inv}}(f) \rvert` actually is across
    the requested band.

    :ivar inverse: Inverse-filter samples (time domain, length ``n_fft``).
    :ivar frequencies: Frequency grid of the design, in Hz.
    :ivar spectrum: Complex inverse spectrum on :attr:`frequencies`,
        including the :math:`\exp(-j 2 \pi f \, \text{delay} / f_\mathrm{s})`
        modeling delay.
    :ivar response_spectrum: Complex spectrum of the measured response the
        filter was designed from, on the same grid.
    :ivar regularization: The frequency-dependent profile
        :math:`\epsilon(f)` (absolute units of
        :math:`\lvert H \rvert^2`).
    :ivar f_range: ``(f1, f2)`` band equalized to unity, in Hz.
    :ivar delay: Modeling delay of the filter, in samples.
    :ivar fs: Sample rate, in Hz.
    :ivar flatness_db: Largest deviation of the equalized magnitude
        :math:`20 \log_{10} \lvert H \, H_{\mathrm{inv}} \rvert` from 0 dB
        inside :math:`[f_1, f_2]`.
    :ivar max_gain_db: Largest filter gain *outside* the transition-padded
        band, peak-normalized as
        :math:`20 \log_{10}(\max \lvert H_{\mathrm{inv}} \rvert \cdot
        \text{peak}_h)` where ``peak_h`` is the peak of
        :math:`\lvert H \rvert` -- the achieved out-of-band boost
        the regularization allowed where the measurement carries no signal.
    """

    inverse: np.ndarray
    frequencies: np.ndarray
    spectrum: np.ndarray
    response_spectrum: np.ndarray
    regularization: np.ndarray
    f_range: tuple[float, float]
    delay: int
    fs: float
    flatness_db: float
    max_gain_db: float

    def __post_init__(self) -> None:
        r"""Reject a design whose spectra, or whose flatness, disagree.

        The three spectra and the regularization profile are the design at
        one frequency each, but only three of the four are read by anything
        that would object. :meth:`plot` forms the equalized magnitude
        :math:`\lvert H \, H_{\mathrm{inv}} \rvert` as an elementwise
        product of :attr:`response_spectrum` and :attr:`spectrum` -- which
        numpy is content to broadcast from a single bin across the whole
        grid -- and then masks each magnitude with the positive-frequency
        mask taken from :attr:`frequencies`, one line before it draws. So
        numpy is what refuses the mismatch today, and it refuses it out
        loud: an ``IndexError`` about two axis sizes where the mask meets a
        shorter array, a ``ValueError`` about two shapes where the product
        does. No figure comes back either way, and neither message names
        the field that is wrong.

        :attr:`regularization` is the silent one. No renderer opens it, so
        a profile a bin short, a bin long or a single bin wide draws the
        whole figure with nothing said, and the :math:`\epsilon(f)` a
        caller reads back to reproduce the residue
        :math:`\epsilon/(\lvert H \rvert^2 + \epsilon)` is the one quantity
        of the four that no picture ever checked.

        :attr:`inverse` is deliberately left out of the length check. It is
        the filter in the time domain, ``n_fft`` samples, while the spectra
        live on the ``n_fft // 2 + 1`` bins of the real transform of it;
        the two lengths are different measurements of the same design and
        pinning them together would reject every filter the module
        produces. Its rank is pinned all the same: a second axis passes
        every length check, draws exactly as before, and doubles the sample
        count :attr:`size` reports.

        Of the two reported decibel figures only :attr:`flatness_db` is pinned,
        by :func:`_require_band_flatness`, because only it is closed over the
        fields stored here. :attr:`max_gain_db` is the achieved gain -- not the
        :math:`1/(2\sqrt{\epsilon})` ceiling -- but it is the largest gain over
        the band padded by ``transition_octaves``, and that padding is a design
        argument the result does not keep. Two genuine designs can therefore
        agree in every field above, profile included, and still report a
        different :attr:`max_gain_db`: put the padded edge exactly on a bin for
        one and just above it for the other and the profile is the same array
        while the bin falls inside one maximum and outside the other. Nothing
        computable from what is stored can tell the two apart, so nothing is
        claimed about it.

        :raises ValueError: if a spectrum or the profile disagrees with the
            frequency grid, a field carries an extra axis, or
            :attr:`flatness_db` does not restate the equalized magnitude.
        """
        require_ranks(
            self,
            inverse=1,
            frequencies=1,
            spectrum=1,
            response_spectrum=1,
            regularization=1,
        )
        require_same_length(
            self,
            "frequencies",
            "spectrum",
            "response_spectrum",
            "regularization",
            axis="frequency",
        )
        _require_band_flatness(self)

    def __array__(
        self, dtype: DTypeLike | None = None, copy: bool | None = None
    ) -> np.ndarray:
        """Return the inverse-filter samples as an array."""
        return np.asarray(self.inverse, dtype=dtype, copy=copy)

    def __len__(self) -> int:
        """Number of inverse-filter samples, the ``n_fft`` of the design."""
        return int(self.inverse.shape[-1])

    @property
    def size(self) -> int:
        """Number of samples in the inverse filter."""
        return int(self.inverse.size)

    def apply(self, x: list[float] | np.ndarray) -> np.ndarray:
        """Equalize a signal with the inverse filter.

        Convolves ``x`` with the filter and removes the modeling delay, so
        the output is time-aligned with the input and has the same length.
        Feeding the response the filter was designed from returns (in-band)
        a band-limited unit impulse at sample 0.

        :param x: The signal to equalize (1-D).
        :return: The equalized, delay-compensated signal, ``len(x)``
            samples.
        """
        from scipy import signal as sp_signal

        arr = _typesignal(x)
        if arr.ndim != 1:
            msg = "'x' must be one-dimensional."
            raise ValueError(msg)
        full = sp_signal.fftconvolve(arr, self.inverse)
        return np.asarray(full[self.delay : self.delay + arr.size])

    def plot(
        self, ax: Axes | None = None, *, language: str = "en", **kwargs: Any
    ) -> Axes:
        r"""Plot the measured, inverse and equalized magnitudes.

        One panel: :math:`\lvert H \rvert`,
        :math:`\lvert H_{\mathrm{inv}} \rvert` and the equalized product
        :math:`\lvert H \, H_{\mathrm{inv}} \rvert` in dB over
        log-frequency, with the equalized band
        shaded. Requires matplotlib (``pip install phonometry[plot]``).

        :param language: Label language, ``"en"`` (default) or ``"es"``.
        """
        from .._i18n import check_language
        from .._plot.signals import plot_inverse_filter

        check_language(language)
        return plot_inverse_filter(self, ax=ax, language=language, **kwargs)


def _regularization_profile(
    freqs: np.ndarray,
    f_range: tuple[float, float],
    eps_inside: float,
    eps_outside: float,
    transition_octaves: float,
) -> np.ndarray:
    r"""Frequency-dependent :math:`\epsilon(f)`: geometric cross-fade.

    :math:`\epsilon` equals ``eps_inside`` across all of
    :math:`[f_1, f_2]` and ``eps_outside`` beyond a
    ``transition_octaves``-wide zone bordering
    each edge; inside each zone the two levels are blended geometrically
    (linearly in :math:`\log \epsilon`) with a half-cosine, following the
    smooth transition-band advice of Kirkeby & Nelson (1999, Sec. 3.2).
    """
    f1, f2 = f_range
    ratio = 2.0**transition_octaves
    weight = np.zeros_like(freqs)  # 1 = in-band, 0 = out-of-band
    inside = (freqs >= f1) & (freqs <= f2)
    weight[inside] = 1.0
    below = (freqs >= f1 / ratio) & (freqs < f1)
    if np.any(below):
        x = np.log2(freqs[below] * ratio / f1) / transition_octaves
        weight[below] = 0.5 - 0.5 * np.cos(np.pi * x)
    above = (freqs > f2) & (freqs <= f2 * ratio)
    if np.any(above):
        x = np.log2(freqs[above] / f2) / transition_octaves
        weight[above] = 0.5 + 0.5 * np.cos(np.pi * x)
    log_eps = weight * np.log(eps_inside) + (1.0 - weight) * np.log(eps_outside)
    return np.asarray(np.exp(log_eps))


def _validated_response(
    response: SignalInput | TimedResponse,
) -> np.ndarray:
    """Validate the measured impulse response array."""
    h = _typesignal(response, name="response")
    if h.ndim != 1:
        msg = "'response' must be one-dimensional."
        raise ValueError(msg)
    if h.size < _MIN_RESPONSE_SAMPLES:
        msg = f"'response' must have at least {_MIN_RESPONSE_SAMPLES} samples."
        raise ValueError(msg)
    if isinstance(response, Signal):
        return apply_calibration(response, h)
    # The calibration contract is Signal-scoped; every other accepted form,
    # the plain arrays and the timed result objects, takes the same
    # pass-through apply_calibration would give it, said here so the wider
    # parameter type checks.
    return h


def _validated_band(f_range: tuple[float, float], fs: float) -> tuple[float, float]:
    """Validate the equalization band against the sample rate."""
    f1, f2 = float(f_range[0]), float(f_range[1])
    if f1 <= 0.0:
        msg = "f_range[0] must be positive"
        raise ValueError(msg)
    if f2 <= f1:
        msg = "f_range[1] must be greater than f_range[0]"
        raise ValueError(msg)
    if f2 > fs / 2.0:
        msg = "f_range[1] must not exceed the Nyquist frequency"
        raise ValueError(msg)
    return f1, f2


def _resolve_fs(
    response: SignalInput | TimedResponse,
    fs: float | None,
) -> float:
    """Take ``fs`` from the argument or from a result carrying one.

    A :class:`phonometry.io.Signal` goes through the library-wide resolver,
    which refuses an explicit rate that disagrees with the one the recording
    carries. The duck-typed branch below stays for the result objects of the
    sweep/MLS/Golay front ends, which carry a rate but no such contract.
    """
    if isinstance(response, Signal):
        return float(_resolve_signal_fs(response, fs, name="response"))
    if fs is None:
        fs = getattr(response, "fs", None)
    if fs is None:
        msg = (
            "'fs' is required (pass it explicitly, or pass a result object "
            "that carries a sample rate)"
        )
        raise ValueError(msg)
    fs_v = float(fs)
    if fs_v <= 0.0:
        msg = "fs must be positive"
        raise ValueError(msg)
    return fs_v


def regularized_inverse_filter(
    response: SignalInput | TimedResponse,
    fs: float | None = None,
    *,
    f_range: tuple[float, float],
    regularization_inside: float = 1e-6,
    regularization_outside: float = 1.0,
    transition_octaves: float = 1.0 / 3.0,
    n_fft: int | None = None,
    delay: int | None = None,
) -> InverseFilterResult:
    r"""Design a regularized inverse filter for a measured impulse response.

    Computes the frequency-dependent Tikhonov inverse of Kirkeby & Nelson
    (JAES 47(7/8), 1999, Eq. (17)),

    .. math::

       H_{\mathrm{inv}}(f)
       = \frac{\overline{H(f)}}{\lvert H(f) \rvert^2 + \epsilon(f)}

    with :math:`\epsilon(f)` small across :math:`[f_1, f_2]` and large
    outside, so the filter equalizes the response to unity in-band while
    the out-of-band gain stays bounded by
    :math:`1/(2\sqrt{\epsilon_{\mathrm{outside}}})` -- the behaviour
    Mueller & Massarani (JAES 49(6), 2001, Secs. 3.1/4.5) obtain by
    band-passing the plain inverse. A modeling delay of ``delay`` samples
    (default half the FFT block) shifts the generally anticausal inverse of
    a mixed-phase response into a causal filter (Kirkeby & Nelson,
    Sec. 2.4).

    Both regularization levels are *relative* to the peak of
    :math:`\lvert H \rvert^2` (like the scalar ``regularization`` of
    :func:`phonometry.room.impulse_response`, which this generalises): in-band
    the equalized magnitude deviates from unity by at most
    ``regularization_inside * max|H|**2 / min|H|**2`` -- the analytic residue
    :math:`\epsilon/(\lvert H \rvert^2 + \epsilon)` -- and the achieved figure
    is reported as :attr:`InverseFilterResult.flatness_db`.

    Use the result's :meth:`InverseFilterResult.apply` to equalize
    recordings (or the excitation, for pre-emphasis) and read
    :attr:`InverseFilterResult.spectrum` to apply it spectrally.

    :param response: Measured impulse response (1-D array), or an
        :class:`phonometry.room.ImpulseResponseResult` from the sweep/MLS/Golay
        front ends (its sample rate is used when ``fs`` is omitted). Also
        accepts a :class:`phonometry.io.Signal`, whose calibration is applied
        to the samples, though an inverse filter undoes the response it is
        built from, so it comes out in 1/Pa, with the regularization floor
        in Pa².
    :param fs: Sample rate in Hz. Optional when ``response`` carries one.
    :param f_range: ``(f1, f2)`` band, in Hz, over which the response is
        equalized to unity. Choose it inside the band actually excited and
        radiated; inverting unexcited regions only amplifies noise.
    :param regularization_inside: In-band regularization, as a fraction of
        the peak spectral power :math:`\max \lvert H \rvert^2`.
        Default 1e-6.
    :param regularization_outside: Out-of-band regularization, same units.
        Default 1.0, which caps the out-of-band gain at 6 dB below the
        peak-normalised unity (:math:`1/(2\sqrt{1}) = 0.5`).
    :param transition_octaves: Width of the geometric cross-fade between
        the two regularization levels, in octaves outside each band edge.
        Default 1/3.
    :param n_fft: FFT block length of the design (also the filter length).
        Default: the next power of two of ``2*len(response)``, so the
        circular design has room for the anticausal (delayed) part.
    :param delay: Modeling delay in samples. Default ``n_fft // 2``.
    :return: An :class:`InverseFilterResult`.
    """
    h = _validated_response(response)
    fs_v = _resolve_fs(response, fs)
    f1, f2 = _validated_band(f_range, fs_v)
    if regularization_inside <= 0.0 or regularization_outside <= 0.0:
        msg = "both regularization levels must be positive"
        raise ValueError(msg)
    if transition_octaves <= 0.0:
        msg = "transition_octaves must be positive"
        raise ValueError(msg)

    size = n_fft if n_fft is not None else 2 ** int(np.ceil(np.log2(2 * h.size)))
    if size < h.size:
        msg = "n_fft must be at least the response length"
        raise ValueError(msg)
    lag = size // 2 if delay is None else int(delay)
    if not 0 <= lag < size:
        msg = "delay must be in [0, n_fft)"
        raise ValueError(msg)

    freqs = np.asarray(np.fft.rfftfreq(size, 1.0 / fs_v), dtype=np.float64)
    if not np.any((freqs >= f1) & (freqs <= f2)):
        msg = "no frequency bin falls within f_range; increase n_fft or widen the band."
        raise ValueError(msg)
    spectrum_h = np.fft.rfft(h, n=size)
    power = np.abs(spectrum_h) ** 2
    scale = float(np.max(power))
    if scale <= 0.0:
        msg = "'response' must not be identically zero."
        raise ValueError(msg)
    eps = _regularization_profile(
        freqs,
        (f1, f2),
        regularization_inside * scale,
        regularization_outside * scale,
        transition_octaves,
    )
    inv_spectrum = np.conj(spectrum_h) / (power + eps)
    inv_spectrum = inv_spectrum * np.exp(-2j * np.pi * freqs * lag / fs_v)
    inverse = np.fft.irfft(inv_spectrum, n=size)

    equalized = np.abs(spectrum_h * inv_spectrum)
    band = (freqs >= f1) & (freqs <= f2)
    with np.errstate(divide="ignore"):
        flatness = float(np.max(np.abs(20.0 * np.log10(equalized[band]))))
    ratio = 2.0**transition_octaves
    outside = (freqs > 0.0) & ((freqs < f1 / ratio) | (freqs > f2 * ratio))
    gain = np.abs(inv_spectrum[outside]) if np.any(outside) else np.array([])
    peak_h = float(np.sqrt(scale))
    max_gain = 20.0 * np.log10(float(np.max(gain)) * peak_h) if gain.size else -np.inf

    return InverseFilterResult(
        inverse=np.asarray(inverse),
        frequencies=freqs,
        spectrum=np.asarray(inv_spectrum),
        response_spectrum=np.asarray(spectrum_h),
        regularization=np.asarray(eps),
        f_range=(f1, f2),
        delay=lag,
        fs=fs_v,
        flatness_db=flatness,
        max_gain_db=max_gain,
    )
