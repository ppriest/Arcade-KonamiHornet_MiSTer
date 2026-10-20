// SPDX-License-Identifier: GPL-3.0-or-later
//
// Float multiply in two stages, bit-exact to sharc_fp_pkg::f_mul (the multiplier flushes
// neither operands nor result). Stage 1 registers at `en`; the result and flags are stage 2's,
// combinational, in the clock after.
//
// Fast path: normal (or zero, infinite, NaN) operands whose product cannot underflow: one DSP
// product (stage 1), a one-bit normalise and the rounding (stage 2). Slow path: a denormal
// operand, or an exponent sum small enough that the result may be denormal: `busy` holds the
// pipeline (en low) for four clocks while the product is normalised, multiplied, shifted to the
// denormal boundary and rounded in steps; the result then enters stage 2 with the next en.

module sharc_fmul (
    input  logic        clk,
    input  logic        en,             // advance the pipeline
    input  logic        restart,        // new operands: the slow path starts again
    input  logic        valid,          // x, y are a multiply's operands
    input  logic [31:0] x,
    input  logic [31:0] y,
    output logic        busy,           // slow path: keep en low and the operands held
    output logic [31:0] r,
    output logic [31:0] astat,          // MN MV MU MI
    output logic [31:0] stky            // MVS MUS MIS
);

import sharc_fp_pkg::*;

// ---------------------------------------------------------------- stage 1

logic        sg, nan1, spec, slow1;
logic [31:0] spec_r;
logic [23:0] ma, mb;
logic [9:0]  esum;
logic [47:0] p;

always_comb begin
    sg = x[31] ^ y[31];
    nan1 = nan_mul(x, y);
    // infinities and zeros give a signed infinity or zero, exactly as ieee_mul's first tests
    spec = is_inf(x) || is_inf(y) || is_zero(x) || is_zero(y);
    spec_r = (is_inf(x) || is_inf(y)) ? {sg, INF[30:0]} : {sg, 31'h0};
    ma = {1'b1, x[22:0]};
    mb = {1'b1, y[22:0]};
    esum = {2'b0, x[30:23]} + {2'b0, y[30:23]};
    // a denormal operand, or a product that may round to a denormal: e = esum - 127 (+1) < 1
    slow1 = valid && !nan1 && !spec && (is_den(x) || is_den(y) || esum <= 10'd128);
    p = ma * mb;
end

// slow path: ieee_mul in four registered steps from the held operands
logic [2:0]  sc;
logic [23:0] qa, qb;
logic signed [11:0] qe;
logic [47:0] qp;
logic [26:0] qs;
logic [31:0] slow_r;

always_ff @(posedge clk) begin
    if (en || restart || !slow1) sc <= 3'd0;
    else if (sc != 3'd4) sc <= sc + 3'd1;
    case (sc)
    3'd0: begin
        logic [4:0]  la, lb;
        logic [23:0] a, b;
        logic signed [11:0] ea, eb;
        a = {x[30:23] != 0, x[22:0]};
        b = {y[30:23] != 0, y[22:0]};
        ea = (x[30:23] == 0) ? 12'sd1 : {4'h0, x[30:23]};
        eb = (y[30:23] == 0) ? 12'sd1 : {4'h0, y[30:23]};
        la = clz24(a); lb = clz24(b);
        qa <= a << la; qb <= b << lb;
        qe <= ea + eb - {7'h0, la} - {7'h0, lb};
    end
    3'd1: qp <= qa * qb;
    3'd2: begin
        logic [47:0] pp;
        logic signed [11:0] e;
        logic [26:0] s;
        if (qp[47]) begin pp = qp; e = qe - 12'sd126; end
        else begin pp = qp << 1; e = qe - 12'sd127; end
        s = {pp[47:22], pp[21:0] != 0};
        if (e < 12'sd1) begin
            logic [11:0] k;
            logic [53:0] wide;
            k = 12'sd1 - e;
            if (k >= 12'd27) s = {26'h0, s != 0};
            else begin
                wide = {s, 27'h0} >> k;
                s = {wide[53:28], wide[27] | (wide[26:0] != 0)};
            end
            e = 12'sd1;
        end
        qs <= s; qe <= e;
    end
    3'd3: slow_r <= round_pack(sg, qe, qs);
    default: ;
    endcase
end

assign busy = slow1 && sc != 3'd4;

logic        v_nan, v_spec, v_slow, v_sg;
logic [31:0] v_r;
logic [47:0] v_p;
logic [9:0]  v_esum;

always_ff @(posedge clk) if (en) begin
    v_nan <= nan1;
    v_spec <= spec;
    v_slow <= slow1;
    v_r <= slow1 ? slow_r : spec_r;
    v_sg <= sg;
    v_p <= p;
    v_esum <= esum;
end

// ---------------------------------------------------------------- stage 2

logic [31:0] res;
always_comb begin
    if (v_spec || v_slow) res = v_r;
    else begin
        logic [26:0] s;
        logic [9:0]  e;
        logic [24:0] m;
        logic        up;
        if (v_p[47]) begin s = {v_p[47:22], v_p[21:0] != 0}; e = v_esum - 10'd126; end
        else         begin s = {v_p[46:21], v_p[20:0] != 0}; e = v_esum - 10'd127; end
        up = s[2] && (s[1] || s[0] || s[3]);
        m = {1'b0, s[26:3]} + {24'h0, up};
        if (m[24]) begin m = m >> 1; e = e + 10'd1; end
        res = (e >= 10'd255) ? {v_sg, INF[30:0]} : {v_sg, e[7:0], m[22:0]};
    end
end

always_comb begin
    if (v_nan) begin r = NAN; astat = MI; stky = MIS; end
    else begin
        r = res;
        astat = (res[31] ? MN : 32'h0) | (is_inf(res) ? MV : 32'h0) | (is_den(res) ? MU : 32'h0);
        stky  = (is_inf(res) ? MVS : 32'h0) | (is_den(res) ? MUS : 32'h0);
    end
end

endmodule
