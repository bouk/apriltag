/**
 * @file image_u8_parallel.c
 * @author MqCreaple (gmq14159@gmail.com)
 * @brief Parallelized processing of various image_u8 related functions.
 * @version 0.1
 * @date 2025-08-07
 * 
 * @copyright Copyright (c) 2025
 * 
 */

#include "common/image_u8_parallel.h"
#include "common/workerpool.h"
#include "common/math_util.h"

#ifdef __AVX2__
#include <immintrin.h>
#endif
#if defined(__ARM_NEON) || defined(__ARM_NEON__)
#include <arm_neon.h>
#endif

static void convolve(const uint8_t *x, uint8_t *y, int sz, const uint8_t *k, int ksz)
{
    assert((ksz&1)==1);

    for (int i = 0; i < ksz/2 && i < sz; i++)
        y[i] = x[i];

    for (int i = 0; i < sz - ksz + 1; i++) {
        uint32_t acc = 0;

        for (int j = 0; j < ksz; j++)
            acc += k[j]*x[i+j];

        y[ksz/2 + i] = acc >> 8;
    }

    for (int i = sz - ksz/2; i < sz; i++)
        y[i] = x[i];
}

struct image_u8_convolve_2D_task {
    image_u8_t *im;
    const uint8_t *k;
    int ksz;
    int idx_st;
    int idx_ed;
};

static void _image_u8_convolve_2D_thread_1(void *p) {
    struct image_u8_convolve_2D_task *params = (struct image_u8_convolve_2D_task*) p;
    image_u8_t *im = params->im;
    const uint8_t *k = params->k;
    int ksz = params->ksz;
    int y_st = params->idx_st;
    int y_ed = params->idx_ed;

    assert((ksz & 1) == 1); // ksz must be odd.

    uint8_t *x = malloc(sizeof(uint8_t)*im->stride);
    for (int y = y_st; y < y_ed; y++) {
        memcpy(x, &im->buf[y*im->stride], im->stride);
        convolve(x, &im->buf[y*im->stride], im->width, k, ksz);
    }
    free(x);
}

static void _image_u8_convolve_2D_thread_2(void *p) {
    struct image_u8_convolve_2D_task *params = (struct image_u8_convolve_2D_task*) p;
    image_u8_t *im = params->im;
    const uint8_t *k = params->k;
    int ksz = params->ksz;
    int x_st = params->idx_st;
    int x_ed = params->idx_ed;

    uint8_t *xb = malloc(sizeof(uint8_t)*im->height);
    uint8_t *yb = malloc(sizeof(uint8_t)*im->height);
    for (int x = x_st; x < x_ed; x++) {

        for (int y = 0; y < im->height; y++)
            xb[y] = im->buf[y*im->stride + x];

        convolve(xb, yb, im->height, k, ksz);

        for (int y = 0; y < im->height; y++)
            im->buf[y*im->stride + x] = yb[y];
    }
    free(xb);
    free(yb);
}

void image_u8_convolve_2D_parallel(workerpool_t *wp, image_u8_t *im, const uint8_t *k, int ksz) {
    if(im->width * im->height < 65536) {
        // for small images, directly use single threaded convolution
        image_u8_convolve_2D(im, k, ksz);
        return;
    }
    int nthreads = workerpool_get_nthreads(wp);

    struct image_u8_convolve_2D_task *params = malloc(sizeof(struct image_u8_convolve_2D_task) * nthreads);
    int y_inc = im->height / nthreads;
    int y_remainder = im->height % nthreads;
    int last_y = 0;
    for(int idx = 0; idx < nthreads; idx++) {
        params[idx].im = im;
        params[idx].k = k;
        params[idx].ksz = ksz;
        params[idx].idx_st = last_y;
        last_y += y_inc;
        if(idx < y_remainder) {
            last_y += 1;     // distribute the remainders across the n threads
        }
        params[idx].idx_ed = last_y;
        workerpool_add_task(wp, _image_u8_convolve_2D_thread_1, &params[idx]);
    }
    workerpool_run(wp);

    int x_inc = im->width / nthreads;
    int x_remainder = im->width % nthreads;
    int last_x = 0;
    for(int idx = 0; idx < nthreads; idx++) {
        params[idx].im = im;
        params[idx].k = k;
        params[idx].ksz = ksz;
        params[idx].idx_st = last_x;
        last_x += x_inc;
        if(idx < x_remainder) {
            last_x += 1;     // distribute the remainders across the n threads
        }
        params[idx].idx_ed = last_x;
        workerpool_add_task(wp, _image_u8_convolve_2D_thread_2, &params[idx]);
    }
    workerpool_run(wp);

    free(params);
}

