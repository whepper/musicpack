/*
 * Musepack audio compression
 *
 * This library is free software; you can redistribute it and/or
 * modify it under the terms of the GNU Lesser General Public
 * License as published by the Free Software Foundation; either
 * version 2.1 of the License, or (at your option) any later version.
 *
 * This library is distributed in the hope that it will be useful,
 * but WITHOUT ANY WARRANTY; without even the implied warranty of
 * MERCHANTABILITY or FITNESS FOR A PARTICULAR PURPOSE.  See the GNU
 * Lesser General Public License for more details.
 *
 * You should have received a copy of the GNU Lesser General Public
 * License along with this library; if not, write to the Free Software
 * Foundation, Inc., 59 Temple Place, Suite 330, Boston, MA  02111-1307  USA
 */

// psy_tab.h
#define PART_LONG          57                   // number of partitions for long
#define PART_SHORT     (PART_LONG / 3)          // number of partitions for short
#define MAX_SPL            20                   // maximum assumed Sound Pressure Level

// psy.c
#define SHORTFFT_OFFSET   168                   // fft-offset for short FFT's
#define PREFAC_LONG        10                   // preecho-factor for long partitions


#define MAX_CVD_LINE      300                   // maximum FFT-Index for CVD
#define CVD_UNPRED          0.040f              // unpredictability (cw) for CVD-detected bins, e33 (04)
#define MIN_ANALYZED_IDX   12                   // maximum base-frequency = 44100/MIN_ANALYZED_IDX ^^^^^^
#define MED_ANALYZED_IDX   50                   // maximum base-frequency = 44100/MED_ANALYZED_IDX ^^^^^^
#define MAX_ANALYZED_IDX  900                   // minimum base-frequency = 44100/MAX_ANALYZED_IDX  (816 for Amnesia)


#define MAX_NS_ORDER        6                   // maximum order of the Adaptive Noise Shaping Filter (IIR)
#define MAX_ANS_BANDS      16
#define MAX_ANS_LINES    (32 * MAX_ANS_BANDS)   // maximum number of noiseshaped FFT-lines
///////// 16 * MAX_ANS_BANDS not sufficient? //////////////////
#define MS2SPAT1             0.5f
#define MS2SPAT2             0.25f
#define MS2SPAT3             0.125f
#define MS2SPAT4             0.0625f

typedef struct {
    float  L [32];
	float  R [32];
	float  M [32];
	float  S [32];
} SMRTyp;

/// Per-instance working state of the psychoacoustic model. Kept inside
/// PsyModel so multiple encoders can run concurrently without sharing
/// file-scope state.
typedef struct {
	float         a [PART_LONG];
	float         b [PART_LONG];
	float         c [PART_LONG];
	float         d [PART_LONG];           // Integrations for tmpMask
	float  Xsave_L [3 * 512];
	float  Xsave_R [3 * 512];              // FFT-Amplitudes L/R
	float  Ysave_L [3 * 512];
	float  Ysave_R [3 * 512];              // FFT-Phases L/R
	float         T_L [PART_LONG];
	float         T_R [PART_LONG];         // time-constants for tmpMask
	float         pre_erg_L [2][PART_SHORT];
	float         pre_erg_R [2][PART_SHORT]; // Preecho-control short
	float         PreThr_L [PART_LONG];
	float         PreThr_R [PART_LONG];    // for Pre-Echo-control L/R
	float         tmp_Mask_L [PART_LONG];
	float         tmp_Mask_R [PART_LONG];  // for Post-Masking L/R
	int           Vocal_L [MAX_CVD_LINE + 4];
	int           Vocal_R [MAX_CVD_LINE + 4]; // FFT-Line belongs to harmonic?
	float         loud;                    // tracked loudness for AdaptLtq
	float         ANSspec_L [MAX_ANS_LINES];
	float         ANSspec_R [MAX_ANS_LINES]; // L/R-masking thresholds for ANS
	float         ANSspec_M [MAX_ANS_LINES];
	float         ANSspec_S [MAX_ANS_LINES]; // M/S-masking thresholds for ANS
} psy_state_t;