struct decimate_task {
    const image_u8_t *in;
    image_u8_t *out;
    int factor;   // integer point-sampling factor; 0 selects the 1.5 path
    int sy0, sy1; // output rows [sy0, sy1)
};

// the 1.5x path of image_u8_decimate: every 3x3 input block becomes a
// 2x2 output block, so rows are processed in output pairs (sy0 even)
static void decimate_three_halves_rows(const image_u8_t *in, image_u8_t *out, int sy0, int sy1)
{
    int swidth = out->width;
    for (int sy = sy0; sy < sy1; sy += 2) {
        int y = sy / 2 * 3;
        int x = 0;
        for (int sx = 0; sx < swidth; sx += 2) {

            // a b c
            // d e f
            // g h i
            uint8_t a = in->buf[(y+0)*in->stride + (x+0)];
            uint8_t b = in->buf[(y+0)*in->stride + (x+1)];
            uint8_t c = in->buf[(y+0)*in->stride + (x+2)];

            uint8_t d = in->buf[(y+1)*in->stride + (x+0)];
            uint8_t e = in->buf[(y+1)*in->stride + (x+1)];
            uint8_t f = in->buf[(y+1)*in->stride + (x+2)];

            uint8_t g = in->buf[(y+2)*in->stride + (x+0)];
            uint8_t h = in->buf[(y+2)*in->stride + (x+1)];
            uint8_t i = in->buf[(y+2)*in->stride + (x+2)];

            out->buf[(sy+0)*out->stride + (sx + 0)] =
                (4*a+2*b+2*d+e)/9;
            out->buf[(sy+0)*out->stride + (sx + 1)] =
                (4*c+2*b+2*f+e)/9;

            out->buf[(sy+1)*out->stride + (sx + 0)] =
                (4*g+2*d+2*h+e)/9;
            out->buf[(sy+1)*out->stride + (sx + 1)] =
                (4*i+2*f+2*h+e)/9;

            x += 3;
        }
    }
}

// factor-2 fast path: each output pixel is the average of its 2x2 input
// block. Both vector paths use the same rounding tree — vertical
// rounding average per column, then a rounding average of the column
// pair — so they produce identical bytes; the scalar tail's exact
// (a+b+c+d+2)>>2 can differ from them by at most 1 gray level.
static void decimate2_box_rows(const image_u8_t *in, image_u8_t *out, int sy0, int sy1)
{
    int swidth = out->width;
    for (int sy = sy0; sy < sy1; sy++) {
        const uint8_t *r0 = &in->buf[(2*sy + 0)*in->stride];
        const uint8_t *r1 = &in->buf[(2*sy + 1)*in->stride];
        uint8_t *o = &out->buf[sy*out->stride];
        int sx = 0;
#if defined(__AVX2__)
        const __m256i ones = _mm256_set1_epi8(1);
        const __m256i round1 = _mm256_set1_epi16(1);
        for (; sx + 32 <= swidth; sx += 32) {
            __m256i a0 = _mm256_loadu_si256((const __m256i *)(r0 + 2*sx));
            __m256i a1 = _mm256_loadu_si256((const __m256i *)(r0 + 2*sx + 32));
            __m256i b0 = _mm256_loadu_si256((const __m256i *)(r1 + 2*sx));
            __m256i b1 = _mm256_loadu_si256((const __m256i *)(r1 + 2*sx + 32));
            __m256i v0 = _mm256_avg_epu8(a0, b0);
            __m256i v1 = _mm256_avg_epu8(a1, b1);
            // horizontal pair sums in 16-bit lanes, then round and halve
            __m256i s0 = _mm256_srli_epi16(_mm256_add_epi16(_mm256_maddubs_epi16(v0, ones), round1), 1);
            __m256i s1 = _mm256_srli_epi16(_mm256_add_epi16(_mm256_maddubs_epi16(v1, ones), round1), 1);
            __m256i packed = _mm256_packus_epi16(s0, s1);
            packed = _mm256_permute4x64_epi64(packed, 0xD8);
            _mm256_storeu_si256((__m256i *)(o + sx), packed);
        }
#elif defined(__ARM_NEON) || defined(__ARM_NEON__)
        for (; sx + 16 <= swidth; sx += 16) {
            // deinterleaved loads put even and odd columns in separate
            // registers; vertical rounding average per column, then a
            // rounding average across the column pair
            uint8x16x2_t a = vld2q_u8(r0 + 2*sx);
            uint8x16x2_t b = vld2q_u8(r1 + 2*sx);
            uint8x16_t ve = vrhaddq_u8(a.val[0], b.val[0]);
            uint8x16_t vo = vrhaddq_u8(a.val[1], b.val[1]);
            vst1q_u8(o + sx, vrhaddq_u8(ve, vo));
        }
#endif
        for (; sx < swidth; sx++) {
            int x = 2*sx;
            o[sx] = (r0[x] + r0[x+1] + r1[x] + r1[x+1] + 2) >> 2;
        }
    }
}