typedef struct {
	int           Max_Band;                    // maximum bandwidth
	float         SampleFreq;
	int MainQual;	// main profile quality
	float FullQual;	// full profile quality

	// profile params
	float            ShortThr;         // Factor to calculate the masking threshold with transients
	int              MinValChoice;
	unsigned int     EarModelFlag;
	float            Ltq_offset;       // Offset for threshold in quiet
	float            TMN;              // Offset for purely sinusoid components
	float            NMT;              // Offset for purely noisy components
	float            minSMR;           // minimum SMR for all subbands
	float            Ltq_max;          // maximum level for threshold in quiet
	float            BandWidth;
	unsigned char    tmpMask_used;     // global flag for temporal masking
	unsigned char    CVD_used;         // global flag for ClearVoiceDetection
	float            varLtq;           // variable threshold in quiet
	unsigned char    MS_Channelmode;
	int              CombPenalities;
	unsigned int    NS_Order;         // Maximum order for ANS
	float            PNS;
	float            TransDetect;      // minimum slewrate for transient detection

	// ans.h
	unsigned int  NS_Order_L [32];
	unsigned int  NS_Order_R [32];                  // frame-wise order of the Noiseshaping (0: off, 1...5: on)
	float         FIR_L      [32] [MAX_NS_ORDER];
	float         FIR_R      [32] [MAX_NS_ORDER];   // contains FIR-Filter for NoiseShaping
	float         SNR_comp_L [32];
	float         SNR_comp_R [32];             // SNR-compensation after SCF-combination and ANS-gain

	float KBD1; // = 2.
	float KBD2; // = -1.

	// per-instance working state (FFT history, masking integrators, ...)
	psy_state_t state;

	// FIXME : remove this :
	int (* SCF_Index_L)[3];
	int (* SCF_Index_R)[3];         // Scalefactor-index for Bitstream

} PsyModel;

// ---- bit-exact psychoacoustic kernel dispatch (Phase 3) --------------------
// The hot spectrum/FFT kernels run through function pointers so the scalar
// reference and the SIMD kernels can be selected once and A/B compared.
// Internal/testable machinery, not a public API.
typedef void (*mpc_powspec_fn)   ( const float* x, float* erg );
typedef void (*mpc_polarspec_fn) ( const float* x, float* erg, float* phs );

enum {
    MPC_PSY_AUTO   = 0, ///< best available (default; SIMD when compiled in)
    MPC_PSY_SCALAR = 1, ///< force the scalar reference path
    MPC_PSY_SIMD   = 2, ///< force the SIMD path (no-op if not compiled in)
};

void mpc_psy_set_impl ( int impl );
int mpc_psy_has_simd ( void );
void mpc_psy_reset_state ( PsyModel* m );

// Spectrum/FFT kernels (fft_routines.c; dispatchers for the psy A/B).
void PowSpec256    ( const float* x, float* erg );
void PowSpec1024   ( const float* x, float* erg );
void PowSpec2048   ( const float* x, float* erg );
void PolarSpec1024 ( const float* x, float* erg, float* phs );

// Batch variants (lane-parallel FFT): process 4/2 independent spectra in one
// call. Scalar default; SIMD when MPC_ENABLE_PSY_SIMD_KERNEL.
typedef void (*mpc_powspec4_fn)  ( const float* x0, const float* x1, const float* x2, const float* x3,
                                   float* e0, float* e1, float* e2, float* e3 );
typedef void (*mpc_powspec2_fn)  ( const float* x0, const float* x1, float* e0, float* e1 );
typedef void (*mpc_polar2_fn)    ( const float* x0, const float* x1,
                                   float* e0, float* e1, float* p0, float* p1 );
void PowSpec256_4    ( const float* x0, const float* x1, const float* x2, const float* x3,
                       float* e0, float* e1, float* e2, float* e3 );
void PowSpec1024_2   ( const float* x0, const float* x1, float* e0, float* e1 );
void PowSpec2048_2   ( const float* x0, const float* x1, float* e0, float* e1 );
void PolarSpec1024_2 ( const float* x0, const float* x1, float* e0, float* e1, float* p0, float* p1 );

// Batched L/R cepstrum FFT (Phase 4): the two independent 2048-point
// cepstrum FFTs consumed by CVD2048 run in one lane-parallel call. Scalar
// default; SIMD when MPC_ENABLE_PSY_SIMD_KERNEL.
typedef void (*mpc_cepstrum2_fn) ( float* cepL, float* cepR, const int MaxLine );
void Cepstrum2048_2 ( float* cepL, float* cepR, const int MaxLine );

// Batched Clear Voice Detection: shared spectrum preparation + one lane-
// parallel cepstrum FFT for both channels; the cepstral analysis (and the
// rest of CVD) stays scalar.
void CVD2048_2 ( PsyModel* m, const float* specL, const float* specR,
                 int* vocalL, int* vocalR, int* isvocL, int* isvocR );

#ifdef MPC_ENABLE_PSY_SIMD_KERNEL
void mpc_powspec256_simd   ( const float* x, float* erg );
void mpc_powspec1024_simd  ( const float* x, float* erg );
void mpc_powspec2048_simd  ( const float* x, float* erg );
void mpc_polarspec1024_simd ( const float* x, float* erg, float* phs );
void mpc_powspec256_4_simd   ( const float* x0, const float* x1, const float* x2, const float* x3,
                               float* e0, float* e1, float* e2, float* e3 );
void mpc_powspec1024_2_simd  ( const float* x0, const float* x1, float* e0, float* e1 );
void mpc_powspec2048_2_simd  ( const float* x0, const float* x1, float* e0, float* e1 );
void mpc_polarspec1024_2_simd ( const float* x0, const float* x1,
                                float* e0, float* e1, float* p0, float* p1 );
void mpc_cepstrum2048_2_simd ( float* cepL, float* cepR, const int MaxLine );
#endif