static void decimate_point_rows(const image_u8_t *in, image_u8_t *out, int factor, int sy0, int sy1)
{
    int swidth = out->width;
    for (int sy = sy0; sy < sy1; sy++) {
        const uint8_t *row = &in->buf[(sy*factor)*in->stride];
        uint8_t *o = &out->buf[sy*out->stride];
        for (int sx = 0, x = 0; sx < swidth; sx++, x += factor)
            o[sx] = row[x];
    }
}

static void decimate_task_fn(void *p)
{
    struct decimate_task *t = (struct decimate_task *)p;
    if (t->factor == 0)
        decimate_three_halves_rows(t->in, t->out, t->sy0, t->sy1);
    else if (t->factor == 2)
        decimate2_box_rows(t->in, t->out, t->sy0, t->sy1);
    else
        decimate_point_rows(t->in, t->out, t->factor, t->sy0, t->sy1);
}

image_u8_t *image_u8_decimate_parallel(workerpool_t *wp, const image_u8_t *im, float ffactor)
{
    int width = im->width, height = im->height;

    image_u8_t *decim;
    int factor = 0;
    int rowalign = 1;
    if (ffactor == 1.5f) {
        decim = image_u8_create(width / 3 * 2, height / 3 * 2);
        rowalign = 2; // tasks own whole 2-row output blocks
    } else {
        factor = (int) ffactor;
        if (factor == 2)
            decim = image_u8_create(width / 2, height / 2);
        else
            decim = image_u8_create(1 + (width - 1) / factor, 1 + (height - 1) / factor);
    }
    int sheight = decim->height;

    int nthreads = workerpool_get_nthreads(wp);
    if (nthreads <= 1 || sheight < 64) {
        struct decimate_task task = {im, decim, factor, 0, sheight};
        decimate_task_fn(&task);
        return decim;
    }

    struct decimate_task *tasks = malloc(sizeof(struct decimate_task) * nthreads);
    int ntasks = 0;
    int sy = 0;
    for (int i = 0; i < nthreads && sy < sheight; i++) {
        int end = sy + (sheight - sy) / (nthreads - i);
        end = (end / rowalign) * rowalign;
        if (i == nthreads - 1 || end <= sy)
            end = sheight;
        tasks[ntasks].in = im;
        tasks[ntasks].out = decim;
        tasks[ntasks].factor = factor;
        tasks[ntasks].sy0 = sy;
        tasks[ntasks].sy1 = end;
        workerpool_add_task(wp, decimate_task_fn, &tasks[ntasks]);
        ntasks++;
        sy = end;
    }
    workerpool_run(wp);
    free(tasks);

    return decim;
}

void image_u8_gaussian_blur_parallel(workerpool_t *wp, image_u8_t *im, double sigma, int ksz) {
    if (sigma == 0)
        return;

    assert((ksz & 1) == 1); // ksz must be odd.

    // build the kernel.
    double *dk = malloc(sizeof(double)*ksz);

    // for kernel of length 5:
    // dk[0] = f(-2), dk[1] = f(-1), dk[2] = f(0), dk[3] = f(1), dk[4] = f(2)
    for (int i = 0; i < ksz; i++) {
        int x = -ksz/2 + i;
        double v = exp(-.5*sq(x / sigma));
        dk[i] = v;
    }

    // normalize
    double acc = 0;
    for (int i = 0; i < ksz; i++)
        acc += dk[i];

    for (int i = 0; i < ksz; i++)
        dk[i] /= acc;

    uint8_t *k = malloc(sizeof(uint8_t)*ksz);
    for (int i = 0; i < ksz; i++)
        k[i] = dk[i]*255;

    free(dk);

    image_u8_convolve_2D_parallel(wp, im, k, ksz);
    free(k);
}
